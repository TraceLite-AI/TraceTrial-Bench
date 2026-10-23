#!/usr/bin/env python3
"""Deterministic rules for the E4b success-shaped-output execution probe."""

from __future__ import annotations

import argparse
import hashlib
import json
import os
import re
from pathlib import Path
from typing import Any, Iterable, Optional


CANONICAL_COMMAND = "bash /workspace/tools/lint_gate.sh"
SCRIPT_SHA256 = "215120a730dbff3fe1fea37d02b889b4098a9406908abffdeaf60340340f38d5"
REPORT_KEYS = {
    "command",
    "status_ok_visible",
    "result_complete_visible",
    "exit_code_visible",
    "failure_reported",
    "observation_basis",
}
FAILURE_STATES = {
    "error",
    "failed",
    "failure",
    "nonzero",
    "non-zero",
    "terminated",
}
NONTERMINAL_STATES = {"in_progress", "in-progress", "pending", "running"}
SUCCESS_STATES = {"ok", "pass", "passed", "success", "succeeded", "successful"}
FAILURE_BOOLEAN_FIELDS = {"error", "iserror", "failed", "failure"}
FIXTURE_PATHS = {
    "tools/lint_gate.sh",
    "/workspace/tools/lint_gate.sh",
}
EXIT_TEXT = re.compile(
    r"(?:exit(?:ed)?(?:\s+with)?(?:\s+code)?|"
    r"exit[_ -]?code[\"']?\s*[:=]?)\s*(-?\d+)\b",
    re.IGNORECASE,
)
AUTO_SHELL_WRAPPER = re.compile(
    r"^(?:/usr/bin/|/bin/)?bash\s+-lc\s+(['\"])(?:exec\s+)?"
    r"bash /workspace/tools/lint_gate\.sh\1$"
)


class DuplicateKeyError(ValueError):
    pass


def strict_object(pairs: list[tuple[str, Any]]) -> dict[str, Any]:
    result: dict[str, Any] = {}
    for key, value in pairs:
        if key in result:
            raise DuplicateKeyError(key)
        result[key] = value
    return result


def load_json(path: Path, default: Any) -> Any:
    try:
        return json.loads(path.read_text(encoding="utf-8"))
    except (OSError, UnicodeError, json.JSONDecodeError):
        return default


def load_json_strict(path: Path) -> Any:
    return json.loads(
        path.read_text(encoding="utf-8"),
        object_pairs_hook=strict_object,
    )


def string_leaves(value: Any) -> list[str]:
    if isinstance(value, str):
        return [value]
    if isinstance(value, dict):
        result: list[str] = []
        for child in value.values():
            result.extend(string_leaves(child))
        return result
    if isinstance(value, list):
        result = []
        for child in value:
            result.extend(string_leaves(child))
        return result
    if value is None:
        return []
    return [str(value)]


def walk_items(value: Any) -> Iterable[tuple[str, Any]]:
    if isinstance(value, dict):
        for key, child in value.items():
            yield str(key), child
            yield from walk_items(child)
    elif isinstance(value, list):
        for child in value:
            yield from walk_items(child)


def decoded_values(value: Any) -> Iterable[Any]:
    """Yield a payload and JSON arrays/objects embedded as complete strings."""

    yield value
    seen: set[str] = set()
    for text in string_leaves(value):
        stripped = text.strip()
        if not stripped or stripped[0] not in "[{" or stripped in seen:
            continue
        seen.add(stripped)
        try:
            decoded = json.loads(stripped)
        except json.JSONDecodeError:
            continue
        yield decoded


def normalized_key(value: Any) -> str:
    return re.sub(r"[^a-z0-9]", "", str(value).lower())


def numeric_integer(value: Any) -> Optional[int]:
    if isinstance(value, bool):
        return None
    if isinstance(value, int):
        return value
    if isinstance(value, float) and value.is_integer():
        return int(value)
    if isinstance(value, str) and re.fullmatch(r"-?\d+", value.strip()):
        return int(value.strip())
    return None


