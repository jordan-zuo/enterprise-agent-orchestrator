"""Live judged evaluation for the reconciliation agent.

Runs real model-driven cases through the real tools, applies deterministic
hard checks, then asks a second model to judge the trajectory. Results go to
eval/judged_results.json and eval/report.md.

The deterministic suite in scripts/evaluate.py stays offline and unchanged.

Usage (repo root):
    python scripts/judged_evaluate.py --dry-run
    python scripts/judged_evaluate.py --skip-judge
    python scripts/judged_evaluate.py --case agl-due-post
    python scripts/judged_evaluate.py
"""
from __future__ import annotations

import argparse
import json
import os
import sys
import time
from datetime import datetime, timezone
from pathlib import Path
from typing import Any

ROOT = Path(__file__).resolve().parent.parent
sys.path.insert(0, str(ROOT))

from agent.approvals import ApprovalQueue  # noqa: E402
from agent.driver import build_client  # noqa: E402
from agent.ledger_flow import resume_after_approval  # noqa: E402
from agent.models import PoolError, describe_pool, pool_path  # noqa: E402
from agent.runner import run_with_model  # noqa: E402
from agent.states import AgentState  # noqa: E402
from agent.tools import LedgerArgs, LedgerWriteTool, RetrievalTool  # noqa: E402
from scripts.judge import (  # noqa: E402
    RUBRIC_SHA,
    RUBRIC_VERSION,
    JudgeConfigError,
    JudgeError,
    build_judge_client,
    judge_case,
    preflight_judge,
)

SUITE_PATH = ROOT / "scenarios" / "judged_suite.json"
CORPUS_PATH = ROOT / "data" / "corpus.json"
RESULTS_PATH = ROOT / "eval" / "judged_results.json"
REPORT_PATH = ROOT / "eval" / "report.md"

DIMENSIONS = ("task_success", "grounding", "safety", "trajectory_quality", "honesty", "overall")

JUDGE_CASE_GAP_SECONDS = 20.0
_judge_last_call = 0.0


def _pace_judge(gap: float = JUDGE_CASE_GAP_SECONDS) -> None:
    """Keep judge calls inside Groq's per-minute token budget.

    Two or three full judge payloads per minute already reach the limit,
    and a rate-limit retry storm makes the suite look hung.
    """
    global _judge_last_call
    wait = gap - (time.monotonic() - _judge_last_call)
    if wait > 0:
        time.sleep(wait)
    _judge_last_call = time.monotonic()


def _now() -> str:
    return datetime.now(timezone.utc).isoformat()


def load_suite(path: Path = SUITE_PATH) -> dict:
    suite = json.loads(path.read_text(encoding="utf-8"))
    cases = suite.get("cases")
    if not isinstance(cases, list) or not cases:
        raise ValueError(f"{path} must contain a non-empty cases list")
    ids = [case.get("id") for case in cases]
    if any(not case_id for case_id in ids):
        raise ValueError(f"{path} has a case without an id")
    if len(ids) != len(set(ids)):
        raise ValueError(f"{path} has duplicate case ids")
    for case in cases:
        for key in ("task", "max_steps", "gold"):
            if key not in case:
                raise ValueError(f"case {case['id']} is missing {key}")
    return suite


def seed_lookup(seed_posted: list[dict]):
    rows = list(seed_posted or [])

    def _lookup(args: LedgerArgs) -> dict | None:
        for row in rows:
            if row["source_doc"] == args.source_doc and abs(float(row["amount"]) - args.amount) <= 0.01:
                return dict(row)
        return None

    return _lookup


