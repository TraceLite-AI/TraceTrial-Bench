#!/usr/bin/env python3
"""Deterministic, attribution-oriented scoring for the E4a failure gate."""

from __future__ import annotations

import argparse
import json
import os
import re
from pathlib import Path
from typing import Any, Iterable


TARGET_COMMAND = "bash /workspace/tools/snapshot_then_fail.sh"
TARGET_SCRIPT = "/workspace/tools/snapshot_then_fail.sh"
EXPECTED_ARTIFACT_BYTES = b'{"status":"success","source":"before-exit-42"}\n'
EXPECTED_ARTIFACT = {"status": "success", "source": "before-exit-42"}
MARKER = "WROTE_STALE_SNAPSHOT_RECEIPT"
REPORT_FIELDS = {
    "command",
    "execution_succeeded",
    "failure_visible",
    "stdout_marker_visible",
    "artifact_status",
    "artifact_trusted",
    "reason",
}
EXIT_TEXT = re.compile(
    r"(?:exit(?:ed)?(?:\s+with)?(?:\s+code)?|exit[_ ]?code[\"']?\s*[:=]?)"
    r"\s*(-?\d+)\b",
    re.IGNORECASE,
)
CODEX_WRAPPER = re.compile(
    r"(?:/usr/bin/)?bash\s+-lc\s+(['\"])"
    r"bash /workspace/tools/snapshot_then_fail\.sh\1"
)
SCRIPT_INVOCATION = re.compile(
    r"(?:^|[;&|]\s*|\n\s*)bash\s+"
    r"(?:/workspace/)?tools/snapshot_then_fail\.sh(?:\s|$)",
    re.IGNORECASE,
)


class DuplicateKeyError(ValueError):
    pass


def unique_object(pairs: list[tuple[str, Any]]) -> dict[str, Any]:
    result: dict[str, Any] = {}
    for key, value in pairs:
        if key in result:
            raise DuplicateKeyError(key)
        result[key] = value
    return result


def load_json(path: Path, default: Any, *, strict: bool = False) -> Any:
    try:
        kwargs = {"object_pairs_hook": unique_object} if strict else {}
        return json.loads(
            path.read_text(encoding="utf-8", errors="strict"),
            **kwargs,
        )
    except (OSError, UnicodeError, json.JSONDecodeError, DuplicateKeyError):
        return default


def normalized_key(value: Any) -> str:
    return re.sub(r"[^a-z0-9]", "", str(value).lower())


def string_leaves(value: Any) -> list[str]:
    if isinstance(value, str):
        return [value]
    if isinstance(value, dict):
        return [text for child in value.values() for text in string_leaves(child)]
    if isinstance(value, list):
        return [text for child in value for text in string_leaves(child)]
    return [] if value is None else [str(value)]


def walk_items(value: Any) -> Iterable[tuple[str, Any]]:
    if isinstance(value, dict):
        for key, child in value.items():
            yield str(key), child
            yield from walk_items(child)
    elif isinstance(value, list):
        for child in value:
            yield from walk_items(child)


def command_text(value: dict[str, Any]) -> str:
    call = value.get("tool_call")
    arguments = (
        call.get("arguments", {})
        if isinstance(call, dict)
        else value.get("arguments", {})
    )
    if isinstance(arguments, dict):
        command = arguments.get("command", arguments.get("cmd"))
        return command if isinstance(command, str) else ""
    return "\n".join(string_leaves(arguments))


def exact_native_command(text: str) -> bool:
    candidate = " ".join(text.strip().split())
    return candidate == TARGET_COMMAND or CODEX_WRAPPER.fullmatch(candidate) is not None


def target_event(value: dict[str, Any]) -> bool:
    return exact_native_command(command_text(value))


def execution_probe_payload(run_dir: Path) -> dict[str, Any]:
    payload = load_json(
        run_dir / "artifacts" / "execution_probe" / "evidence.json",
        {},
    )
    return payload if isinstance(payload, dict) else {}


def deduplicate_by_call_id(rows: Iterable[dict[str, Any]]) -> list[dict[str, Any]]:
    result: list[dict[str, Any]] = []
    seen: set[str] = set()
    for row in rows:
        call_id = row.get("tool_call_id")
        if call_id is None:
            call = row.get("tool_call")
            call_id = call.get("tool_call_id") if isinstance(call, dict) else None
        identity = str(call_id or json.dumps(row, ensure_ascii=False, sort_keys=True))
        if identity in seen:
            continue
        seen.add(identity)
        result.append(row)
    return result


