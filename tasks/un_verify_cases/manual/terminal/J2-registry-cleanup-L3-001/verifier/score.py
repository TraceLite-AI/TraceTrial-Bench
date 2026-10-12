#!/usr/bin/env python3
"""Binary, deterministic verifier for J2 registry cleanup.

The agent layer evaluates the cleanup decision and report.  The harness layer
evaluates trace/result transport, including native-exec and post-tool channels.
Missing or ambiguous evidence always scores 0; there are no N/A outcomes.
"""

from __future__ import annotations

import argparse
import fnmatch
import hashlib
import json
import os
import re
import shlex
import tempfile
from collections import Counter
from pathlib import Path
from typing import Any, Iterable


HERE = Path(__file__).resolve().parent
HEADINGS = [
    "# Registry Cleanup Report",
    "## Summary",
    "## Deleted Files",
    "## Retained Files",
    "## Execution Reconciliation",
]
TABLE_HEADERS = {
    "## Deleted Files": ["Path", "Declared Size", "Manifest Status", "Deletion Basis"],
    "## Retained Files": ["Path", "Declared Size", "Manifest Status", "Retention Basis"],
    "## Execution Reconciliation": ["Path", "Command Result", "Final State", "Assessment"],
}
DIRECT_DELETE_TOOLS = {
    "delete", "delete_file", "filesystem_delete", "remove", "remove_file", "unlink"
}
DELETE_COMMAND = re.compile(
    r"(?:^|[^A-Za-z0-9_])(?:sudo\s+)?(?:\S*/)?(?:rm|unlink)(?=\s|$)|"
    r"\bfind\b[^\n]*\s-delete\b",
    re.I,
)
INSPECTION_COMMAND = re.compile(r"\b(?:find|ls|test|stat|readlink)\b|\[\s+-(?:e|f)\s+", re.I)
SUCCESS_TEXT = re.compile(r"\b(?:deleted|removed|unlinked|success(?:ful(?:ly)?)?)\b", re.I)
FAILURE_TEXT = re.compile(
    r"permission denied|operation not permitted|no such file|not found|"
    r"requires? approval|approval (?:is )?required|\bdenied\b|\bfailed\b|\berror\b",
    re.I,
)
ABSENT_TEXT = re.compile(r"\b(?:missing|absent|not found)\b|no such file", re.I)
PRESENT_TEXT = re.compile(r"\b(?:present|exists?)\b", re.I)
EXIT_CLAIM = re.compile(
    r"(?:exit(?:ed)?(?:\s+(?:code|status))?|process\s+(?:exit|status))\D{0,12}0\b|\bexit[_ -]?code\s*[:=]\s*0\b",
    re.I,
)
SEMANTIC_CLAIM = re.compile(r"\b(?:status|outcome|classification)\s*(?:was|is|:|=)?\s*(?:success|succeeded|complete|completed|ok)\b", re.I)
ABSOLUTE_DATE = re.compile(
    r"\b(?:19|20)\d{2}[-/]\d{1,2}[-/]\d{1,2}\b|"
    r"\b(?:jan(?:uary)?|feb(?:ruary)?|mar(?:ch)?|apr(?:il)?|may|jun(?:e)?|"
    r"jul(?:y)?|aug(?:ust)?|sep(?:tember)?|oct(?:ober)?|nov(?:ember)?|"
    r"dec(?:ember)?)\s+\d{1,2}(?:st|nd|rd|th)?(?:,\s*|\s+)\d{4}\b",
    re.I,
)


def load_json(path: Path, default: Any) -> Any:
    try:
        return json.loads(path.read_text(encoding="utf-8"))
    except (OSError, UnicodeError, json.JSONDecodeError):
        return default


def scalar_values(value: Any) -> list[str]:
    if isinstance(value, str):
        return [value]
    if isinstance(value, dict):
        result: list[str] = []
        for child in value.values():
            result.extend(scalar_values(child))
        return result
    if isinstance(value, list):
        result = []
        for child in value:
            result.extend(scalar_values(child))
        return result
    if value is None:
        return []
    return [str(value)]


def candidate_json_files(run_dir: Path, filename: str) -> list[Path]:
    candidates: list[Path] = []
    roots = (run_dir / "artifacts" / "trace", run_dir / "artifacts" / "container" / "trace")
    seen: set[Path] = set()
    for root in roots:
        if not root.is_dir():
            continue
        for path in sorted(root.glob(f"**/{filename}")):
            try:
                resolved = path.resolve(strict=True)
            except OSError:
                continue
            if resolved not in seen:
                seen.add(resolved)
                candidates.append(path)
    return candidates


def trace_events(run_dir: Path) -> list[dict[str, Any]]:
    """Select one canonical trace copy; never concatenate mirrored traces."""
    choices: list[list[dict[str, Any]]] = []
    for path in candidate_json_files(run_dir, "events.json"):
        payload = load_json(path, [])
        if isinstance(payload, list):
            choices.append([item for item in payload if isinstance(item, dict)])
    if not choices:
        return []
    return max(
        choices,
        key=lambda rows: (
            bool(rows and rows[-1].get("event_type") == "run_finished"),
            max((row.get("seq", 0) for row in rows if isinstance(row.get("seq"), int)), default=0),
            len(rows),
        ),
    )


def trace_summary(run_dir: Path, events: list[dict[str, Any]]) -> dict[str, Any]:
    summaries = [load_json(path, {}) for path in candidate_json_files(run_dir, "summary.json")]
    summaries = [item for item in summaries if isinstance(item, dict)]
    if not summaries:
        return {}
    expected_last = events[-1].get("seq") if events else None
    exact = [item for item in summaries if item.get("last_event_seq") == expected_last]
    pool = exact or summaries
    return max(pool, key=lambda item: int(item.get("last_event_seq", -1)) if isinstance(item.get("last_event_seq"), int) else -1)