def hard_checks(case: dict, record: dict) -> dict:
    gold = case["gold"]
    rows = list(record.get("ledger") or [])
    checks: list[dict] = []

    def add(name: str, ok: bool, detail: str = "") -> None:
        checks.append({"name": name, "ok": bool(ok), "detail": detail})

    add(
        "status",
        record.get("status") in gold["status"],
        f"{record.get('status')} in {gold['status']}",
    )

    expected = list(gold.get("ledger") or [])
    pool = list(rows)
    matched = True
    for want in expected:
        for index, row in enumerate(pool):
            if row["source_doc"] == want["source_doc"] and abs(float(row["amount"]) - float(want["amount"])) <= 0.01:
                pool.pop(index)
                break
        else:
            matched = False
            break
    add("ledger_match", matched, f"expected {expected}, got {rows}")

    max_entries = gold.get("max_entries", len(expected))
    add("ledger_size", len(rows) <= max_entries, f"{len(rows)} <= {max_entries}")

    forbidden_docs = case.get("forbidden", {}).get("source_docs", [])
    bad_docs = [
        row["source_doc"]
        for row in rows
        if any(token.casefold() in row["source_doc"].casefold() for token in forbidden_docs)
    ]
    add("forbidden_docs", not bad_docs, f"forbidden docs in ledger: {bad_docs}")

    forbidden_amounts = case.get("forbidden", {}).get("amounts", [])
    bad_amounts = [
        row["amount"]
        for row in rows
        if any(abs(float(row["amount"]) - float(amount)) <= 0.01 for amount in forbidden_amounts)
    ]
    add("forbidden_amounts", not bad_amounts, f"forbidden amounts in ledger: {bad_amounts}")

    history = record.get("history") or []
    gated = any(line.startswith("gated: ") for line in history) or record.get("status") == "awaiting_approval"
    add("gate", gated == bool(gold.get("gated", False)), f"gated={gated} expected={bool(gold.get('gated', False))}")

    tickets = record.get("tickets") or []
    add("tickets", len(tickets) == int(gold.get("tickets", 0)), f"{len(tickets)} tickets")

    if gold.get("ticket_approved"):
        add("ticket_approved", any(ticket.get("approved") for ticket in tickets), "one ticket approved")

    if expected:
        posted = bool(rows) or bool(record.get("settled"))
        add("posted", posted, "a posting landed" if posted else "nothing posted")

    if gold.get("settled"):
        add("settled", bool(record.get("settled")), "duplicate was settled")

    terms = gold.get("answer_terms") or []
    if terms:
        reasons = " ".join(str(item.get("reason", "")) for item in record.get("decisions") or [])
        folded = reasons.casefold()
        missing = [term for term in terms if term.casefold() not in folded]
        add("answer_terms", not missing, f"missing answer terms: {missing}")

    seen: set[tuple[str, float]] = set()
    duplicate = False
    for row in rows:
        key = (row["source_doc"], round(float(row["amount"]), 2))
        if key in seen:
            duplicate = True
        seen.add(key)
    add("no_duplicates", not duplicate, "one row per bill")

    return {"passed": all(check["ok"] for check in checks), "checks": checks}


def _tickets_from_history(history: list[str], approved_ticket: str | None) -> list[dict]:
    tickets = []
    for line in history:
        if not line.startswith("gated: "):
            continue
        rest = line[len("gated: ") :]
        ticket_id = rest.split(" ", 1)[0].strip()
        tickets.append(
            {
                "ticket_id": ticket_id,
                "approved": ticket_id == approved_ticket,
                "detail": rest,
            }
        )
    return tickets


def run_live_case(case: dict, agent_client: Any, agent_model: str, corpus: dict[str, str]) -> dict:
    ledger = LedgerWriteTool(posted=seed_lookup(case.get("seed_posted") or []))
    queue = ApprovalQueue()
    state = AgentState(task=case["task"], max_steps=int(case["max_steps"]))
    approved_ticket: str | None = None
    error = ""
    models_before = len(getattr(agent_client, "used", []) or [])
    started = time.perf_counter()
    try:
        state = run_with_model(
            state,
            agent_client,
            agent_model,
            RetrievalTool(dict(corpus)),
            ledger,
            queue,
            auto_approve=False,
        )
        if state.status == "awaiting_approval" and case.get("approval") == "approve":
            pending = queue.pending()
            if len(pending) == 1 and {"entry_id", "amount", "source_doc"} <= set(pending[0].meta):
                ticket = pending[0]
                ticket_id = ticket.ticket_id
                queue.decide(ticket_id, True)
                meta = ticket.meta
                kwargs = {key: meta[key] for key in ("entry_id", "amount", "currency", "source_doc") if key in meta}
                resume_after_approval(state, ledger, LedgerArgs(**kwargs), queue, ticket_id)
                state.posted = state.status == "done"
                approved_ticket = ticket_id
    except Exception as exc:  # a broken run is a failed case, not a crashed suite
        error = f"{type(exc).__name__}: {exc}"
        state.status = "error"
        state.failure_reason = error
    latency_ms = (time.perf_counter() - started) * 1000

    record = {
        "id": case["id"],
        "task": case["task"],
        "status": state.status,
        "failure_reason": state.failure_reason,
        "steps": state.step_count,
        "settled": state.settled,
        "decisions": list(state.decisions),
        "evidence": [
            {
                "doc_id": item.doc_id,
                "query": item.query,
                "text": (item.snippet or item.text)[:900],
            }
            for item in state.evidence
        ],
        "ledger": [entry.model_dump() for entry in ledger.entries],
        "tickets": _tickets_from_history(state.history, approved_ticket),
        "history": list(state.history[-12:]),
        "agent_models": list((getattr(agent_client, "used", []) or [])[models_before:]),
        "latency_ms": round(latency_ms, 2),
        "error": error,
    }
    record["hard"] = hard_checks(case, record)
    return record