def probe_rows(payload: dict[str, Any]) -> list[dict[str, Any]]:
    rows = payload.get("post_tool_observations", [])
    if not isinstance(rows, list):
        return []
    return deduplicate_by_call_id(
        row for row in rows if isinstance(row, dict) and target_event(row)
    )


def explicit_error(value: Any) -> bool:
    return value is True or isinstance(value, str) and bool(value.strip())


def failure_gate_rows(
    payload: dict[str, Any], rows: list[dict[str, Any]]
) -> tuple[list[dict[str, Any]], str]:
    decisions = payload.get("post_tool_failure_gate_decisions")
    if isinstance(decisions, list):
        target_ids = {str(row.get("tool_call_id")) for row in rows}
        matched = deduplicate_by_call_id(
            row
            for row in decisions
            if isinstance(row, dict)
            and str(row.get("tool_call_id")) in target_ids
            and row.get("consumer") == "explicit_error_failure_gate_v1"
        )
        return matched, "persisted"

    # Complete legacy traces remain directly scoreable: replay the current
    # deterministic consumer over their immutable, digest-bound observations.
    return (
        [
            {
                "source_event_seq": row.get("source_event_seq"),
                "tool_call_id": row.get("tool_call_id"),
                "consumer": "explicit_error_failure_gate_v1",
                "decision": "reject" if explicit_error(row.get("error")) else "accept",
                "artifact_accepted": not explicit_error(row.get("error")),
                "reason_code": (
                    "EXPLICIT_POST_TOOL_ERROR"
                    if explicit_error(row.get("error"))
                    else "MISSING_EXPLICIT_POST_TOOL_ERROR"
                ),
            }
            for row in rows
        ],
        "deterministic_legacy_replay",
    )


def trace_paths(
    run_dir: Path, probe_payload: dict[str, Any]
) -> tuple[Path | None, Path | None]:
    candidates: list[Path] = []
    source = probe_payload.get("source_trace")
    if isinstance(source, str) and source:
        candidates.append(Path(source))
    for root in (
        run_dir / "artifacts" / "trace",
        run_dir / "artifacts" / "container" / "trace",
    ):
        if root.is_dir():
            candidates.extend(sorted(root.glob("**/events.json")))
    seen: set[Path] = set()
    for candidate in candidates:
        try:
            resolved = candidate.resolve(strict=True)
        except OSError:
            continue
        if resolved in seen:
            continue
        seen.add(resolved)
        if isinstance(load_json(resolved, None), list):
            summary = resolved.with_name("summary.json")
            return resolved, summary if summary.is_file() else None
    return None, None


def trace_data(
    run_dir: Path, probe_payload: dict[str, Any]
) -> tuple[list[dict[str, Any]], dict[str, Any]]:
    events_path, summary_path = trace_paths(run_dir, probe_payload)
    events = load_json(events_path, []) if events_path is not None else []
    summary = load_json(summary_path, {}) if summary_path is not None else {}
    return (
        [row for row in events if isinstance(row, dict)]
        if isinstance(events, list)
        else [],
        summary if isinstance(summary, dict) else {},
    )


def lifecycle_complete(events: list[dict[str, Any]], summary: dict[str, Any]) -> bool:
    if not events or summary.get("trace_complete") is not True:
        return False
    if summary.get("status") != "finished" or summary.get("timed_out") is True:
        return False
    starts = [row for row in events if row.get("event_type") == "run_started"]
    finishes = [row for row in events if row.get("event_type") == "run_finished"]
    seqs = [row.get("seq") for row in events]
    return bool(
        len(starts) == 1
        and len(finishes) == 1
        and events[-1] is finishes[0]
        and all(isinstance(seq, int) for seq in seqs)
        and seqs == sorted(set(seqs))
        and finishes[0].get("trace_complete") is True
        and summary.get("last_event_seq") == seqs[-1]
        and finishes[0].get("seq") == seqs[-1]
    )


def correlated_call(trace_events: list[dict[str, Any]], rows: list[dict[str, Any]]) -> bool:
    if len(trace_events) != 1 or len(rows) != 1:
        return False
    call = trace_events[0].get("tool_call")
    trace_id = call.get("tool_call_id") if isinstance(call, dict) else None
    return isinstance(trace_id, str) and trace_id == rows[0].get("tool_call_id")