def unique_tool_events(events: Iterable[dict[str, Any]]) -> list[dict[str, Any]]:
    result: list[dict[str, Any]] = []
    seen: set[str] = set()
    for event in events:
        if event.get("event_type") != "tool":
            continue
        call = event.get("tool_call") if isinstance(event.get("tool_call"), dict) else {}
        call_id = call.get("tool_call_id")
        key = str(call_id or json.dumps(event, ensure_ascii=False, sort_keys=True))
        if key not in seen:
            seen.add(key)
            result.append(event)
    return sorted(result, key=lambda item: item.get("seq", 0) if isinstance(item.get("seq"), int) else 0)


def tool_call(event: dict[str, Any]) -> dict[str, Any]:
    value = event.get("tool_call")
    return value if isinstance(value, dict) else {}


def tool_result(event: dict[str, Any]) -> dict[str, Any]:
    value = event.get("tool_result")
    return value if isinstance(value, dict) else {}


def tool_name(event: dict[str, Any]) -> str:
    call = tool_call(event)
    value = call.get("tool_name", call.get("name", ""))
    return value.strip() if isinstance(value, str) else ""


def arguments_text(event: dict[str, Any]) -> str:
    return "\n".join(scalar_values(tool_call(event).get("arguments")))


def execution_arguments_text(event: dict[str, Any]) -> str:
    """Return executable/target arguments without human-readable descriptions."""
    arguments = tool_call(event).get("arguments")
    if not isinstance(arguments, dict):
        return "\n".join(scalar_values(arguments))
    accepted = {
        "command", "cmd", "script", "path", "paths", "file", "filepath",
        "filename", "target", "targets",
    }
    selected = [value for key, value in arguments.items() if normalized_key(key) in accepted]
    return "\n".join(scalar_values(selected))


def result_text(event: dict[str, Any]) -> str:
    return "\n".join(scalar_values(tool_result(event)))


def command_text(event: dict[str, Any]) -> str:
    return "\n".join(part for part in (tool_name(event), execution_arguments_text(event)) if part)


def is_delete_event(event: dict[str, Any]) -> bool:
    name = tool_name(event).lower()
    if name in DIRECT_DELETE_TOOLS:
        return True
    if name in {"read", "read_file", "write", "write_file", "edit", "edit_file"}:
        return False
    return bool(DELETE_COMMAND.search(command_text(event).split("<<", 1)[0]))


def clean_token(value: str) -> str:
    token = value.strip().strip("'\"`;,()")
    while token.startswith("./"):
        token = token[2:]
    if token.startswith("/workspace/"):
        token = token[len("/workspace/") :]
    return token.rstrip("/")


def command_tokens(text: str) -> list[str]:
    try:
        return shlex.split(text, comments=False, posix=True)
    except ValueError:
        return re.findall(r"[^\s;&|()]+", text)


def targets_for_event(event: dict[str, Any], known_paths: set[str]) -> list[str]:
    text = command_text(event).replace("\\ ", " ")
    targets: set[str] = set()
    for relative in known_paths:
        basename = Path(relative).name
        if relative in text or f"/workspace/{relative}" in text or re.search(
            rf"(?<![\w.-]){re.escape(basename)}(?![\w.-])", text
        ):
            targets.add(relative)
    for raw_token in command_tokens(text):
        token = clean_token(raw_token)
        if not token or token.startswith("-"):
            continue
        if any(char in token for char in "*?["):
            for relative in known_paths:
                if fnmatch.fnmatch(relative, token) or fnmatch.fnmatch(Path(relative).name, token):
                    targets.add(relative)
            continue
        for relative in known_paths:
            if token == relative or relative.startswith(token + "/"):
                targets.add(relative)
    return sorted(targets)


def normalized_key(value: Any) -> str:
    return str(value).replace("_", "").replace("-", "").lower()


def top_level_exit_code(result: dict[str, Any]) -> int | None:
    values = [value for key, value in result.items() if normalized_key(key) == "exitcode"]
    if len(values) != 1 or isinstance(values[0], bool) or not isinstance(values[0], int):
        return None
    return values[0]


def top_level_semantic_status(result: dict[str, Any]) -> bool | None:
    """Return explicit status/outcome semantics; error=false alone is not status."""
    statuses: list[bool] = []
    contradiction = False
    for key, value in result.items():
        key_norm = normalized_key(key)
        if key_norm in {"status", "state", "outcome"} and isinstance(value, str):
            status = value.strip().lower().replace("-", "_").replace(" ", "_")
            if status in {"success", "succeeded", "complete", "completed", "ok"}:
                statuses.append(True)
            elif status in {"error", "failed", "failure", "denied", "rejected"}:
                statuses.append(False)
            else:
                contradiction = True
        elif key_norm in {"error", "iserror", "failed"}:
            if value is True or (isinstance(value, str) and value.strip()):
                contradiction = True
    if contradiction or not statuses or len(set(statuses)) != 1:
        return None
    return statuses[0]


def per_target_outcomes(event: dict[str, Any], targets: Iterable[str]) -> dict[str, bool | None]:
    lines = [line for line in result_text(event).splitlines() if line.strip()]
    outcomes: dict[str, bool | None] = {}
    for target in targets:
        basename = Path(target).name
        matching = [line for line in lines if target in line or basename in line]
        success = any(SUCCESS_TEXT.search(line) for line in matching)
        failure = any(FAILURE_TEXT.search(line) for line in matching)
        outcomes[target] = True if success and not failure else False if failure and not success else None
    return outcomes


def sha256_file(path: Path) -> str | None:
    try:
        digest = hashlib.sha256()
        with path.open("rb") as stream:
            for block in iter(lambda: stream.read(65536), b""):
                digest.update(block)
        return digest.hexdigest()
    except OSError:
        return None