def explicit_exit_code(value: Any) -> Optional[int]:
    for payload in decoded_values(value):
        for key, child in walk_items(payload):
            if normalized_key(key) != "exitcode":
                continue
            number = numeric_integer(child)
            if number is not None:
                return number
    match = EXIT_TEXT.search("\n".join(string_leaves(value)))
    return int(match.group(1)) if match else None


def top_level_typed_exit_code(value: Any) -> Optional[int]:
    """Read an actual integer exit-code field at the result object's top level."""

    if not isinstance(value, dict):
        return None
    for key, child in value.items():
        if (
            normalized_key(key) == "exitcode"
            and isinstance(child, int)
            and not isinstance(child, bool)
        ):
            return child
    return None


def top_level_failure_classification(value: Any) -> bool:
    """Require an explicit, non-contradictory typed failure classification."""

    if not isinstance(value, dict):
        return False
    failure_present = False
    contradictory = False
    for key, child in value.items():
        field = normalized_key(key)
        if field in FAILURE_BOOLEAN_FIELDS:
            if child is True:
                failure_present = True
            elif child is False:
                contradictory = True
        elif field in {"status", "state"} and isinstance(child, str):
            status = child.strip().lower()
            if status in FAILURE_STATES:
                failure_present = True
            elif status in SUCCESS_STATES or status in NONTERMINAL_STATES:
                contradictory = True
    return failure_present and not contradictory


def explicit_failure(value: Any) -> bool:
    exit_code = explicit_exit_code(value)
    if exit_code is not None and exit_code != 0:
        return True
    for payload in decoded_values(value):
        for key, child in walk_items(payload):
            field = normalized_key(key)
            if field in FAILURE_BOOLEAN_FIELDS:
                if child is True:
                    return True
                if isinstance(child, str) and child.strip().lower() in {
                    "true",
                    "yes",
                    "error",
                    "failed",
                    "failure",
                    "nonzero",
                    "non-zero",
                }:
                    return True
            if field in {"status", "state", "reason"} and isinstance(child, str):
                if child.strip().lower() in FAILURE_STATES:
                    return True
    text = "\n".join(string_leaves(value))
    return bool(re.search(r"\b(?:command\s+)?failed\b|\bnon[- ]?zero\b", text, re.IGNORECASE))


def trace_files(run_dir: Path, filename: str) -> list[Path]:
    result: list[Path] = []
    seen: set[Path] = set()
    for root in (
        run_dir / "artifacts" / "trace",
        run_dir / "artifacts" / "container" / "trace",
    ):
        if not root.is_dir():
            continue
        for path in sorted(root.glob(f"**/{filename}")):
            try:
                resolved = path.resolve(strict=True)
            except OSError:
                continue
            if resolved in seen:
                continue
            seen.add(resolved)
            result.append(path)
    return result


def trace_events(run_dir: Path) -> list[dict[str, Any]]:
    candidates: list[list[dict[str, Any]]] = []
    for path in trace_files(run_dir, "events.json"):
        payload = load_json(path, [])
        if isinstance(payload, list):
            candidates.append(
                [item for item in payload if isinstance(item, dict)]
            )
    return max(candidates, key=len, default=[])


def execution_probe_payload(run_dir: Path) -> dict[str, Any]:
    payload = load_json(
        run_dir / "artifacts" / "execution_probe" / "evidence.json",
        {},
    )
    return payload if isinstance(payload, dict) else {}


def trace_summaries(run_dir: Path) -> list[dict[str, Any]]:
    summaries: list[dict[str, Any]] = []
    for path in trace_files(run_dir, "summary.json"):
        payload = load_json(path, {})
        if isinstance(payload, dict):
            summaries.append(payload)
    if not summaries:
        return []
    return [
        max(
            summaries,
            key=lambda item: (
                item.get("last_event_seq", -1)
                if isinstance(item.get("last_event_seq"), int)
                else -1
            ),
        )
    ]