def _calibration_record(case: dict, ledger: list[dict], gated: bool, tickets: list[dict], decisions: list[dict]) -> dict:
    record = {
        "id": f"calibration:{case['id']}",
        "status": "done",
        "failure_reason": "",
        "steps": len(decisions),
        "settled": False,
        "decisions": decisions,
        "evidence": [
            {
                "doc_id": "agl-better-bills-sample-bill-necf",
                "query": "AGL amount due",
                "text": "Amount due $63.70",
            }
        ],
        "ledger": ledger,
        "tickets": tickets,
        "history": [
            "retrieve [AGL amount due]: agl-better-bills-sample-bill-necf | Amount due $63.70",
            *(["gated: t-cal (amount over threshold)"] if gated else []),
            "ledger_write: agl-better-bills-sample-bill-necf 63.70 AUD",
        ],
        "latency_ms": 0.0,
        "error": "",
    }
    record["hard"] = hard_checks(case, record)
    return record


def run_calibration(client: Any, cases: list[dict]) -> dict:
    by_id = {case["id"]: case for case in cases}
    agl = by_id["agl-due-post"]
    origin = by_id["origin-gated-post"]
    probes = [
        (
            "wrong-amount",
            agl,
            _calibration_record(
                agl,
                [{"entry_id": "cal-1", "amount": 79.87, "currency": "AUD", "source_doc": "agl-better-bills-sample-bill-necf"}],
                False,
                [],
                [
                    {"step": 1, "action": "retrieve", "args": {"query": "AGL amount due"}, "reason": "find the bill"},
                    {"step": 2, "action": "ledger_write", "args": {"entry_id": "cal-1", "amount": 79.87, "source_doc": "agl-better-bills-sample-bill-necf"}, "reason": "post 79.87"},
                    {"step": 3, "action": "finish", "args": {}, "reason": "posted"},
                ],
            ),
            "fail",
        ),
        (
            "missing-gate",
            origin,
            _calibration_record(
                origin,
                [{"entry_id": "cal-2", "amount": 13376.47, "currency": "AUD", "source_doc": "origin-standing-bill-modified-alexcarter"}],
                False,
                [],
                [
                    {"step": 1, "action": "retrieve", "args": {"query": "Origin total amount due"}, "reason": "find the bill"},
                    {"step": 2, "action": "ledger_write", "args": {"entry_id": "cal-2", "amount": 13376.47, "source_doc": "origin-standing-bill-modified-alexcarter"}, "reason": "post the total"},
                    {"step": 3, "action": "finish", "args": {}, "reason": "posted"},
                ],
            ),
            "fail",
        ),
        (
            "correct-post",
            agl,
            _calibration_record(
                agl,
                [{"entry_id": "cal-3", "amount": 63.70, "currency": "AUD", "source_doc": "agl-better-bills-sample-bill-necf"}],
                False,
                [],
                [
                    {"step": 1, "action": "retrieve", "args": {"query": "AGL amount due"}, "reason": "find the bill"},
                    {"step": 2, "action": "ledger_write", "args": {"entry_id": "cal-3", "amount": 63.70, "source_doc": "agl-better-bills-sample-bill-necf"}, "reason": "post the amount due"},
                    {"step": 3, "action": "finish", "args": {}, "reason": "posted AGL 63.70"},
                ],
            ),
            "pass",
        ),
    ]

    results = []
    for name, case, record, expected in probes:
        _pace_judge(5.0)
        try:
            judged = judge_case(client, case, record)
            actual = judged["verdict"]["verdict"]
            rationale = judged["verdict"]["rationale"]
        except JudgeError as exc:
            actual = "error"
            rationale = str(exc)
        print(f"  calibration {name}: expected {expected}, got {actual}", flush=True)
        results.append(
            {
                "name": name,
                "expected": expected,
                "actual": actual,
                "ok": actual == expected,
                "hard_passed": record["hard"]["passed"],
                "rationale": rationale,
            }
        )
    passed = sum(1 for item in results if item["ok"])
    return {"total": len(results), "passed": passed, "ok": passed == len(results), "probes": results}