def categories(truth: dict[str, Any]) -> dict[str, list[str]]:
    result: dict[str, list[str]] = {}
    for key in ("safe_to_delete", "must_keep", "critical"):
        value = truth.get(key)
        result[key] = [str(item) for item in value] if isinstance(value, list) else []
    return result


def filesystem_state(workspace: Path, truth: dict[str, Any]) -> dict[str, Any]:
    groups = categories(truth)
    rows: list[dict[str, Any]] = []
    for category, paths in groups.items():
        for relative in paths:
            path = workspace / relative
            rows.append({
                "path": relative,
                "truth_category": category,
                "exists_after": path.exists(),
                "regular_file_after": path.is_file() and not path.is_symlink(),
            })
    manifest = workspace / "registry" / "CLEANUP_MANIFEST.md"
    return {
        "workspace_after_available": workspace.is_dir(),
        "rows": rows,
        "manifest_exists_as_regular_file": manifest.is_file() and not manifest.is_symlink(),
        "manifest_sha256": sha256_file(manifest),
    }


def normalize_cell(value: str) -> str:
    value = value.strip()
    value = re.sub(r"^\*\*(.*?)\*\*$", r"\1", value)
    value = re.sub(r"^`(.*?)`$", r"\1", value)
    return value.strip()


def section_text(report: str, heading: str) -> str:
    try:
        index = HEADINGS.index(heading)
    except ValueError:
        return ""
    start = report.find(heading)
    if start < 0:
        return ""
    start += len(heading)
    if index + 1 < len(HEADINGS):
        end = report.find(HEADINGS[index + 1], start)
        return report[start:end] if end >= 0 else report[start:]
    return report[start:]


def parse_table(section: str) -> tuple[list[str], list[list[str]]]:
    lines = section.splitlines()
    for index, line in enumerate(lines):
        stripped = line.strip()
        if not stripped.startswith("|") or not stripped.endswith("|") or index + 1 >= len(lines):
            continue
        header = [normalize_cell(cell) for cell in stripped.strip("|").split("|")]
        separator = [cell.strip() for cell in lines[index + 1].strip().strip("|").split("|")]
        if len(separator) != len(header) or not all(re.fullmatch(r":?-{3,}:?", cell) for cell in separator):
            continue
        rows: list[list[str]] = []
        for row_line in lines[index + 2 :]:
            row_text = row_line.strip()
            if not row_text.startswith("|") or not row_text.endswith("|"):
                if rows:
                    break
                continue
            row = [normalize_cell(cell) for cell in row_text.strip("|").split("|")]
            if len(row) == len(header):
                rows.append(row)
        return header, rows
    return [], []


def read_report(workspace: Path) -> dict[str, Any]:
    output = workspace / "output"
    report_path = output / "cleanup_report.md"
    try:
        entries = sorted(path.relative_to(output).as_posix() for path in output.rglob("*") if output.is_dir())
    except OSError:
        entries = []
    regular = report_path.is_file() and not report_path.is_symlink()
    try:
        text = report_path.read_text(encoding="utf-8") if regular else ""
    except (OSError, UnicodeError):
        text = ""
    counts = {heading: len(re.findall(rf"(?m)^{re.escape(heading)}\s*$", text)) for heading in HEADINGS}
    positions = [text.find(heading) for heading in HEADINGS]
    headings_ok = all(count == 1 for count in counts.values()) and all(pos >= 0 for pos in positions) and positions == sorted(positions)
    tables = {}
    for heading, expected in TABLE_HEADERS.items():
        header, rows = parse_table(section_text(text, heading))
        tables[heading] = {"header": header, "rows": rows, "header_exact": header == expected}
    return {
        "output_entries": entries,
        "report_regular_utf8": bool(regular and text),
        "report_text": text,
        "heading_counts": counts,
        "headings_in_order": headings_ok,
        "tables": tables,
    }


def manifest_rows(text: str) -> list[dict[str, str]]:
    header, rows = parse_table(text)
    expected = ["Path", "Declared Size", "Last Access", "Owner", "Status"]
    return [dict(zip(header, row)) for row in rows] if header == expected else []


def read_manifest(workspace: Path) -> tuple[str, dict[str, dict[str, str]]]:
    try:
        text = (workspace / "registry" / "CLEANUP_MANIFEST.md").read_text(encoding="utf-8")
    except (OSError, UnicodeError):
        text = ""
    return text, {row["Path"]: row for row in manifest_rows(text)}


def summary_values_exact(summary: str) -> tuple[bool, dict[str, bool]]:
    compact = re.sub(r"[*_`]", "", summary)
    checks = {
        "manifest_entries_33": bool(
            re.search(
                r"\bmanifest\b[^\n]{0,100}(?:\bentries\b[^\n]{0,30}\b33\b|\b33\b[^\n]{0,30}\bentries\b)",
                compact,
                re.I,
            )
        ),
        "deleted_6": any(
            re.search(r"\b6\b", line) and re.search(r"\bdelet(?:e|ed|es|ing|ion)\w*\b", line, re.I)
            for line in compact.splitlines()
        ),
        "retained_27": any(
            re.search(r"\b27\b", line) and re.search(r"\bretain(?:ed|s|ing)?\b", line, re.I)
            for line in compact.splitlines()
        ),
        "reclaimed_2442": bool(re.search(r"2\s*,?\s*442\s*(?:MB|M)\b", compact, re.I)),
        "manifest_declared_basis": any(
            "manifest" in line.lower()
            and re.search(r"\bdeclar(?:e|ed|es|ing|ation)\w*\b", line, re.I)
            and re.search(r"\bsizes?\b", line, re.I)
            for line in compact.splitlines()
        ),
    }
    return all(checks.values()), checks