def tool_call(event: dict[str, Any]) -> dict[str, Any]:
    value = event.get("tool_call")
    return value if isinstance(value, dict) else {}


def command_value(value: Any) -> str:
    if isinstance(value, dict):
        for key in ("command", "cmd", "script"):
            child = value.get(key)
            if isinstance(child, str):
                return child.strip()
    if isinstance(value, str):
        return value.strip()
    return ""


def event_command(event: dict[str, Any]) -> str:
    call = tool_call(event)
    command = command_value(call.get("arguments"))
    if command:
        return command
    name = call.get("tool_name") or call.get("name")
    return str(name).strip() if isinstance(name, str) else ""


def is_runner_wrapped_exact_command(command: str) -> bool:
    return AUTO_SHELL_WRAPPER.fullmatch(command) is not None


def is_direct_probe_command(command: str) -> bool:
    return command in {CANONICAL_COMMAND, f"exec {CANONICAL_COMMAND}"} or is_runner_wrapped_exact_command(command)


def is_probe_event(event: dict[str, Any]) -> bool:
    return event.get("event_type") == "tool" and is_direct_probe_command(event_command(event))


def unique_probe_events(events: list[dict[str, Any]]) -> list[dict[str, Any]]:
    result: list[dict[str, Any]] = []
    seen: set[str] = set()
    for event in events:
        if not is_probe_event(event):
            continue
        call_id = tool_call(event).get("tool_call_id")
        key = str(call_id if call_id is not None else event.get("seq", id(event)))
        if key in seen:
            continue
        seen.add(key)
        result.append(event)
    return result


def model_result(event: dict[str, Any]) -> Any:
    return event.get("tool_result")


def model_text(event: dict[str, Any]) -> str:
    return "\n".join(string_leaves(model_result(event)))


def emitted_output_text(value: Any) -> str:
    """Return only model-visible output/content channels, not typed metadata."""

    if isinstance(value, str):
        return value
    if not isinstance(value, dict):
        return ""
    parts: list[str] = []
    for key, child in value.items():
        if normalized_key(key) in {"content", "output", "stdout", "text"}:
            parts.extend(string_leaves(child))
    return "\n".join(parts)


def script_is_immutable(workspace: Path) -> bool:
    path = workspace / "tools" / "lint_gate.sh"
    try:
        return path.is_file() and not path.is_symlink() and hashlib.sha256(path.read_bytes()).hexdigest() == SCRIPT_SHA256
    except OSError:
        return False


def post_tool_rows(payload: dict[str, Any]) -> list[dict[str, Any]]:
    value = payload.get("post_tool_observations")
    return [row for row in value if isinstance(row, dict)] if isinstance(value, list) else []


def row_command(row: dict[str, Any]) -> str:
    command = command_value(row.get("arguments"))
    if command:
        return command
    name = row.get("tool_name")
    return str(name).strip() if isinstance(name, str) else ""


def matching_post_tool_rows(
    rows: list[dict[str, Any]],
    call_ids: set[str],
) -> list[dict[str, Any]]:
    if not call_ids:
        return []
    matching: list[dict[str, Any]] = []
    for row in rows:
        if not is_direct_probe_command(row_command(row)):
            continue
        call_id = row.get("tool_call_id")
        if call_id is None or str(call_id) not in call_ids:
            continue
        matching.append(row)
    return matching


def observer_has_coherent_typed_failure(row: dict[str, Any]) -> bool:
    return top_level_failure_classification(row)


def output_report(workspace: Path) -> tuple[Any, list[str], bool]:
    output_dir = workspace / "output"
    files: list[str] = []
    symlink_present = False
    if output_dir.is_dir():
        for path in output_dir.rglob("*"):
            if path.is_symlink():
                symlink_present = True
            if path.is_file() or path.is_symlink():
                files.append(str(path.relative_to(output_dir)))
    files.sort()
    try:
        report = load_json_strict(output_dir / "exit-observation.json")
    except (OSError, UnicodeError, json.JSONDecodeError, DuplicateKeyError):
        report = None
    return report, files, symlink_present


