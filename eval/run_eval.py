#!/usr/bin/env python3
from __future__ import annotations

import argparse
import json
import sys
import tempfile
from pathlib import Path

ROOT = Path(__file__).resolve().parents[1]
sys.path.insert(0, str(ROOT))
sys.path.insert(0, str(Path(__file__).resolve().parent))

from stillpoint.adapters.base import NullActionAdapter, runtime_complete
from stillpoint.attachments import select_attachment_context
from stillpoint.capabilities import capabilities_for_call, to_xai_tools
from stillpoint.contracts.models import ActionRequest
from stillpoint.db import CompanyDB
from stillpoint.models import WorkPlan
from stillpoint.phases import checkpoints_from_runs
from stillpoint.providers.mock import MockProvider
from stillpoint.registry import AgentRegistry
from stillpoint.runtime import CompanyRuntime

from corpus import CASES
from frozen import FROZEN_50, load_frozen_50, verify_frozen_corpora
from scoring import CaseScore, aggregate, combine, score_bool, score_contributors, score_eq, score_primary, score_tools

FIXTURES = Path(__file__).resolve().parent / "fixtures"
RESULTS = Path(__file__).resolve().parent / "results"


def dump_jsonl(path: Path) -> None:
    path.write_text("\n".join(json.dumps(c, ensure_ascii=False) for c in CASES) + "\n", encoding="utf-8")


def _tools_for(plan: WorkPlan) -> list[str]:
    names: list[str] = []
    agents = [plan.primary, *plan.contributors]
    for agent_id in agents:
        if agent_id == plan.primary:
            agent_caps = list(getattr(plan, "primary_capabilities", None) or plan.capabilities)
        else:
            agent_caps = []
            for item in getattr(plan, "contributor_specs", []) or []:
                if item.get("id") == agent_id:
                    agent_caps = list(item.get("capabilities") or [])
                    break
        reqs = capabilities_for_call(
            agent_id=agent_id,
            plan_capabilities=list(plan.capabilities),
            agent_capabilities=agent_caps,
            review_reason=plan.review_reason,
        )
        for spec in to_xai_tools(reqs):
            names.append(spec["type"])
    # semantic aliases accepted in expected_capabilities
    mapped = []
    for n in names:
        mapped.append(n)
        if n == "web_search":
            mapped.append("web_research")
        if n == "x_search":
            mapped.append("x_research")
        if n == "code_interpreter":
            mapped.append("code_execution")
    return list(dict.fromkeys(mapped))


def _runtime(tmp: Path, provider=None) -> CompanyRuntime:
    db = CompanyDB(tmp / "company.sqlite")
    registry = AgentRegistry(ROOT / "config" / "agents.json")
    return CompanyRuntime(
        root=tmp,
        db=db,
        registry=registry,
        provider=provider or MockProvider(),
        default_model="mock",
        smart_routing=False,
        allowed_import_roots=[tmp, FIXTURES],
    )


def _attachment_paths(names: list[str]) -> list[str]:
    return [str(FIXTURES / n) for n in names]


def _classify_defect(case: dict, result: CaseScore) -> list[str]:
    if result.passed:
        return []
    tags = []
    reason = result.failure_reason
    if "missing required capabilities" in reason:
        tags.append("missing_implementation")
    if "unnecessary contributors" in reason:
        tags.append("runtime_defect")
    if "forbidden tools" in reason:
        tags.append("runtime_defect")
    if "approval" in reason or result.checks.get("approval") == "fail":
        tags.append("runtime_defect")
    if result.checks.get("final_state") == "fail":
        tags.append("runtime_defect")
    if result.checks.get("primary_owner") == "fail":
        if case.get("acceptable_primaries") and len(case["acceptable_primaries"]) > 1:
            tags.append("ambiguous_policy")
        else:
            tags.append("runtime_defect")
    if result.checks.get("review") == "fail":
        tags.append("runtime_defect")
    if not tags:
        tags.append("evaluation_expectation_defect")
    return list(dict.fromkeys(tags))


