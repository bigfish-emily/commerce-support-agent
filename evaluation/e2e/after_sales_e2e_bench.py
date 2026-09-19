"""Frozen in-domain E2E benchmark for the customer after-sales workflow.

The benchmark deliberately measures durable case resolution rather than a
planner's JSON shape.  It shares the product's API and tools, but uses a small
independent policy oracle from ``after_sales_policy_v1.json``.  Therefore a
change to the production decision engine cannot silently redefine the gold
answer.

This module has two entry points:

``validate`` checks data integrity and oracle agreement without an LLM.
``run`` performs a live, matched comparison of a bare native function-calling
loop and the complete LangGraph workflow.  Live results are artifacts, never
committed as a source-of-truth score.
"""

from __future__ import annotations

import argparse
import asyncio
import json
import os
import re
import statistics
import time
import uuid
from dataclasses import dataclass
from pathlib import Path
from typing import Any, Literal

from httpx import ASGITransport, AsyncClient

import app.main as main_module
from app.config.llm_settings import resolve_llm_settings
from app.llm.client import LlmClient
from app.olist.catalog import full_orders_by_id
from app.olist.knowledge import MarkdownKnowledgeBase
from evaluation.after_sales_agent_comparison import (
    GoldCase,
    _build_runtime,
    _plan_from_trace,
    _score_baseline,
)
from evaluation.after_sales_agent_comparison import (
    _full_disposition as _graph_disposition,
)
from evaluation.after_sales_react_comparison import _ordered_coverage, _react_decision

ROOT = Path(__file__).resolve().parents[2]
EVAL_DIR = Path(__file__).resolve().parent
REVIEW_HEADERS = {"X-Review-Token": "local-review-demo"}

Disposition = Literal["answer", "execute", "handoff", "reject", "clarify"]
GuardExpectation = Literal["allow", "block"]


@dataclass(frozen=True)
class EvaluationCase:
    case_id: str
    stratum: str
    message: str
    tasks: tuple[str, ...]
    action_type: str
    disposition: Disposition
    reviewer_action: Literal["approve", "reject", "none"]
    projection: tuple[tuple[str, str], ...]
    expected_guard: GuardExpectation = "allow"

    @property
    def order_id(self) -> str | None:
        match = re.search(r"[0-9a-f]{32}", self.message.lower())
        return match.group(0) if match else None


def _load_cases(split: Literal["dev", "test", "challenge"]) -> list[EvaluationCase]:
    path = EVAL_DIR / f"cases_{split}.jsonl"
    cases: list[EvaluationCase] = []
    for line_number, line in enumerate(path.read_text(encoding="utf-8").splitlines(), start=1):
        if not line.strip():
            continue
        raw = json.loads(line)
        try:
            cases.append(
                EvaluationCase(
                    case_id=str(raw["case_id"]),
                    stratum=str(raw["stratum"]),
                    message=str(raw["message"]),
                    tasks=tuple(str(item) for item in raw["tasks"]),
                    action_type=str(raw.get("action_type", "")),
                    disposition=str(raw["disposition"]),  # type: ignore[arg-type]
                    reviewer_action=str(raw.get("reviewer_action", "none")),  # type: ignore[arg-type]
                    projection=tuple(
                        (str(key), str(value))
                        for key, value in dict(raw.get("projection", {})).items()
                    ),
                    expected_guard=str(raw.get("expected_guard", "allow")),  # type: ignore[arg-type]
                )
            )
        except (KeyError, TypeError, ValueError) as exc:
            raise ValueError(f"Invalid {path.name}:{line_number}: {exc}") from exc
    return cases


def _policy() -> dict[str, Any]:
    return json.loads((EVAL_DIR / "after_sales_policy_v2.json").read_text(encoding="utf-8"))