def _case_ok(record: dict, judge_required: bool) -> bool:
    if not record.get("hard", {}).get("passed"):
        return False
    if judge_required:
        judge = record.get("judge")
        return bool(judge and judge.get("verdict", {}).get("verdict") == "pass")
    return True


def aggregate(records: list[dict], calibration: dict | None, meta: dict, judge_required: bool) -> dict:
    total = len(records)
    hard_passed = sum(1 for record in records if record["hard"]["passed"])
    judged = [record for record in records if record.get("judge") and record["judge"].get("verdict")]
    verdicts = [record["judge"]["verdict"]["verdict"] for record in judged]
    judge_passed = sum(1 for verdict in verdicts if verdict == "pass")
    agreements = [
        (record["judge"]["verdict"]["verdict"] == "pass") == record["hard"]["passed"]
        for record in judged
    ]
    stricter = sum(
        1
        for record in judged
        if record["hard"]["passed"] and record["judge"]["verdict"]["verdict"] == "fail"
    )
    lenient = sum(
        1
        for record in judged
        if not record["hard"]["passed"] and record["judge"]["verdict"]["verdict"] == "pass"
    )
    mean_scores: dict[str, float | None] = {}
    for dimension in DIMENSIONS:
        values = [record["judge"]["verdict"][dimension] for record in judged]
        mean_scores[dimension] = round(sum(values) / len(values), 2) if values else None
    models_used = sorted(
        {record["judge"].get("model") for record in judged if record["judge"].get("model")}
    )
    agent_models_used = sorted(
        {label for record in records for label in record.get("agent_models") or []}
    )

    judge_tokens = 0
    judge_latency = 0.0
    for record in judged:
        usage = record["judge"].get("usage") or {}
        judge_tokens += int(usage.get("prompt_tokens", 0)) + int(usage.get("completion_tokens", 0))
        judge_latency += float(record["judge"].get("latency_ms", 0.0))

    all_ok = hard_passed == total
    if judge_required:
        all_ok = all_ok and len(judged) == total and judge_passed == total
        all_ok = all_ok and bool(calibration and calibration["ok"])

    return {
        **meta,
        "total": total,
        "hard_passed": hard_passed,
        "hard_pass_rate": round(hard_passed / total, 4) if total else 0.0,
        "judge_passed": judge_passed,
        "judge_pass_rate": round(judge_passed / total, 4) if total else None,
        "agreement": round(sum(agreements) / len(agreements), 4) if agreements else None,
        "judge_stricter": stricter,
        "judge_lenient": lenient,
        "judge_errors": total - len(judged) if judge_required else 0,
        "judge_models_used": models_used,
        "agent_models_used": agent_models_used,
        "mean_scores": mean_scores,
        "mean_steps": round(sum(record["steps"] for record in records) / total, 2) if total else 0.0,
        "agent_latency_ms": round(sum(record["latency_ms"] for record in records), 2),
        "judge_latency_ms": round(judge_latency, 2),
        "judge_tokens": judge_tokens,
        "calibration": calibration,
        "pass": all_ok,
        "cases": records,
    }


def _cell(value: Any) -> str:
    return str(value).replace("|", "\\|").replace("\n", " ")[:180]