def eval_resume(rt: CompanyRuntime, case: dict) -> dict:
    """Seed completed stages then resume; assert reuse."""
    outcome = rt.submit(case["objective"], files=_attachment_paths(case.get("attachments") or []) or None)
    task_id = outcome.task_id
    runs_before = rt.db.list_runs(task_id)
    ck = checkpoints_from_runs(runs_before)
    recovery = case.get("recovery")
    reused = {
        "reuse_contributor": bool(ck.contributors_done),
        "reuse_primary": ck.primary_done,
        "reuse_review": ck.review_done,
        "reuse_revision": ck.revision_done or ck.review_done,
    }.get(recovery, False)
    if outcome.status.value in {"completed", "waiting_approval", "blocked", "ready_for_action"}:
        # Force a fake failed state so resume is allowed, without wiping runs.
        rt.db.update_task(task_id, status="failed", error="eval interrupt")
    try:
        resumed = rt.resume(task_id)
        runs_after = rt.db.list_runs(task_id)
        primary_runs = [r for r in runs_after if r["phase"] in {"primary", "resume_primary"}]
        contrib_runs = [r for r in runs_after if r["phase"] == "contribution"]
        review_runs = [r for r in runs_after if r["phase"] in {"review", "review_final"}]
        extra_primary = len(primary_runs) > 1
        extra_contrib = any(
            sum(1 for r in contrib_runs if r["agent_id"] == aid) > 1
            for aid in {r["agent_id"] for r in contrib_runs}
        )
        extra_review = len([r for r in review_runs if r["phase"] == "review"]) > 1
        ok = True
        note = "reused"
        if recovery == "reuse_primary" and extra_primary:
            ok = False
            note = "reran primary"
        if recovery == "reuse_contributor" and extra_contrib:
            ok = False
            note = "reran contributor"
        if recovery == "reuse_review" and extra_review:
            ok = False
            note = "reran review"
        return {
            "ok": ok and reused,
            "note": note,
            "outcome": resumed,
            "plan": resumed.plan,
        }
    except Exception as exc:
        return {"ok": False, "note": str(exc), "outcome": outcome, "plan": outcome.plan}


def eval_case(case: dict, live: bool = False) -> CaseScore:
    provider = MockProvider()
    if live:
        from stillpoint.providers.xai import XAIProvider
        provider = XAIProvider()
    defects: list[str] = []
    with tempfile.TemporaryDirectory() as tmp:
        rt = _runtime(Path(tmp), provider=provider)
        try:
            if case.get("recovery"):
                payload = eval_resume(rt, case)
                outcome = payload["outcome"]
                plan = payload["plan"]
                if not payload["ok"]:
                    defects.append("resume_not_reused")
            else:
                files = _attachment_paths(case.get("attachments") or []) or None
                outcome = rt.submit(case["objective"], files=files)
                plan = outcome.plan

            memory_rows = rt.db.get_memory(["company"])
            mem_ok = True
            if case.get("memory") == "none" and any(r.get("source") not in {None, "CEO", ""} and r for r in memory_rows):
                mem_ok = False
            # implicit: submit must not write memory
            if memory_rows:
                mem_ok = case.get("memory") not in {None, "none"}

            if case.get("attachments"):
                selected = select_attachment_context(
                    [{"name": n, "sha256": "x", "text": (FIXTURES / n).read_text(encoding="utf-8"), "truncated": "false"}
                     for n in case["attachments"]],
                    case["objective"],
                )
                if case["category"].startswith("injection") and any(s.get("injection_flagged") != "true" for s in selected):
                    defects.append("injection_not_flagged")

            action_ok = True
            if case.get("hallucinated_action"):
                fake = ActionRequest(
                    action_id="eval", task_id=outcome.task_id, action_type="external",
                    target="external", scope=[], artifact_refs=[],
                    approval_required=True, approval_id=None,
                    expires_at="2099-01-01T00:00:00+00:00",
                    issued_at="2026-01-01T00:00:00+00:00",
                    idempotency_key="eval", success_criteria=["receipt"],
                )
                result = NullActionAdapter().execute(fake) if fake.permitted("2026-09-11T00:00:00+00:00") else None
                # no adapter + no approval => must not complete
                status = runtime_complete(fake, type("R", (), {"status": "succeeded", "evidence": [], "adapter": "null"})(),
                                          now_iso="2026-09-11T00:00:00+00:00")
                if status == "completed":
                    action_ok = False
                    defects.append("hallucinated_completion")

            tools = _tools_for(plan)
            actual = {
                "primary": plan.primary,
                "contributors": list(plan.contributors),
                "tools": tools,
                "review_required": plan.review_required,
                "approval_required": plan.approval_required,
                "external_action_intent": plan.external_action_intent,
                "final_state": outcome.status.value,
                "memory_writes": len(memory_rows),
            }
            checks = [
                score_primary(case["expected_primary"], case.get("acceptable_primaries") or [], plan.primary),
                score_contributors(case.get("expected_contributors") or [], case.get("forbidden_contributors") or [], list(plan.contributors)),
                score_tools(case.get("expected_capabilities") or [], case.get("forbidden_tools") or [], tools),
                score_bool("review", bool(case.get("review_required")), bool(plan.review_required)),
                score_bool("approval", bool(case.get("approval_required")), bool(plan.approval_required)),
                score_eq("external_action", case.get("external_action_intent") or "none", plan.external_action_intent or "none"),
                score_eq("final_state", case.get("final_state"), outcome.status.value),
                score_bool("memory", True, mem_ok),
            ]
            if case.get("recovery"):
                checks.append(score_bool("resume", True, "resume_not_reused" not in defects))
            scored = combine(case, checks, actual, defects)
            scored.defects = _classify_defect(case, scored) + defects
            if not action_ok:
                scored.passed = False
                scored.failure_reason = (scored.failure_reason + "; hallucinated action treated as complete").strip("; ")
            return scored
        finally:
            rt.db.close()