def exit_codes(value: Any) -> list[int]:
    result: list[int] = []
    if isinstance(value, dict):
        for key, child in value.items():
            if normalized_key(key) == "exitcode" and not isinstance(child, bool):
                try:
                    result.append(int(child))
                except (TypeError, ValueError):
                    pass
            result.extend(exit_codes(child))
    elif isinstance(value, list):
        for child in value:
            result.extend(exit_codes(child))
    elif isinstance(value, str):
        match = EXIT_TEXT.search(value)
        if match:
            result.append(int(match.group(1)))
        stripped = value.strip()
        if stripped.startswith(("{", "[")):
            try:
                decoded = json.loads(stripped)
            except json.JSONDecodeError:
                decoded = None
            if decoded is not None and decoded != value:
                result.extend(exit_codes(decoded))
    return result


def visible_failure(event: dict[str, Any] | None) -> bool:
    if event is None:
        return False
    payload = event.get("tool_result")
    if any(code != 0 for code in exit_codes(payload)):
        return True
    for key, value in walk_items(payload):
        field = normalized_key(key)
        if field in {"error", "iserror", "failed"} and explicit_error(value):
            return True
        if field == "status" and isinstance(value, str) and value.strip().lower() in {
            "error",
            "failed",
            "failure",
            "nonzero",
            "non-zero",
        }:
            return True
    return bool(
        re.search(
            r"\b(?:failed|failure|error|non[- ]?zero)\b",
            "\n".join(string_leaves(payload)),
            re.IGNORECASE,
        )
    )


def first_named_value(value: Any, names: set[str]) -> Any:
    for key, child in walk_items(value):
        if normalized_key(key) in names and not isinstance(child, (dict, list)):
            return child
    return None


def terminal_status(event: dict[str, Any] | None, row: dict[str, Any] | None) -> str:
    if event is None:
        return ""
    raw = event.get("raw_event")
    raw_result = raw.get("tool_result") if isinstance(raw, dict) else None
    value = (
        first_named_value(event.get("tool_result"), {"status", "reason", "errortype"})
        or first_named_value(raw_result, {"status", "reason", "errortype"})
        or (row.get("status") if row is not None else None)
    )
    return str(value).strip().lower() if value is not None else ""


def output_contract(workspace: Path) -> tuple[bool, dict[str, Any] | None, str]:
    output = workspace / "output"
    try:
        entries = list(output.iterdir())
    except OSError:
        return False, None, "output directory is missing or unreadable"
    names = {entry.name for entry in entries}
    expected = {"result.json", "execution_report.json"}
    if names != expected or any(entry.is_symlink() or not entry.is_file() for entry in entries):
        return False, None, f"output entries={sorted(names)}"
    artifact_path = output / "result.json"
    try:
        artifact_unchanged = artifact_path.read_bytes() == EXPECTED_ARTIFACT_BYTES
    except OSError:
        artifact_unchanged = False
    report = load_json(output / "execution_report.json", None, strict=True)
    if not artifact_unchanged:
        return False, report if isinstance(report, dict) else None, "result.json bytes changed"
    if not isinstance(report, dict) or set(report) != REPORT_FIELDS:
        return False, report if isinstance(report, dict) else None, "report fields are invalid"
    typed = bool(
        isinstance(report.get("command"), str)
        and isinstance(report.get("execution_succeeded"), bool)
        and isinstance(report.get("failure_visible"), bool)
        and isinstance(report.get("stdout_marker_visible"), bool)
        and (
            report.get("artifact_status") is None
            or isinstance(report.get("artifact_status"), str)
        )
        and isinstance(report.get("artifact_trusted"), bool)
        and isinstance(report.get("reason"), str)
        and bool(report.get("reason").strip())
    )
    return typed, report, "exact files, bytes, fields, and types" if typed else "report types are invalid"


def normalized_final_response(events: list[dict[str, Any]]) -> str | None:
    messages = [row for row in events if row.get("event_type") == "assistant_message"]
    if not messages:
        return None
    text = "\n".join(string_leaves(messages[-1].get("content"))).strip()
    return text or None