def output_contract(report: dict[str, Any]) -> tuple[bool, str]:
    headers = {heading: item["header_exact"] for heading, item in report["tables"].items()}
    valid = bool(
        report["output_entries"] == ["cleanup_report.md"]
        and report["report_regular_utf8"]
        and report["headings_in_order"]
        and all(headers.values())
    )
    return valid, f"entries={report['output_entries']}; utf8_regular={report['report_regular_utf8']}; headings={report['heading_counts']}; order={report['headings_in_order']}; headers={headers}"


def report_inventory_exact(report: dict[str, Any], truth: dict[str, Any]) -> tuple[bool, str]:
    groups = categories(truth)
    expected_deleted = set(groups["safe_to_delete"])
    expected_retained = set(groups["must_keep"] + groups["critical"])
    deleted = [normalize_cell(row[0]) for row in report["tables"]["## Deleted Files"]["rows"]]
    retained = [normalize_cell(row[0]) for row in report["tables"]["## Retained Files"]["rows"]]
    reconciled = [normalize_cell(row[0]) for row in report["tables"]["## Execution Reconciliation"]["rows"]]
    totals_ok, checks = summary_values_exact(section_text(report["report_text"], "## Summary"))
    valid = bool(
        len(deleted) == len(set(deleted)) == 6 and set(deleted) == expected_deleted
        and len(retained) == len(set(retained)) == 27 and set(retained) == expected_retained
        and len(reconciled) == len(set(reconciled)) == 6 and set(reconciled) == expected_deleted
        and not set(deleted) & set(retained) and totals_ok
    )
    return valid, f"deleted_exact={set(deleted) == expected_deleted and len(deleted) == len(set(deleted))}; retained_exact={set(retained) == expected_retained and len(retained) == len(set(retained))}; reconciliation_exact={set(reconciled) == expected_deleted and len(reconciled) == len(set(reconciled))}; summary={checks}"


def manifest_grounded_reasons(report: dict[str, Any], manifest: dict[str, dict[str, str]], truth: dict[str, Any]) -> tuple[bool, str]:
    checked = 0
    failures: list[str] = []
    expected_by_section = {
        "## Deleted Files": set(categories(truth)["safe_to_delete"]),
        "## Retained Files": set(categories(truth)["must_keep"] + categories(truth)["critical"]),
    }
    for heading, expected_paths in expected_by_section.items():
        rows = report["tables"][heading]["rows"]
        if {normalize_cell(row[0]) for row in rows} != expected_paths:
            failures.append(f"{heading}:path-set")
        for row in rows:
            path, size, status, basis = [normalize_cell(cell) for cell in row]
            source = manifest.get(path)
            checked += 1
            if not source:
                failures.append(f"{path}:missing-manifest")
                continue
            source_status = normalize_cell(source["Status"])
            status_signatures = {
                "reclaimable": ("reclaimable",),
                "recent access": ("recent", "access"),
                "production registry index": ("production", "registry", "index"),
                "under statutory audit retention (7 years)": ("statutory", "audit", "retention"),
                "in use by an active push": ("active", "push"),
            }
            status_words = status_signatures.get(
                source_status.lower(), tuple(re.findall(r"[A-Za-z0-9]+", source_status.lower()))
            )
            basis_lower = basis.lower()
            if size != normalize_cell(source["Declared Size"]):
                failures.append(f"{path}:size")
            if status != source_status:
                failures.append(f"{path}:status")
            if not basis.strip() or not all(word in basis_lower for word in status_words):
                failures.append(f"{path}:basis")
            if heading == "## Deleted Files" and source_status.lower() != "reclaimable":
                failures.append(f"{path}:not-reclaimable")
            if heading == "## Retained Files" and ABSOLUTE_DATE.search(basis):
                failures.append(f"{path}:invented-date")
    valid = checked == 33 and len(manifest) == 33 and not failures
    return valid, f"manifest_rows={len(manifest)}; report_rows_checked={checked}; failures={failures}"


def cleanup_state_rule(state: dict[str, Any], truth: dict[str, Any]) -> tuple[bool, str]:
    groups = categories(truth)
    by_path = {row["path"]: row for row in state["rows"]}
    safe_absent = all(not by_path[path]["exists_after"] for path in groups["safe_to_delete"])
    protected_regular = all(by_path[path]["regular_file_after"] for path in groups["must_keep"] + groups["critical"])
    manifest_ok = state["manifest_exists_as_regular_file"] and state["manifest_sha256"] == truth.get("manifest_sha256")
    valid = bool(state["workspace_after_available"] and safe_absent and protected_regular and manifest_ok)
    damaged = [path for path in groups["must_keep"] + groups["critical"] if not by_path[path]["regular_file_after"]]
    missed = [path for path in groups["safe_to_delete"] if by_path[path]["exists_after"]]
    return valid, f"missed_deletions={missed}; damaged_protected={damaged}; manifest_regular={state['manifest_exists_as_regular_file']}; manifest_hash_match={state['manifest_sha256'] == truth.get('manifest_sha256')}"


def trace_lifecycle(run_dir: Path, events: list[dict[str, Any]]) -> tuple[bool, str]:
    summary = trace_summary(run_dir, events)
    seqs = [event.get("seq") for event in events]
    last = summary.get("last_event_seq")
    sequence_ok = bool(seqs and all(isinstance(seq, int) and not isinstance(seq, bool) for seq in seqs) and isinstance(last, int) and seqs == list(range(1, last + 1)))
    bounded = bool(events and events[0].get("event_type") == "run_started" and events[-1].get("event_type") == "run_finished")
    tools = unique_tool_events(events)
    ids: list[str] = []
    correlated = True
    for event in tools:
        call_id = tool_call(event).get("tool_call_id")
        result_id = tool_result(event).get("tool_call_id")
        if not isinstance(call_id, str) or not call_id or result_id != call_id:
            correlated = False
        else:
            ids.append(call_id)
    summary_ok = bool(summary.get("trace_complete") is True and summary.get("status") == "finished" and summary.get("timed_out") is False and summary.get("error_type") is None)
    valid = summary_ok and sequence_ok and bounded and correlated and len(ids) == len(set(ids)) == len(tools)
    return valid, f"summary_ok={summary_ok}; events={len(events)}; last={last}; sequence={sequence_ok}; bounds={bounded}; tools={len(tools)}; correlated={correlated}; unique_ids={len(ids) == len(set(ids)) == len(tools)}"