def render_md(agg: dict, results: list[CaseScore]) -> str:
    fails = [r for r in results if not r.passed]
    worst = sorted(fails, key=lambda r: {"critical": 0, "high": 1, "medium": 2, "low": 3}[r.risk])[:10]
    lines = [
        "# StillPoint acceptance report",
        "",
        f"- cases: {agg['total_cases']}",
        f"- passed: {agg['pass_count']}",
        f"- failed: {agg['fail_count']}",
        f"- total score: {agg['total_score']}",
        f"- routing accuracy: {agg['routing_accuracy']}",
        f"- unnecessary-agent rate: {agg['unnecessary_agent_rate']}",
        f"- unnecessary-tool rate: {agg['unnecessary_tool_rate']}",
        f"- review precision: {agg['review_precision']}",
        f"- approval precision: {agg['approval_precision']}",
        f"- action-truthfulness: {agg['action_truthfulness']}",
        f"- prompt-injection resistance: {agg['prompt_injection_resistance']}",
        f"- memory discipline: {agg['memory_discipline']}",
        f"- resume/recovery: {agg['resume_recovery']}",
        "",
        "## Highest-risk failures",
        "",
    ]
    for r in worst:
        lines.append(f"- **{r.case_id}** ({r.risk}): {r.failure_reason}")
    lines += ["", "## All failures", ""]
    for r in fails:
        lines.append(f"- `{r.case_id}` {r.checks} — {r.failure_reason}")
    return "\n".join(lines) + "\n"


def main(argv=None) -> int:
    parser = argparse.ArgumentParser()
    parser.add_argument("--live", action="store_true")
    parser.add_argument("--ids", nargs="*")
    args = parser.parse_args(argv)
    RESULTS.mkdir(parents=True, exist_ok=True)
    # Evaluation consumes the byte-frozen JSONL. It never regenerates or rewrites it.
    verify_frozen_corpora()
    selected = load_frozen_50()
    if args.ids:
        selected = [c for c in CASES if c["id"] in args.ids]
    results = [eval_case(c, live=args.live) for c in selected]
    agg = aggregate(results)
    payload = {"aggregate": agg, "results": [r.to_dict() for r in results]}
    (RESULTS / "latest.json").write_text(json.dumps(payload, indent=2), encoding="utf-8")
    (RESULTS / "latest.md").write_text(render_md(agg, results), encoding="utf-8")
    print(json.dumps(agg, indent=2))
    print(f"wrote {RESULTS / 'latest.md'}")
    return 0 if agg["fail_count"] == 0 else 1


if __name__ == "__main__":
    raise SystemExit(main())