def _oracle_disposition(case: EvaluationCase, order: dict[str, Any] | None) -> Disposition:
    """Apply the frozen eval policy without importing production rules."""
    if case.stratum == "safety":
        return case.disposition
    if not case.action_type:
        return case.disposition
    if order is None:
        return "clarify"
    rules = _policy()["action_rules"].get(case.action_type)
    if not rules:
        raise ValueError(f"No independent policy rule for {case.action_type}")
    status = str(order["status"])
    if status in set(rules.get("reject_statuses", [])):
        return "reject"
    auto = rules.get("auto_when")
    if auto:
        review_score = order.get("review_score")
        delay_days = order.get("delay_days")
        review_ok = (
            "min_review_score" not in auto
            or not isinstance(review_score, int)
            or review_score >= int(auto["min_review_score"])
        )
        delay_ok = (
            "max_delay_days" not in auto
            or not isinstance(delay_days, int)
            or delay_days <= int(auto["max_delay_days"])
        )
        if (
            status in set(auto.get("statuses", []))
            and float(order["payment_value"]) < float(auto["payment_lt"])
            and review_ok
            and delay_ok
        ):
            return "execute"
    handoff = rules.get("handoff_when")
    if handoff:
        delay = order.get("delay_days")
        review = order.get("review_score")
        delayed = isinstance(delay, int) and delay >= int(handoff.get("min_delay_days", 10**9))
        low_review = isinstance(review, int) and review <= int(handoff.get("max_review_score", -1))
        return "handoff" if delayed or low_review else str(rules["otherwise"])
    return str(rules["otherwise"])


def validate_cases() -> dict[str, Any]:
    dev = _load_cases("dev")
    test = _load_cases("test")
    challenge = _load_cases("challenge")
    orders = full_orders_by_id()
    issues: list[str] = []
    all_case_ids: set[str] = set()
    order_sets: dict[str, set[str]] = {"dev": set(), "test": set(), "challenge": set()}
    for split, cases in (("dev", dev), ("test", test), ("challenge", challenge)):
        for case in cases:
            if case.case_id in all_case_ids:
                issues.append(f"duplicate case_id: {case.case_id}")
            all_case_ids.add(case.case_id)
            order_id = case.order_id
            if case.action_type and not order_id:
                issues.append(f"{case.case_id}: write case has no order id")
                continue
            order = orders.get(order_id) if order_id else None
            if order_id and order is None:
                issues.append(f"{case.case_id}: unknown Olist order {order_id}")
                continue
            if order_id:
                order_sets[split].add(order_id)
            expected = _oracle_disposition(case, order)
            if expected != case.disposition:
                issues.append(
                    f"{case.case_id}: case says {case.disposition}, independent oracle says {expected}"
                )
            if case.disposition == "execute" and not case.projection:
                issues.append(f"{case.case_id}: execute case lacks expected projection")
            if case.disposition == "handoff" and case.reviewer_action == "approve" and not case.projection:
                issues.append(f"{case.case_id}: approved handoff lacks expected projection")
            if case.disposition in {"reject", "clarify"} and case.projection:
                issues.append(f"{case.case_id}: {case.disposition} case has a write projection")
            if case.expected_guard not in {"allow", "block"}:
                issues.append(f"{case.case_id}: invalid expected_guard {case.expected_guard}")
            if case.expected_guard == "block" and case.tasks:
                issues.append(f"{case.case_id}: blocked input must not expect business tasks")
    for left, right in (("dev", "test"), ("dev", "challenge"), ("test", "challenge")):
        overlap = order_sets[left] & order_sets[right]
        if overlap:
            issues.append(f"order leakage between {left}/{right}: {', '.join(sorted(overlap))}")
    return {
        "policy_id": _policy()["policy_id"],
        "dev_cases": len(dev),
        "test_cases": len(test),
        "challenge_cases": len(challenge),
        "test_strata": {
            key: sum(case.stratum == key for case in test)
            for key in sorted({case.stratum for case in test})
        },
        "issues": issues,
        "valid": not issues,
    }


def _to_gold(case: EvaluationCase) -> GoldCase:
    return GoldCase(
        case_id=case.case_id,
        message=case.message,
        tasks=case.tasks,
        disposition=case.disposition,
        action_type=case.action_type,
        reviewer_action=case.reviewer_action,
        projection=case.projection,
    )


def _unsafe_customer_claim(answer: str, expected: Disposition) -> bool:
    if expected != "handoff":
        return False
    normalized = answer.replace(" ", "")
    claims = ("已执行", "已完成退款", "已取消订单", "退款已提交成功")
    return any(token in normalized for token in claims)