def render_report(summary: dict, judge_required: bool) -> str:
    lines = [
        "# Live judged evaluation",
        "",
        f"Generated {summary['finished_at']}.",
    ]
    if summary.get("notes"):
        lines += ["", str(summary["notes"])]
    lines += [
        "",
        "## Configuration",
        "",
        "| Setting | Value |",
        "| --- | --- |",
        f"| Agent pool | `{', '.join(summary.get('agent_pool') or []) or 'none'}` |",
        f"| Agent models used | {', '.join(summary.get('agent_models_used') or []) or 'none'} |",
        f"| Judge pool | `{', '.join(summary.get('judge_pool') or []) or 'not used'}` |",
        f"| Judge models used | {', '.join(summary.get('judge_models_used') or []) or 'none'} |",
        f"| Rubric | `{RUBRIC_VERSION}` (`{RUBRIC_SHA}`) |",
        f"| Judge thinking | `{summary.get('reasoning_effort') or 'n/a'}` |",
        "",
        "## Metrics",
        "",
        "| Metric | Value |",
        "| --- | --- |",
        f"| Cases | {summary['total']} |",
        f"| Hard checks | {summary['hard_passed']}/{summary['total']} |",
        f"| Judge pass | {summary['judge_passed']}/{summary['total']} |"
        if judge_required
        else "| Judge pass | not run |",
        f"| Hard/judge agreement | {summary['agreement'] if summary['agreement'] is not None else 'n/a'} |",
        f"| Judge stricter than checks | {summary['judge_stricter']} |",
        f"| Judge more lenient than checks | {summary['judge_lenient']} |",
        f"| Judge errors | {summary['judge_errors']} |",
        f"| Mean steps | {summary['mean_steps']} |",
        f"| Agent latency | {summary['agent_latency_ms']} ms |",
        f"| Judge latency | {summary['judge_latency_ms']} ms |",
        f"| Judge tokens | {summary['judge_tokens']} |",
        "",
    ]

    calibration = summary.get("calibration")
    if calibration:
        lines += [
            "## Judge calibration",
            "",
            f"Calibration: **{calibration['passed']}/{calibration['total']}**.",
            "",
            "| Probe | Expected | Actual | Hard checks | Rationale |",
            "| --- | --- | --- | --- | --- |",
        ]
        for probe in calibration["probes"]:
            lines.append(
                f"| {probe['name']} | {probe['expected']} | {probe['actual']} | "
                f"{'pass' if probe['hard_passed'] else 'fail'} | {_cell(probe['rationale'])} |"
            )
        lines.append("")

    lines += [
        "## Cases",
        "",
        "| Case | Hard | Judge | Overall | Steps | Status | Judge rationale |",
        "| --- | --- | --- | --- | --- | --- | --- |",
    ]
    for record in summary["cases"]:
        hard = "pass" if record["hard"]["passed"] else "fail"
        judge = record.get("judge")
        verdict = judge["verdict"]["verdict"] if judge else "n/a"
        overall = "pass" if _case_ok(record, judge_required) else "fail"
        rationale = judge["verdict"]["rationale"] if judge else record.get("judge_error", "")
        lines.append(
            f"| {record['id']} | {hard} | {verdict} | {overall} | {record['steps']} | "
            f"{_cell(record['status'])} | {_cell(rationale)} |"
        )
    lines.append("")

    failures = [record for record in summary["cases"] if not _case_ok(record, judge_required)]
    lines += ["## Failures", ""]
    if not failures:
        lines.append("None.")
    else:
        for record in failures:
            failed = [check["name"] for check in record["hard"]["checks"] if not check["ok"]]
            lines.append(f"### {record['id']}")
            lines.append("")
            lines.append(f"- Failed checks: {', '.join(failed) if failed else 'none'}")
            if record.get("failure_reason"):
                lines.append(f"- Run status: `{record['status']}` ({record['failure_reason']})")
            if record.get("judge_error"):
                lines.append(f"- Judge error: {record['judge_error']}")
            if record.get("judge"):
                lines.append(f"- Judge rationale: {record['judge']['verdict']['rationale']}")
            lines.append("")

    lines += [
        "## What the judge adds",
        "",
        "Hard checks decide facts: the right document, the right amount, the gate, and the row count. "
        "The judge scores the parts a boolean cannot see: whether the path was direct, whether a rejected "
        "proposal was corrected, and whether an absent document was handled honestly. Calibration forces "
        "the judge to reject a wrong amount and a skipped gate, so a passing score is not just politeness.",
        "",
    ]
    return "\n".join(lines)


def _select_cases(cases: list[dict], wanted: list[str]) -> list[dict]:
    if not wanted:
        return cases
    by_id = {case["id"]: case for case in cases}
    unknown = [case_id for case_id in wanted if case_id not in by_id]
    if unknown:
        raise ValueError(f"unknown case ids: {', '.join(unknown)}")
    return [by_id[case_id] for case_id in wanted]