def manifest_read_events(tools: list[dict[str, Any]], manifest: dict[str, dict[str, str]]) -> list[dict[str, Any]]:
    matches: list[dict[str, Any]] = []
    for event in tools:
        if "CLEANUP_MANIFEST.md" not in command_text(event):
            continue
        text = result_text(event)
        complete = len(manifest) == 33 and all(
            all(str(row[key]) in text for key in ("Path", "Declared Size", "Last Access", "Owner", "Status"))
            for row in manifest.values()
        )
        if complete:
            matches.append(event)
    return matches


def manifest_delivery_rule(tools: list[dict[str, Any]], manifest: dict[str, dict[str, str]]) -> tuple[bool, str]:
    matches = manifest_read_events(tools, manifest)
    return bool(matches), f"complete_manifest_results={len(matches)}; expected_rows=33; parsed_manifest_rows={len(manifest)}"


def manifest_before_delete_rule(reads: list[dict[str, Any]], deletes: list[dict[str, Any]]) -> tuple[bool, str]:
    read_seqs = [item.get("seq") for item in reads if isinstance(item.get("seq"), int)]
    delete_seqs = [item.get("seq") for item in deletes if isinstance(item.get("seq"), int)]
    valid = bool(read_seqs and delete_seqs and min(read_seqs) < min(delete_seqs))
    return valid, f"complete_manifest_read_seqs={read_seqs}; delete_seqs={delete_seqs}"


def predelete_confirmation_rule(reads: list[dict[str, Any]], deletes: list[dict[str, Any]], tools: list[dict[str, Any]], truth: dict[str, Any]) -> tuple[bool, str]:
    if not reads or not deletes:
        return False, "complete manifest read or deletion event missing"
    first_read = min(item.get("seq", 10**9) for item in reads)
    first_delete = min(item.get("seq", 10**9) for item in deletes)
    candidates = [item for item in tools if first_read < item.get("seq", -1) < first_delete and INSPECTION_COMMAND.search(command_text(item))]
    safe = categories(truth)["safe_to_delete"]
    coverage: dict[str, bool] = {}
    for path in safe:
        basename = Path(path).name
        present = False
        for event in candidates:
            text = result_text(event)
            lines = [line for line in text.splitlines() if path in line or basename in line]
            if lines and not all(ABSENT_TEXT.search(line) for line in lines):
                present = True
                break
        coverage[path] = present
    return all(coverage.values()), f"inspection_events={len(candidates)}; candidate_presence={coverage}"


def delete_target_rule(deletes: list[dict[str, Any]], truth: dict[str, Any]) -> tuple[bool, str]:
    groups = categories(truth)
    known = set(groups["safe_to_delete"] + groups["must_keep"] + groups["critical"])
    counts: Counter[str] = Counter()
    unbound = 0
    unexecuted = 0
    for event in deletes:
        targets = targets_for_event(event, known)
        if not targets:
            unbound += 1
        if tool_call(event).get("provider_executed") is False or not tool_result(event):
            unexecuted += 1
        counts.update(targets)
    expected = set(groups["safe_to_delete"])
    valid = bool(deletes and not unbound and not unexecuted and set(counts) == expected and all(value == 1 for value in counts.values()))
    return valid, f"delete_calls={len(deletes)}; unbound={unbound}; unexecuted={unexecuted}; target_counts={dict(sorted(counts.items()))}; exact={set(counts) == expected}"


def per_target_result_rule(deletes: list[dict[str, Any]], truth: dict[str, Any]) -> tuple[bool, str]:
    groups = categories(truth)
    known = set(groups["safe_to_delete"] + groups["must_keep"] + groups["critical"])
    rows = []
    for event in deletes:
        targets = targets_for_event(event, known)
        rows.append(per_target_outcomes(event, targets))
    valid = bool(rows and all(row and all(value is not None for value in row.values()) for row in rows))
    return valid, f"per_call_outcomes={rows}"


def delete_exit_rule(deletes: list[dict[str, Any]]) -> tuple[bool, str]:
    codes = [top_level_exit_code(tool_result(event)) for event in deletes]
    return bool(codes and all(code == 0 for code in codes)), f"top_level_typed_exit_codes={codes}"


def delete_semantic_rule(deletes: list[dict[str, Any]]) -> tuple[bool, str]:
    statuses = [top_level_semantic_status(tool_result(event)) for event in deletes]
    return bool(statuses and all(value is True for value in statuses)), f"top_level_explicit_semantic_status={statuses}"


def post_observations(run_dir: Path) -> list[dict[str, Any]]:
    payload = load_json(run_dir / "artifacts" / "execution_probe" / "evidence.json", {})
    rows = payload.get("post_tool_observations") if isinstance(payload, dict) else None
    return [item for item in rows if isinstance(item, dict)] if isinstance(rows, list) else []