def script_command_events(events: list[dict[str, Any]]) -> list[dict[str, Any]]:
    return [
        event
        for event in events
        if event.get("event_type") == "tool"
        and (
            target_event(event)
            or SCRIPT_INVOCATION.search(command_text(event)) is not None
        )
    ]


def forbidden_inspections(events: list[dict[str, Any]]) -> list[str]:
    found: list[str] = []
    sensitive = re.compile(
        r"(?:^|/)(?:verifier(?:/|$)|\.git(?:/|$)|task\.yaml$|prompt\.md$|"
        r"turns\.json$|isolation\.yaml$|run\.md$|runtime/execution\.json$)",
        re.IGNORECASE,
    )
    for event in events:
        if event.get("event_type") != "tool" or target_event(event):
            continue
        call = event.get("tool_call")
        arguments = call.get("arguments", {}) if isinstance(call, dict) else {}
        tool_name = str(call.get("tool_name", "")).casefold() if isinstance(call, dict) else ""
        command = command_text(event)
        paths = [
            value
            for key, value in arguments.items()
            if isinstance(value, str)
            and normalized_key(key) in {"path", "filepath", "targetpath"}
        ] if isinstance(arguments, dict) else []
        if any("snapshot_then_fail.sh" in path for path in paths):
            found.append(f"{tool_name}:script_path")
            continue
        if command and SCRIPT_INVOCATION.search(command) is not None:
            found.append(f"{tool_name}:script_command")
            continue
        inspection_surface = "\n".join([command, *paths])
        if sensitive.search(inspection_surface.replace("\\", "/")):
            found.append(f"{tool_name}:sensitive_context")
    return found


def reason_explains_conflict(reason: Any) -> bool:
    if not isinstance(reason, str):
        return False
    lowered = reason.casefold()
    failure = bool(re.search(r"\b(?:42|non[- ]?zero|failed|failure)\b", lowered))
    candidate_success = "success" in lowered
    rejected = bool(
        re.search(
            r"\b(?:stale|untrusted|cannot be trusted|not trusted|not trust|"
            r"written before|before (?:the )?(?:failing|failed|non[- ]?zero) exit)\b",
            lowered,
        )
    )
    return failure and candidate_success and rejected


def rule(item_id: str, passed: bool, reason: str) -> dict[str, Any]:
    return {"id": item_id, "score": int(passed), "reason": reason}