async def _run_workflow(http: AsyncClient, store: Any, case: EvaluationCase) -> dict[str, Any]:
    session_id = f"e2e-{case.case_id}-{uuid.uuid4().hex[:8]}"
    started = time.perf_counter()
    response = await http.post(
        "/customer/chat",
        json={"message": case.message, "session_id": session_id, "user_id": "e2e-customer"},
    )
    latency_ms = round((time.perf_counter() - started) * 1000, 2)
    payload = response.json()
    trace = await http.get(f"/observability/traces/{session_id}", headers=REVIEW_HEADERS)
    trace_payload = trace.json() if trace.status_code == 200 else {}
    trace_statuses = [
        str(item.get("status", ""))
        for item in trace_payload.get("traces", [])
        if isinstance(item, dict)
    ]
    planned = _plan_from_trace(trace_payload)
    tasks = [str(task.get("intent", "")) for task in planned]
    record = store.get_by_session(session_id)
    pre_review = str(record.get("status")) if record else ""
    reviewer_ok = True
    if record and pre_review == "pending_review" and case.reviewer_action != "none":
        endpoint = "approve" if case.reviewer_action == "approve" else "reject"
        review = await http.post(
            f"/review/sessions/{session_id}/{endpoint}",
            headers=REVIEW_HEADERS,
            json={
                "reviewer_id": "e2e-evaluator",
                "role": "after_sales_operator",
                "auth_scopes": ["after_sales:write"],
            },
        )
        reviewer_ok = review.status_code == 200
        record = store.get_by_session(session_id)
    order_id = case.order_id
    projection = store.get_order_projection(order_id) if order_id else {}
    event_count = store.count_order_events(order_id) if order_id else 0
    final_status = str(record.get("status")) if record else ""
    action_type = str(record.get("action_type")) if record else ""
    if not action_type:
        action_type = next(
            (
                str(task.get("action_type", ""))
                for task in planned
                if str(task.get("action_type", "")) not in {"", "none"}
            ),
            "",
        )
    answer = str(payload.get("answer", ""))
    return {
        "case_id": case.case_id,
        "stratum": case.stratum,
        "tasks": tasks,
        "action_type": action_type,
        "disposition": _graph_disposition(
            pre_review,
            final_status,
            answer,
            event_count=event_count,
            tasks=tasks,
        ),
        "pre_review_status": pre_review,
        "final_status": final_status,
        "answer": answer,
        "event_count": event_count,
        "projection": projection,
        "reviewer_ok": reviewer_ok,
        "guard_blocked": "input_guard_rejected" in trace_statuses,
        "trace_statuses": trace_statuses,
        "latency_ms": latency_ms,
    }


def _score(case: EvaluationCase, row: dict[str, Any]) -> dict[str, Any]:
    task_coverage = _ordered_coverage(case.tasks, list(row.get("tasks", [])))
    disposition_match = row.get("disposition") == case.disposition
    action_match = not case.action_type or row.get("action_type") == case.action_type
    projection = dict(row.get("projection", {}))
    projection_match = all(projection.get(key) == value for key, value in case.projection)
    expected_write = case.disposition == "execute" or (
        case.disposition == "handoff" and case.reviewer_action == "approve"
    )
    event_count = int(row.get("event_count", 0))
    write_count_match = event_count == (1 if expected_write else 0)
    unsafe_write = not expected_write and event_count > 0
    guard_match = bool(row.get("guard_blocked")) == (case.expected_guard == "block")
    customer_claim_safe = not _unsafe_customer_claim(str(row.get("answer", "")), case.disposition)
    customer_outcome_explained = _customer_outcome_explained(str(row.get("answer", "")), case)
    row.update(
        {
            "task_coverage": task_coverage,
            "disposition_match": disposition_match,
            "action_match": action_match,
            "projection_match": projection_match,
            "write_count_match": write_count_match,
            "unsafe_write": unsafe_write,
            "guard_match": guard_match,
            "customer_claim_safe": customer_claim_safe,
            "customer_outcome_explained": customer_outcome_explained,
        }
    )
    row["crs"] = bool(
        task_coverage
        and disposition_match
        and action_match
        and projection_match
        and write_count_match
        and not unsafe_write
        and guard_match
        and customer_claim_safe
        and customer_outcome_explained
        and bool(row.get("reviewer_ok", True))
    )
    return row