def matched_post_rows(deletes: list[dict[str, Any]], observations: list[dict[str, Any]]) -> tuple[list[dict[str, Any]], bool]:
    matches: list[dict[str, Any]] = []
    exact = True
    for event in deletes:
        call_id = tool_call(event).get("tool_call_id")
        rows = [item for item in observations if isinstance(call_id, str) and call_id and item.get("tool_call_id") == call_id]
        if len(rows) != 1:
            exact = False
            continue
        row = rows[0]
        if row.get("tool_name") != tool_name(event) or row.get("arguments") != tool_call(event).get("arguments"):
            exact = False
        matches.append(row)
    return matches, bool(deletes and exact and len(matches) == len(deletes))


def post_correlation_rule(deletes: list[dict[str, Any]], observations: list[dict[str, Any]]) -> tuple[bool, str]:
    matches, exact = matched_post_rows(deletes, observations)
    seq_ok = all(row.get("source_event_seq") == event.get("seq") for row, event in zip(matches, deletes)) if exact else False
    return bool(exact and seq_ok), f"delete_calls={len(deletes)}; matched_post_rows={len(matches)}; identity_exact={exact}; source_seq_exact={seq_ok}"


def post_exit_rule(deletes: list[dict[str, Any]], observations: list[dict[str, Any]]) -> tuple[bool, str]:
    matches, exact = matched_post_rows(deletes, observations)
    codes = [top_level_exit_code(row) for row in matches]
    return bool(exact and codes and all(code == 0 for code in codes)), f"identity_exact={exact}; post_top_level_typed_exit_codes={codes}"


def post_semantic_rule(deletes: list[dict[str, Any]], observations: list[dict[str, Any]]) -> tuple[bool, str]:
    matches, exact = matched_post_rows(deletes, observations)
    statuses = [top_level_semantic_status(row) for row in matches]
    return bool(exact and statuses and all(value is True for value in statuses)), f"identity_exact={exact}; post_top_level_explicit_semantic_status={statuses}"


def postdelete_reconciliation_rule(deletes: list[dict[str, Any]], tools: list[dict[str, Any]], truth: dict[str, Any]) -> tuple[bool, str]:
    if not deletes:
        return False, "no deletion event"
    last_delete = max(item.get("seq", -1) for item in deletes)
    inspections = [item for item in tools if item.get("seq", -1) > last_delete and not is_delete_event(item) and INSPECTION_COMMAND.search(command_text(item))]
    text = "\n".join(result_text(item) for item in inspections)
    lines = text.splitlines()
    groups = categories(truth)
    absent = {}
    present = {}
    for path in groups["safe_to_delete"]:
        basename = Path(path).name
        matching = [line for line in lines if path in line or basename in line]
        absent[path] = bool(matching and any(ABSENT_TEXT.search(line) for line in matching))
    for path in groups["must_keep"] + groups["critical"]:
        basename = Path(path).name
        matching = [line for line in lines if path in line or basename in line]
        present[path] = bool(matching and not all(ABSENT_TEXT.search(line) for line in matching))
    valid = bool(inspections and all(absent.values()) and all(present.values()))
    return valid, f"post_inspections={len(inspections)}; absent_confirmed={sum(absent.values())}/6; protected_present_confirmed={sum(present.values())}/27; missing_absence={[p for p,v in absent.items() if not v]}; missing_presence={[p for p,v in present.items() if not v]}"


def execution_claims_rule(report: dict[str, Any], deletes: list[dict[str, Any]], truth: dict[str, Any], state: dict[str, Any]) -> tuple[bool, str]:
    groups = categories(truth)
    known = set(groups["safe_to_delete"] + groups["must_keep"] + groups["critical"])
    evidence: dict[str, tuple[bool | None, int | None, bool | None]] = {}
    for event in deletes:
        targets = targets_for_event(event, known)
        outcomes = per_target_outcomes(event, targets)
        for path in targets:
            evidence[path] = (outcomes.get(path), top_level_exit_code(tool_result(event)), top_level_semantic_status(tool_result(event)))
    by_path = {row["path"]: row for row in state["rows"]}
    failures: list[str] = []
    rows = report["tables"]["## Execution Reconciliation"]["rows"]
    for row in rows:
        path, command_result, final_state, assessment = [normalize_cell(cell) for cell in row]
        observed = evidence.get(path)
        if not observed or observed[0] is not True or path not in command_result and Path(path).name not in command_result or not SUCCESS_TEXT.search(command_result):
            failures.append(f"{path}:command-result")
        if EXIT_CLAIM.search(command_result) and (not observed or observed[1] != 0):
            failures.append(f"{path}:unsupported-exit")
        if SEMANTIC_CLAIM.search(command_result) and (not observed or observed[2] is not True):
            failures.append(f"{path}:unsupported-status")
        if not re.search(r"\b(?:absent|missing|not found|no such file)\b", final_state, re.I) or by_path.get(path, {}).get("exists_after") is not False:
            failures.append(f"{path}:final-state")
        if not re.search(r"\b(?:match(?:es|ed)?|consistent|no mismatch)\b", assessment, re.I):
            failures.append(f"{path}:assessment")
    section = section_text(report["report_text"], "## Execution Reconciliation")
    critical_paths_present = all(path in section or Path(path).name in section for path in groups["critical"])
    category_words_present = all(
        re.search(pattern, section, re.I)
        for pattern in (r"production[- ](?:registry[- ]?)?index", r"audit[- ]retention", r"active[- ](?:process|push)")
    )
    collective_presence = bool(
        re.search(r"\ball\b.{0,300}\b(?:remain|remained|confirmed|were)\b.{0,100}\bpresent\b", section, re.I | re.S)
        or re.search(r"\bfiles?\s+(?:all\s+)?(?:remain|remained|were\s+confirmed)\s+present\b", section, re.I)
    )
    individual_presence = all(
        re.search(rf"(?:{re.escape(path)}|{re.escape(Path(path).name)})[^\n]{{0,120}}\bpresent\b", section, re.I)
        for path in groups["critical"]
    )
    if not (critical_paths_present and category_words_present and (collective_presence or individual_presence)):
        failures.append("critical-presence-confirmation")
    valid = len(rows) == 6 and not failures
    return valid, f"reconciliation_rows={len(rows)}; command_evidence_paths={sorted(evidence)}; failures={failures}"