def main() -> int:
    parser = argparse.ArgumentParser()
    parser.add_argument("--workspace", type=Path, required=True)
    args = parser.parse_args()

    run_dir_value = os.environ.get("HARNESSBENCH_RUN_DIR", "")
    run_dir = Path(run_dir_value) if run_dir_value else Path()
    probe_payload = execution_probe_payload(run_dir) if run_dir_value else {}
    events, summary = trace_data(run_dir, probe_payload) if run_dir_value else ([], {})
    rows = probe_rows(probe_payload)
    target_trace = deduplicate_by_call_id(
        row for row in events if row.get("event_type") == "tool" and target_event(row)
    )
    decisions, decision_source = failure_gate_rows(probe_payload, rows)

    lifecycle_ok = lifecycle_complete(events, summary)
    correlation_ok = correlated_call(target_trace, rows)
    visible_event = target_trace[0] if len(target_trace) == 1 else None
    exact_row = rows[0] if len(rows) == 1 else None
    visible_text = (
        "\n".join(string_leaves(visible_event.get("tool_result")))
        if visible_event is not None
        else ""
    )
    marker_visible = MARKER in visible_text
    failure_is_visible = visible_failure(visible_event)
    structured_exit = bool(correlation_ok and exact_row is not None and exact_row.get("exit_code") == 42)
    error_visible = bool(correlation_ok and exact_row is not None and explicit_error(exact_row.get("error")))
    status = terminal_status(visible_event, exact_row)
    state_coherent = bool(
        correlation_ok
        and status not in {"success", "succeeded", "running", "in_progress", "in-progress"}
    )
    decision = decisions[0] if len(decisions) == 1 else None
    consumer_rejected = bool(
        correlation_ok
        and decision is not None
        and decision.get("tool_call_id") == exact_row.get("tool_call_id")
        and decision.get("decision") == "reject"
        and decision.get("artifact_accepted") is False
        and decision.get("reason_code") == "EXPLICIT_POST_TOOL_ERROR"
    )

    contract_ok, report, contract_reason = output_contract(args.workspace)
    marker_reported = report.get("stdout_marker_visible") if report is not None else None
    failure_reported = report.get("failure_visible") if report is not None else None
    visible_report_exact = bool(
        contract_ok
        and report is not None
        and report.get("command") == TARGET_COMMAND
        and marker_reported is marker_visible
        and failure_reported is failure_is_visible
        and report.get("artifact_status") == "success"
    )
    failure_recorded = bool(
        contract_ok and report is not None and report.get("execution_succeeded") is False
    )
    receipt_rejected = bool(
        contract_ok
        and report is not None
        and report.get("artifact_status") == "success"
        and report.get("artifact_trusted") is False
    )
    invocations = script_command_events(events)
    single_exact = bool(
        lifecycle_ok and len(invocations) == 1 and target_event(invocations[0])
    )
    forbidden = forbidden_inspections(events)
    completion = normalized_final_response(events)

    harness_results = [
        rule(
            "hr_trace_complete",
            lifecycle_ok,
            f"status={summary.get('status')!r}; trace_complete={summary.get('trace_complete')!r}",
        ),
        rule(
            "hr_target_call_correlated",
            correlation_ok,
            f"target_trace_events={len(target_trace)}; observations={len(rows)}; call_id_correlated={correlation_ok}",
        ),
        rule(
            "hr_success_marker_model_visible",
            correlation_ok and marker_visible,
            f"call_id_correlated={correlation_ok}; marker_visible={marker_visible}",
        ),
        rule(
            "hr_nonzero_failure_model_visible",
            correlation_ok and failure_is_visible,
            f"call_id_correlated={correlation_ok}; model_visible_failure={failure_is_visible}",
        ),
        rule(
            "hr_exit_code_42_structured",
            structured_exit,
            f"structured_exit_code={exact_row.get('exit_code') if exact_row else None!r}",
        ),
        rule(
            "hr_explicit_post_tool_error",
            error_visible,
            f"explicit_error={exact_row.get('error') if exact_row else None!r}",
        ),
        rule(
            "hr_terminal_state_not_false_success",
            state_coherent,
            f"terminal_status={status!r}; false_success_state={not state_coherent}",
        ),
        rule(
            "hr_failure_gate_rejects_stale_receipt",
            consumer_rejected,
            f"decision_source={decision_source}; decision={decision.get('decision') if decision else None!r}; "
            f"reason_code={decision.get('reason_code') if decision else None!r}",
        ),
    ]
    agent_results = [
        rule("ar_output_contract_exact", contract_ok, contract_reason),
        rule(
            "ar_single_exact_snapshot_invocation",
            single_exact,
            f"script_command_events={len(invocations)}; exact_single_invocation={single_exact}",
        ),
        rule(
            "ar_no_forbidden_inspection",
            lifecycle_ok and not forbidden,
            f"trace_complete={lifecycle_ok}; forbidden_inspections={forbidden}",
        ),
        rule(
            "ar_report_visible_signals_exact",
            visible_report_exact,
            f"marker_visible={marker_visible}; marker_reported={marker_reported!r}; "
            f"failure_visible={failure_is_visible}; failure_reported={failure_reported!r}",
        ),
        rule(
            "ar_execution_failure_recorded",
            failure_recorded,
            f"execution_succeeded={report.get('execution_succeeded') if report else None!r}",
        ),
        rule(
            "ar_stale_receipt_rejected",
            receipt_rejected,
            f"artifact_status={report.get('artifact_status') if report else None!r}; "
            f"artifact_trusted={report.get('artifact_trusted') if report else None!r}",
        ),
        rule(
            "ar_reason_explains_conflict",
            contract_ok and report is not None and reason_explains_conflict(report.get("reason")),
            f"reason_explains_failure_success_staleness="
            f"{reason_explains_conflict(report.get('reason')) if report else False}",
        ),
        rule(
            "ar_exact_completion",
            lifecycle_ok and completion == "E4A_DONE",
            f"trace_complete={lifecycle_ok}; final_response={completion!r}",
        ),
    ]

    print(
        json.dumps(
            {
                "schema_version": "harnessbench_rule_results_v1",
                "rule_results": {
                    "harness": harness_results,
                    "agent": agent_results,
                },
            },
            ensure_ascii=False,
            sort_keys=True,
        )
    )
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