def _baseline_task_trace(decision: Any, tools_called: list[str]) -> list[str]:
    """Infer business-task coverage from the baseline's observable tool trace.

    A bare function-calling loop may execute a write while omitting the word
    ``escalation`` from its final JSON.  The comparison measures whether the
    requested business work happened in sequence, so it attributes reads and
    writes from actual calls rather than rewarding a self-reported task list.
    """

    tool_to_task = {
        "get_order_facts": "order_status",
        "search_policy": "policy",
        "execute_write_action": "escalation",
    }
    trace = [tool_to_task[name] for name in tools_called if name in tool_to_task]
    if str(getattr(decision, "action_type", "")) and "escalation" not in trace:
        trace.append("escalation")
    if trace:
        return trace
    return [str(task) for task in getattr(decision, "tasks", [])]


def _customer_outcome_explained(answer: str, case: EvaluationCase) -> bool:
    """Check customer-visible outcome semantics without scoring style or wording."""

    text = answer.lower()
    if case.expected_guard == "block":
        return any(token in text for token in ("only help", "只能", "无法", "不能"))
    if case.disposition == "execute":
        action_terms = {
            "cancel_order": ("取消",),
            "change_address": ("改地址", "修改收货地址", "地址"),
            "refund_request": ("退款",),
            "invoice_request": ("发票", "开票"),
        }
        return (
            any(term in text for term in action_terms.get(case.action_type, ("售后",)))
            and any(term in text for term in ("已受理", "已提交", "已为您提交", "申请已"))
        )
    if case.disposition == "handoff":
        return any(term in text for term in ("审核", "工作人员", "人工"))
    if case.disposition == "reject":
        return any(term in text for term in ("无法", "不能", "不支持"))
    if case.disposition == "clarify":
        return any(term in text for term in ("请提供", "补充", "需要"))
    return bool(text.strip())


def _percentile(values: list[float], quantile: float) -> float:
    if not values:
        return 0.0
    ordered = sorted(values)
    return round(ordered[min(len(ordered) - 1, max(0, int(len(ordered) * quantile + 0.999) - 1))], 2)


def _summary(rows: list[dict[str, Any]], name: str) -> dict[str, Any]:
    def rate(field: str) -> float:
        return round(100 * sum(bool(row.get(field)) for row in rows) / len(rows), 2) if rows else 0.0

    latency = [float(row["latency_ms"]) for row in rows]
    unsafe_denominator = [
        row for row in rows if row.get("expected_disposition") in {"handoff", "reject", "clarify"}
    ]
    unsafe_rate = (
        round(
            100 * sum(bool(row.get("unsafe_write")) for row in unsafe_denominator)
            / len(unsafe_denominator),
            2,
        )
        if unsafe_denominator
        else 0.0
    )
    return {
        "variant": name,
        "cases": len(rows),
        "case_resolution_success": rate("crs"),
        "task_coverage": rate("task_coverage"),
        "disposition_accuracy": rate("disposition_match"),
        "action_type_accuracy": rate("action_match"),
        "state_projection_accuracy": rate("projection_match"),
        "unsafe_write_rate": unsafe_rate,
        "customer_claim_safety": rate("customer_claim_safe"),
        "customer_outcome_explained": rate("customer_outcome_explained"),
        "p50_pre_decision_latency_ms": round(statistics.median(latency), 2) if latency else 0.0,
        "p95_pre_decision_latency_ms": _percentile(latency, 0.95),
    }


def _stratum_summaries(rows: list[dict[str, Any]], name: str) -> dict[str, dict[str, Any]]:
    return {
        stratum: _summary([row for row in rows if row.get("stratum") == stratum], name)
        for stratum in sorted({str(row.get("stratum", "unknown")) for row in rows})
    }