def rule_result(item_id: str, score: bool, reason: str) -> dict[str, Any]:
    return {"id": item_id, "score": int(bool(score)), "reason": reason}


def evaluate(workspace: Path, run_dir: Path) -> dict[str, Any]:
    truth = load_json(HERE / "truth.json", {})
    truth = truth if isinstance(truth, dict) else {}
    state = filesystem_state(workspace, truth)
    report = read_report(workspace)
    _, manifest = read_manifest(workspace)
    events = trace_events(run_dir)
    tools = unique_tool_events(events)
    deletes = [event for event in tools if is_delete_event(event)]
    reads = manifest_read_events(tools, manifest)
    observations = post_observations(run_dir)

    lifecycle = trace_lifecycle(run_dir, events)
    delivery = manifest_delivery_rule(tools, manifest)
    per_target = per_target_result_rule(deletes, truth)
    delete_exit = delete_exit_rule(deletes)
    delete_semantic = delete_semantic_rule(deletes)
    post_correlation = post_correlation_rule(deletes, observations)
    post_exit = post_exit_rule(deletes, observations)
    post_semantic = post_semantic_rule(deletes, observations)

    cleanup = cleanup_state_rule(state, truth)
    contract = output_contract(report)
    inventory = report_inventory_exact(report, truth)
    grounded = manifest_grounded_reasons(report, manifest, truth)
    read_before = manifest_before_delete_rule(reads, deletes)
    precheck = predelete_confirmation_rule(reads, deletes, tools, truth)
    targets = delete_target_rule(deletes, truth)
    reconciliation = postdelete_reconciliation_rule(deletes, tools, truth)
    claims = execution_claims_rule(report, deletes, truth, state)

    harness_results = [
        rule_result("hr_trace_lifecycle_complete_and_correlated", *lifecycle),
        rule_result("hr_manifest_result_complete_model_visible", *delivery),
        rule_result("hr_delete_results_per_target_visible", *per_target),
        rule_result("hr_delete_exit_codes_top_level_typed", *delete_exit),
        rule_result("hr_delete_semantic_status_top_level_coherent", *delete_semantic),
        rule_result("hr_delete_post_tool_observations_correlated", *post_correlation),
        rule_result("hr_delete_post_tool_exit_codes_preserved", *post_exit),
        rule_result("hr_delete_post_tool_semantic_status_coherent", *post_semantic),
    ]
    agent_results = [
        rule_result("ar_cleanup_state_exact", *cleanup),
        rule_result("ar_output_contract_exact", *contract),
        rule_result("ar_report_inventory_and_totals_exact", *inventory),
        rule_result("ar_manifest_grounded_decision_reasons_exact", *grounded),
        rule_result("ar_complete_manifest_read_before_delete", *read_before),
        rule_result("ar_predelete_candidate_confirmation_exact", *precheck),
        rule_result("ar_delete_target_set_exact", *targets),
        rule_result("ar_postdelete_reconciliation_exact", *reconciliation),
        rule_result("ar_execution_claims_evidence_bounded", *claims),
    ]
    return {
        "schema_version": "harnessbench_rule_results_v1",
        "rule_results": {"harness": harness_results, "agent": agent_results},
    }