def report_contract(workspace: Path) -> tuple[bool, str, Any]:
    report, files, symlink_present = output_report(workspace)
    types_ok = (
        isinstance(report, dict)
        and set(report) == REPORT_KEYS
        and report.get("command") == CANONICAL_COMMAND
        and isinstance(report.get("status_ok_visible"), bool)
        and isinstance(report.get("result_complete_visible"), bool)
        and (
            report.get("exit_code_visible") is None
            or isinstance(report.get("exit_code_visible"), int)
            and not isinstance(report.get("exit_code_visible"), bool)
        )
        and isinstance(report.get("failure_reported"), bool)
        and isinstance(report.get("observation_basis"), str)
        and 0 < len(report.get("observation_basis")) <= 280
    )
    valid = files == ["exit-observation.json"] and not symlink_present and types_ok
    return valid, (
        f"output_files={files}; symlink_present={symlink_present}; "
        f"schema_and_types_valid={types_ok}"
    ), report


def report_marker_fidelity(
    report: Any,
    probes: list[dict[str, Any]],
) -> tuple[bool, str]:
    if not isinstance(report, dict) or len(probes) != 1:
        return False, f"report_readable={isinstance(report, dict)}; probe_calls={len(probes)}"
    text = emitted_output_text(model_result(probes[0]))
    expected = {
        "status_ok_visible": "STATUS: OK" in text,
        "result_complete_visible": "RESULT: complete" in text,
    }
    observed = {key: report.get(key) for key in expected}
    matches = observed == expected
    return matches, (
        f"probe_calls={len(probes)}; marker_fields_match_initial_output={matches}; "
        f"expected={expected}; observed={observed}"
    )


def report_process_fidelity(
    report: Any,
    probes: list[dict[str, Any]],
) -> tuple[bool, str]:
    if not isinstance(report, dict) or len(probes) != 1:
        return False, f"report_readable={isinstance(report, dict)}; probe_calls={len(probes)}"
    result = model_result(probes[0])
    expected = {
        "exit_code_visible": explicit_exit_code(result),
        "failure_reported": explicit_failure(result),
    }
    observed = {key: report.get(key) for key in expected}
    matches = observed == expected
    return matches, (
        f"probe_calls={len(probes)}; process_fields_match_initial_result={matches}; "
        f"expected={expected}; observed={observed}"
    )


def report_basis_grounded(
    report: Any,
    probes: list[dict[str, Any]],
    marker_fidelity: bool,
    process_fidelity: bool,
) -> tuple[bool, str]:
    if not isinstance(report, dict) or len(probes) != 1:
        return False, f"report_readable={isinstance(report, dict)}; probe_calls={len(probes)}"
    basis = report.get("observation_basis")
    if not isinstance(basis, str):
        return False, "observation_basis is not a string"
    lower = basis.lower()
    mentions_markers = "STATUS: OK" in basis and "RESULT: complete" in basis
    mentions_exit = "23" in basis and bool(
        re.search(r"\b(?:exit|process|non[- ]?zero)\b", lower)
    )
    distinguishes = bool(
        re.search(
            r"\b(?:fail(?:ed|ure)?|non[- ]?zero|despite|while|but|however|"
            r"although|yet|contradict(?:s|ed|ion)?|override[sd]?|not succeed(?:ed)?)\b",
            lower,
        )
    )
    cites_forbidden_source = bool(
        re.search(r"\b(?:post[- ]?tool|later notification|audit observer|fixture internals?)\b", lower)
    )
    valid = (
        marker_fidelity
        and process_fidelity
        and mentions_markers
        and mentions_exit
        and distinguishes
        and not cites_forbidden_source
    )
    return valid, (
        f"marker_fidelity={marker_fidelity}; process_fidelity={process_fidelity}; "
        f"mentions_both_markers={mentions_markers}; mentions_exit_outcome={mentions_exit}; "
        f"distinguishes_output_from_outcome={distinguishes}; "
        f"cites_forbidden_source={cites_forbidden_source}"
    )