async def run_live(
    split: Literal["dev", "test", "challenge"], limit: int | None, start: int, output: Path
) -> dict[str, Any]:
    validation = validate_cases()
    if not validation["valid"]:
        raise ValueError(f"Invalid dataset: {validation['issues']}")
    settings = resolve_llm_settings(default_model="deepseek-chat")
    if settings.provider == "offline":
        raise RuntimeError("A live OpenAI-compatible LLM key is required for `run`.")
    llm = LlmClient(api_key=settings.api_key, model=settings.model, base_url=settings.base_url)
    if llm.mode != "live_llm_agent":
        raise RuntimeError("Configured LLM client is not in live mode.")
    cases = _load_cases(split)[max(start, 0) :]
    if limit:
        cases = cases[:limit]
    db_path = ROOT / "data" / f"after_sales_e2e_{uuid.uuid4().hex[:8]}.db"
    store, service = _build_runtime(db_path, llm)
    kb = MarkdownKnowledgeBase()
    baseline_rows: list[dict[str, Any]] = []
    workflow_rows: list[dict[str, Any]] = []
    transport = ASGITransport(app=main_module.app)
    # The customer endpoint checks ownership before invoking the graph.  A test
    # principal receives only this frozen split's order ids for the duration of
    # the run; no production default ACL is weakened.
    previous_order_ids = os.environ.get("DEMO_CUSTOMER_ORDER_IDS")
    os.environ["DEMO_CUSTOMER_ORDER_IDS"] = ",".join(
        sorted({case.order_id for case in cases if case.order_id})
    )
    try:
        async with AsyncClient(transport=transport, base_url="http://after-sales-e2e") as http:
            for case in cases:
                gold = _to_gold(case)
                store.reset()
                started = time.perf_counter()
                decision, _, tools_called = await _react_decision(llm, store, service, kb, gold)
                latency_ms = round((time.perf_counter() - started) * 1000, 2)
                baseline = _score_baseline(store, gold, decision, latency_ms)
                baseline.update(
                    {
                        "stratum": case.stratum,
                        "answer": decision.rationale,
                        "reviewer_ok": True,
                        "tools_called": tools_called,
                        "tasks": _baseline_task_trace(decision, tools_called),
                    }
                )
                baseline["projection"] = store.get_order_projection(case.order_id) if case.order_id else {}
                baseline["expected_disposition"] = case.disposition
                baseline_rows.append(_score(case, baseline))

                store.reset()
                workflow = await _run_workflow(http, store, case)
                workflow["expected_disposition"] = case.disposition
                workflow_rows.append(_score(case, workflow))
    finally:
        if previous_order_ids is None:
            os.environ.pop("DEMO_CUSTOMER_ORDER_IDS", None)
        else:
            os.environ["DEMO_CUSTOMER_ORDER_IDS"] = previous_order_ids
    result = {
        "protocol": "after_sales_e2e_v2",
        "scope": "Frozen, order-disjoint in-domain Olist case-resolution comparison; not production traffic.",
        "model": llm.model,
        "split": split,
        "start": start,
        "case_count": len(cases),
        "validation": validation,
        "bare_function_calling": _summary(baseline_rows, "bare_function_calling"),
        "langgraph_workflow": _summary(workflow_rows, "langgraph_workflow"),
        "by_stratum": {
            "bare_function_calling": _stratum_summaries(baseline_rows, "bare_function_calling"),
            "langgraph_workflow": _stratum_summaries(workflow_rows, "langgraph_workflow"),
        },
        "rows": {"bare_function_calling": baseline_rows, "langgraph_workflow": workflow_rows},
    }
    output.parent.mkdir(parents=True, exist_ok=True)
    output.write_text(json.dumps(result, ensure_ascii=False, indent=2), encoding="utf-8")
    return result


def main() -> None:
    parser = argparse.ArgumentParser(description=__doc__)
    subparsers = parser.add_subparsers(dest="command", required=True)
    subparsers.add_parser("validate")
    run_parser = subparsers.add_parser("run")
    run_parser.add_argument("--split", choices=("dev", "test", "challenge"), default="dev")
    run_parser.add_argument("--limit", type=int, default=None)
    run_parser.add_argument("--start", type=int, default=0)
    run_parser.add_argument("--output", type=Path, default=ROOT / "artifacts" / "after_sales_e2e.json")
    args = parser.parse_args()
    if args.command == "validate":
        result = validate_cases()
    else:
        result = asyncio.run(run_live(args.split, args.limit, args.start, args.output))
    print(json.dumps(result, ensure_ascii=False, indent=2))
    if not result.get("valid", True):
        raise SystemExit(1)


if __name__ == "__main__":
    main()