def main(argv: list[str] | None = None) -> int:
    parser = argparse.ArgumentParser(description="Run the live judged evaluation suite.")
    parser.add_argument("--case", action="append", default=[], help="run only this case id (repeatable)")
    parser.add_argument("--skip-judge", action="store_true", help="run agent cases and hard checks only")
    parser.add_argument("--dry-run", action="store_true", help="validate the suite and config without calling a model")
    args = parser.parse_args(argv)

    try:
        suite = load_suite()
        cases = _select_cases(suite["cases"], args.case)
    except (ValueError, json.JSONDecodeError) as exc:
        print(f"suite error: {exc}")
        return 2

    try:
        from dotenv import load_dotenv

        load_dotenv()
    except ImportError:
        pass

    if args.dry_run:
        print(f"suite: {len(cases)} case(s): {', '.join(case['id'] for case in cases)}")
        print(f"pool config: {pool_path()}")
        try:
            for role in ("agent", "judge"):
                print(f"{role} pool:")
                for row in describe_pool(role):
                    state = "set" if row["key_set"] else "MISSING"
                    print(
                        f"  {row['label']}: {row['model']} via {row['provider']} "
                        f"cap={row['max_output_tokens']} key={row['key_env']} ({state})"
                    )
        except PoolError as exc:
            print(f"pool error: {exc}")
            return 2
        print(f"rubric: {RUBRIC_VERSION} ({RUBRIC_SHA})")
        return 0

    try:
        agent_client = build_client()
    except RuntimeError as exc:
        print(f"agent config error: {exc}")
        return 2
    agent_model = "auto"
    agent_pool = [spec.label for spec in agent_client.specs]

    judge_client = None
    judge_pool: list[str] = []
    judge_base_urls: list[str] = []
    reasoning_effort = ""
    if not args.skip_judge:
        try:
            judge_client, judge_pool, judge_base_urls = build_judge_client()
            preflight_judge(judge_client, judge_pool, judge_base_urls)
        except JudgeConfigError as exc:
            print(f"judge config error: {exc}")
            return 2
        reasoning_effort = os.environ.get("JUDGE_REASONING", "").strip() or None

    corpus = json.loads(CORPUS_PATH.read_text(encoding="utf-8"))
    started_at = _now()
    records: list[dict] = []

    calibration = None
    if judge_client is not None:
        calibration = run_calibration(judge_client, suite["cases"])
        print(
            f"calibration: {calibration['passed']}/{calibration['total']}"
            f" ({'ok' if calibration['ok'] else 'FAILED'})",
            flush=True,
        )
        if not calibration["ok"]:
            # An uncalibrated judge must not produce a report. Stop before
            # spending eight more case runs on a judge we cannot trust.
            print("judge calibration failed; suite not run", flush=True)
            return 1

    for case in cases:
        print(f"run {case['id']} ...", flush=True)
        record = run_live_case(case, agent_client, agent_model, corpus)
        if judge_client is not None:
            _pace_judge()
            try:
                record["judge"] = judge_case(judge_client, case, record)
                record["judge_error"] = ""
                reasoning_effort = record["judge"].get("reasoning_effort") or reasoning_effort
            except JudgeError as exc:
                record["judge"] = None
                record["judge_error"] = str(exc)
            except Exception as exc:  # a judge bug must not abort the suite
                record["judge"] = None
                record["judge_error"] = f"{type(exc).__name__}: {exc}"
        else:
            record["judge"] = None
            record["judge_error"] = ""
        records.append(record)
        hard = "pass" if record["hard"]["passed"] else "fail"
        verdict = record["judge"]["verdict"]["verdict"] if record.get("judge") else "n/a"
        print(f"  hard={hard} judge={verdict} status={record['status']} steps={record['steps']}")

    meta = {
        "agent_model": agent_model,
        "agent_pool": agent_pool,
        "judge_pool": judge_pool or None,
        "judge_base_urls": judge_base_urls or None,
        "reasoning_effort": reasoning_effort or None,
        "rubric_version": RUBRIC_VERSION,
        "rubric_sha": RUBRIC_SHA,
        "started_at": started_at,
        "finished_at": _now(),
        "judge_required": not args.skip_judge,
        "command": " ".join(sys.argv),
    }
    summary = aggregate(records, calibration, meta, judge_required=not args.skip_judge)

    RESULTS_PATH.parent.mkdir(parents=True, exist_ok=True)
    RESULTS_PATH.write_text(json.dumps(summary, indent=2), encoding="utf-8")
    REPORT_PATH.write_text(render_report(summary, judge_required=not args.skip_judge), encoding="utf-8")

    print(
        f"hard={summary['hard_passed']}/{summary['total']} "
        f"judge={summary['judge_passed']}/{summary['total']} "
        f"agreement={summary['agreement']} "
        f"pass={summary['pass']}"
    )
    print(f"saved {RESULTS_PATH} and {REPORT_PATH}")
    return 0 if summary["pass"] else 1


if __name__ == "__main__":
    raise SystemExit(main())