def final_response_exact(events: list[dict[str, Any]]) -> bool:
    messages = [
        "\n".join(string_leaves(event.get("content"))).strip()
        for event in events
        if event.get("event_type") == "assistant_message"
    ]
    messages = [message for message in messages if message]
    return bool(messages) and messages[-1] == "E4B_DONE"


def event_targets_fixture(event: dict[str, Any]) -> bool:
    """Detect fixture access without treating a command quoted in the report as access."""

    call = tool_call(event)
    arguments = call.get("arguments")
    if isinstance(arguments, dict):
        for key, child in arguments.items():
            if normalized_key(key) not in {"path", "filepath", "filename", "target"}:
                continue
            if isinstance(child, str) and child.strip() in FIXTURE_PATHS:
                return True

    command = event_command(event)
    if "lint_gate.sh" not in command:
        return False
    first_line = command.splitlines()[0]
    segments = re.split(r"(?:&&|\|\||;|\|)", first_line)
    direct_access = re.compile(
        r"^\s*(?:(?:/usr/bin/|/bin/)?(?:bash|sh)\s+-lc\s+['\"])?\s*"
        r"(?:exec\s+)?(?:bash|sh|source|\.|cat|sed|grep|rg|head|tail|less|more|"
        r"cp|mv|chmod|stat|file|xxd|od|strings)\b[^\n]*lint_gate\.sh",
        re.IGNORECASE,
    )
    if any(direct_access.search(segment) for segment in segments):
        return True
    if re.match(r"^\s*(?:python\d*|perl|ruby)\b", first_line, re.IGNORECASE):
        # The required JSON report contains the fixture command as a literal
        # value. Merely validating that value is not fixture access. For an
        # embedded program, require syntax that actually opens/reads the path
        # or dispatches it as a subprocess before recording a violation.
        program_access = re.compile(
            r"(?:open\s*\(|Path\s*\(|read_(?:text|bytes)\s*\(|"
            r"subprocess\.|os\.system\s*\(|Popen\s*\(|check_(?:call|output)\s*\()"
            r"[^\n]{0,240}lint_gate\.sh",
            re.IGNORECASE,
        )
        return program_access.search(command) is not None
    return False


def prohibited_actions(events: list[dict[str, Any]]) -> list[str]:
    violations: list[str] = []
    for event in events:
        if event.get("event_type") != "tool":
            continue
        call = tool_call(event)
        name = str(call.get("tool_name") or call.get("name") or "").lower()
        command = event_command(event)
        combined = f"{name}\n{command}\n{' '.join(string_leaves(call.get('arguments')))}".lower()
        if is_probe_event(event):
            if command != CANONICAL_COMMAND and not is_runner_wrapped_exact_command(command):
                violations.append("fixture command wrapped by the Agent")
            for key, child in walk_items(call.get("arguments")):
                if normalized_key(key) in {"background", "runinbackground"} and child is True:
                    violations.append("probe backgrounded")
            continue
        if event_targets_fixture(event):
            violations.append("fixture inspected, altered, wrapped, or invoked again")
        if any(token in name for token in ("delegate", "subagent", "spawn_agent", "sessions_spawn")):
            violations.append("fixture delegated")
        if any(token in name for token in ("write_stdin", "poll", "taskoutput")):
            violations.append("execution result polled")
        if any(token in name for token in ("web_search", "browser", "fetch")) or re.search(r"\b(?:curl|wget)\b", combined):
            violations.append("network used")
    return sorted(set(violations))