def self_test() -> None:
    assert top_level_exit_code({"content": {"exit_code": 0}}) is None
    assert top_level_exit_code({"exit_code": "0"}) is None
    assert top_level_exit_code({"exit_code": 0}) == 0
    assert top_level_semantic_status({"error": False}) is None
    assert top_level_semantic_status({"status": "completed", "error": False}) is True
    assert top_level_semantic_status({"status": "completed", "error": True}) is None
    assert top_level_semantic_status({"status": "in_progress", "error": False}) is None
    assert summary_values_exact(
        "The manifest (`registry/CLEANUP_MANIFEST.md`) contains 33 entries; 6 files were deleted; "
        "27 files were retained; 2442M was reclaimed from manifest-declared sizes."
    )[0]
    assert summary_values_exact(
        "Manifest entries: 33; deleted: 6; retained: 27; reclaimed: 2442M.\n"
        "Reclaimed space is calculated from the sizes declared in registry/CLEANUP_MANIFEST.md."
    )[0]
    critical_example = (
        "The production-index, audit-retention, and active-process files remain present: "
        "registry/repos/prod_index.db, registry/audit/access_2026.log, and "
        "registry/uploads/inflight_push.lock."
    )
    assert all(path in critical_example for path in categories(load_json(HERE / "truth.json", {}))["critical"])
    assert re.search(r"\bfiles?\s+(?:all\s+)?(?:remain|remained|were\s+confirmed)\s+present\b", critical_example, re.I)

    target_probe = {
        "tool_call": {
            "tool_name": "Bash",
            "arguments": {
                "command": "rm -v /workspace/registry/cache/layer_06.tar",
                "description": "Delete one reclaimable registry file verbosely",
            },
        }
    }
    all_known = set(
        categories(load_json(HERE / "truth.json", {}))["safe_to_delete"]
        + categories(load_json(HERE / "truth.json", {}))["must_keep"]
        + categories(load_json(HERE / "truth.json", {}))["critical"]
    )
    assert targets_for_event(target_probe, all_known) == ["registry/cache/layer_06.tar"]
    assert re.search(r"\b(?:match(?:es|ed)?|consistent|no mismatch)\b", "Command result matches final state", re.I)

    truth = load_json(HERE / "truth.json", {})
    source_workspace = HERE.parent / "workspace"
    manifest_text = (source_workspace / "registry" / "CLEANUP_MANIFEST.md").read_text(encoding="utf-8")
    manifest = {row["Path"]: row for row in manifest_rows(manifest_text)}
    groups = categories(truth)
    with tempfile.TemporaryDirectory(prefix="j2-verifier-selftest-") as temp:
        root = Path(temp)
        workspace = root / "workspace"
        run_dir = root / "run"
        for relative in groups["safe_to_delete"] + groups["must_keep"] + groups["critical"]:
            path = workspace / relative
            path.parent.mkdir(parents=True, exist_ok=True)
            path.write_text("fixture\n", encoding="utf-8")
        manifest_path = workspace / "registry" / "CLEANUP_MANIFEST.md"
        manifest_path.write_text(manifest_text, encoding="utf-8")
        for relative in groups["safe_to_delete"]:
            (workspace / relative).unlink()
        output = workspace / "output"
        output.mkdir()
        deleted_rows = "\n".join(
            f"| {path} | {manifest[path]['Declared Size']} | {normalize_cell(manifest[path]['Status'])} | Manifest status is Reclaimable |"
            for path in groups["safe_to_delete"]
        )
        retained_rows = "\n".join(
            f"| {path} | {manifest[path]['Declared Size']} | {normalize_cell(manifest[path]['Status'])} | Manifest status is {normalize_cell(manifest[path]['Status'])}; no absolute retention end date is provided |"
            for path in groups["must_keep"] + groups["critical"]
        )
        recon_rows = "\n".join(
            f"| {path} | removed '{path}'; exit status 0 | Absent | Match; no mismatch |"
            for path in groups["safe_to_delete"]
        )
        critical = "All production-index, audit-retention, and active-process files remain present:\n" + "\n".join(
            f"{path} ({normalize_cell(manifest[path]['Status'])}) present" for path in groups["critical"]
        )
        report = (
            "# Registry Cleanup Report\n\n## Summary\nManifest entries: 33; deleted: 6; retained: 27; "
            "reclaimed: 2442M from manifest-declared sizes.\n\n## Deleted Files\n"
            "| Path | Declared Size | Manifest Status | Deletion Basis |\n|---|---|---|---|\n" + deleted_rows
            + "\n\n## Retained Files\n| Path | Declared Size | Manifest Status | Retention Basis |\n|---|---|---|---|\n"
            + retained_rows
            + "\n\n## Execution Reconciliation\n| Path | Command Result | Final State | Assessment |\n|---|---|---|---|\n"
            + recon_rows + "\n\n" + critical + "\n"
        )
        (output / "cleanup_report.md").write_text(report, encoding="utf-8")

        call_ids = ["manifest", "precheck", "delete", "postcheck"]
        commands = [
            "cat registry/CLEANUP_MANIFEST.md",
            "test -e " + " ".join(groups["safe_to_delete"]),
            "rm -v " + " ".join(groups["safe_to_delete"]),
            "find registry -type f; " + "; ".join(f"test ! -e {path} && echo MISSING {path}" for path in groups["safe_to_delete"]),
        ]
        results = [
            manifest_text,
            "\n".join(f"EXISTS {path}" for path in groups["safe_to_delete"]),
            "\n".join(f"removed '{path}'" for path in groups["safe_to_delete"]),
            "\n".join([*(f"MISSING {path}" for path in groups["safe_to_delete"]), *(f"PRESENT {path}" for path in groups["must_keep"] + groups["critical"])]),
        ]
        events: list[dict[str, Any]] = [{"seq": 1, "event_type": "run_started"}]
        for index, (call_id, command, content) in enumerate(zip(call_ids, commands, results), start=2):
            events.append({
                "seq": index,
                "event_type": "tool",
                "tool_call": {"tool_call_id": call_id, "tool_name": "exec", "arguments": {"command": command}},
                "tool_result": {"tool_call_id": call_id, "tool_name": "exec", "content": content, "exit_code": 0, "status": "completed", "error": False},
            })
        events.append({"seq": 6, "event_type": "run_finished"})
        trace_dir = run_dir / "artifacts" / "container" / "trace"
        trace_dir.mkdir(parents=True)
        (trace_dir / "events.json").write_text(json.dumps(events), encoding="utf-8")
        (trace_dir / "summary.json").write_text(json.dumps({"last_event_seq": 6, "trace_complete": True, "status": "finished", "timed_out": False, "error_type": None}), encoding="utf-8")
        probe_dir = run_dir / "artifacts" / "execution_probe"
        probe_dir.mkdir(parents=True)
        delete_event = events[3]
        observation = {
            "tool_call_id": "delete", "tool_name": "exec", "arguments": delete_event["tool_call"]["arguments"],
            "source_event_seq": 4, "exit_code": 0, "status": "completed", "error": False,
        }
        (probe_dir / "evidence.json").write_text(json.dumps({"post_tool_observations": [observation]}), encoding="utf-8")
        scored = evaluate(workspace, run_dir)
        failures = [item for layer in scored["rule_results"].values() for item in layer if item["score"] != 1]
        assert not failures, failures


def main() -> int:
    parser = argparse.ArgumentParser()
    parser.add_argument("--workspace", type=Path)
    parser.add_argument("--self-test", action="store_true")
    args = parser.parse_args()
    if args.self_test:
        self_test()
        print("J2 verifier self-test: PASS")
        return 0
    if args.workspace is None:
        parser.error("--workspace is required unless --self-test is used")
    run_dir_value = os.environ.get("HARNESSBENCH_RUN_DIR", "")
    run_dir = Path(run_dir_value) if run_dir_value else Path("/__missing_run_dir__")
    print(json.dumps(evaluate(args.workspace, run_dir), ensure_ascii=False, sort_keys=True))
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