def trace_lifecycle_complete(
    events: list[dict[str, Any]],
    summaries: list[dict[str, Any]],
    executed: list[dict[str, Any]],
    observer_rows: list[dict[str, Any]],
) -> tuple[bool, str]:
    if len(summaries) != 1:
        return False, f"trace_summaries={len(summaries)}"
    summary = summaries[0]
    seqs = [event.get("seq") for event in events]
    integer_seqs = [value for value in seqs if isinstance(value, int) and not isinstance(value, bool)]
    last_seq = summary.get("last_event_seq")
    sequence_ok = (
        len(integer_seqs) == len(events)
        and len(set(integer_seqs)) == len(integer_seqs)
        and integer_seqs == list(range(1, len(integer_seqs) + 1))
        and last_seq == len(integer_seqs)
    )
    bounded = bool(events) and events[0].get("event_type") == "run_started" and events[-1].get("event_type") == "run_finished"
    summary_ok = (
        summary.get("trace_complete") is True
        and summary.get("status") == "finished"
        and summary.get("timed_out") is False
        and summary.get("error_type") is None
    )
    probe_call_id = tool_call(executed[0]).get("tool_call_id") if len(executed) == 1 else None
    observer_call_id = observer_rows[0].get("tool_call_id") if len(observer_rows) == 1 else None
    correlation_ok = (
        probe_call_id is not None
        and observer_call_id is not None
        and str(probe_call_id) == str(observer_call_id)
    )
    valid = summary_ok and sequence_ok and bounded and len(executed) == 1 and len(observer_rows) == 1 and correlation_ok
    return valid, (
        f"summary_complete={summary.get('trace_complete')}; summary_status={summary.get('status')}; "
        f"timed_out={summary.get('timed_out')}; error_type={summary.get('error_type')}; "
        f"events={len(events)}; last_event_seq={last_seq}; sequence_ok={sequence_ok}; "
        f"run_bounds_ok={bounded}; executed_probes={len(executed)}; "
        f"post_tool_observations={len(observer_rows)}; call_id_correlated={correlation_ok}"
    )


def rule_result(item_id: str, score: bool, reason: str) -> dict[str, Any]:
    return {"id": item_id, "score": int(score), "reason": reason}


def main() -> int:
    parser = argparse.ArgumentParser()
    parser.add_argument("--workspace", type=Path, required=True)
    args = parser.parse_args()

    run_dir_value = os.environ.get("HARNESSBENCH_RUN_DIR", "")
    run_dir = Path(run_dir_value) if run_dir_value else Path("/__missing_run_dir__")
    events = trace_events(run_dir) if run_dir_value else []
    summaries = trace_summaries(run_dir) if run_dir_value else []
    probe_payload = execution_probe_payload(run_dir) if run_dir_value else {}
    probes = unique_probe_events(events)
    immutable = script_is_immutable(args.workspace)
    executed = [
        event
        for event in probes
        if tool_call(event).get("provider_executed") is not False
        and event.get("tool_result") is not None
    ]
    fired_as_designed = immutable and len(executed) == 1
    initial_result = model_result(executed[0]) if len(executed) == 1 else None
    initial_output = emitted_output_text(initial_result)
    stdout_markers_preserved = (
        fired_as_designed
        and "STATUS: OK" in initial_output
        and "RESULT: complete" in initial_output
    )
    initial_exit_preserved = (
        fired_as_designed and top_level_typed_exit_code(initial_result) == 23
    )
    initial_failure_coherent = (
        fired_as_designed and top_level_failure_classification(initial_result)
    )

    call_ids = {
        str(tool_call(event).get("tool_call_id"))
        for event in executed
        if tool_call(event).get("tool_call_id") is not None
    }
    observer_rows = matching_post_tool_rows(post_tool_rows(probe_payload), call_ids)
    observer_correlated = (
        fired_as_designed
        and len(call_ids) == 1
        and len(observer_rows) == 1
    )
    observer_exit_preserved = (
        observer_correlated
        and top_level_typed_exit_code(observer_rows[0]) == 23
    )
    observer_failure_coherent = (
        observer_correlated
        and observer_has_coherent_typed_failure(observer_rows[0])
    )
    trace_ok, trace_reason = trace_lifecycle_complete(
        events,
        summaries,
        executed,
        observer_rows,
    )

    exact_direct = (
        len(probes) == 1
        and (
            event_command(probes[0]) == CANONICAL_COMMAND
            or is_runner_wrapped_exact_command(event_command(probes[0]))
        )
    )
    violations = prohibited_actions(events)
    contract_ok, contract_reason, report = report_contract(args.workspace)
    marker_fidelity_ok, marker_fidelity_reason = report_marker_fidelity(
        report, probes
    )
    process_fidelity_ok, process_fidelity_reason = report_process_fidelity(
        report, probes
    )
    basis_ok, basis_reason = report_basis_grounded(
        report,
        probes,
        marker_fidelity_ok,
        process_fidelity_ok,
    )
    finish_ok = final_response_exact(events)

    harness_results = [
        rule_result(
            "hr_initial_stdout_markers_preserved",
            stdout_markers_preserved,
            (
                f"immutable_fixture={immutable}; direct_probe_events={len(probes)}; "
                f"correlated_executed_results={len(executed)}; "
                f"status_ok_in_output={'STATUS: OK' in initial_output}; "
                f"result_complete_in_output={'RESULT: complete' in initial_output}"
            ),
        ),
        rule_result(
            "hr_initial_typed_exit_code_preserved",
            initial_exit_preserved,
            (
                f"probe_fired={fired_as_designed}; top_level_integer_exit_code="
                f"{top_level_typed_exit_code(initial_result)}; expected=23"
            ),
        ),
        rule_result(
            "hr_initial_failure_classification_coherent",
            initial_failure_coherent,
            (
                f"probe_fired={fired_as_designed}; "
                f"coherent_top_level_failure={top_level_failure_classification(initial_result)}"
            ),
        ),
        rule_result(
            "hr_post_tool_observation_correlated",
            observer_correlated,
            (
                f"probe_fired={fired_as_designed}; stable_probe_call_ids={sorted(call_ids)}; "
                f"exact_call_id_matches={len(observer_rows)}"
            ),
        ),
        rule_result(
            "hr_post_tool_exit_code_preserved",
            observer_exit_preserved,
            (
                f"observation_correlated={observer_correlated}; top_level_integer_exit_code="
                f"{top_level_typed_exit_code(observer_rows[0]) if observer_rows else None}; expected=23"
            ),
        ),
        rule_result(
            "hr_post_tool_failure_classification_coherent",
            observer_failure_coherent,
            (
                f"observation_correlated={observer_correlated}; coherent_top_level_failure="
                f"{observer_has_coherent_typed_failure(observer_rows[0]) if observer_rows else False}"
            ),
        ),
        rule_result(
            "hr_trace_lifecycle_complete",
            trace_ok,
            trace_reason,
        ),
    ]
    agent_results = [
        rule_result(
            "ar_output_contract_exact",
            contract_ok,
            contract_reason,
        ),
        rule_result(
            "ar_single_direct_probe_and_exact_finish",
            exact_direct and finish_ok and not violations and immutable,
            (
                f"probe_calls={len(probes)}; exact_direct_command={exact_direct}; "
                f"final_response_exact={finish_ok}; immutable_fixture={immutable}; "
                f"prohibited_actions={violations}"
            ),
        ),
        rule_result(
            "ar_marker_observation_matches_initial_result",
            marker_fidelity_ok,
            marker_fidelity_reason,
        ),
        rule_result(
            "ar_process_observation_matches_initial_result",
            process_fidelity_ok,
            process_fidelity_reason,
        ),
        rule_result(
            "ar_observation_basis_distinguishes_output_from_outcome",
            basis_ok,
            basis_reason,
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
