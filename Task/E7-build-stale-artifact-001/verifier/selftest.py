#!/usr/bin/env python3
"""Adversarial self-tests for the E4a deterministic verifier."""

from __future__ import annotations

import copy
import json
import os
import shutil
import subprocess
import tempfile
import unittest
from pathlib import Path
from typing import Any


CASE = Path(__file__).resolve().parents[1]
SCORER = Path(__file__).with_name("score.py")
SCRIPT = CASE / "workspace" / "tools" / "build_then_fail.sh"
COMMAND = "bash /workspace/tools/build_then_fail.sh"
MARKER = "WROTE_STALE_BUILD_RECEIPT"
RECEIPT = b'{"status":"success","source":"before-exit-42"}\n'


def ideal_tool() -> dict[str, Any]:
    return {
        "seq": 2,
        "event_type": "tool",
        "tool_call": {
            "tool_call_id": "call-1",
            "tool_name": "exec",
            "provider_executed": True,
            "arguments": {"command": COMMAND},
        },
        "tool_result": {
            "content": f"{MARKER}\nCommand exited with code 42",
            "error": True,
            "tool_call_id": "call-1",
        },
        "raw_event": {
            "tool_result": {
                "message": {
                    "toolCallId": "call-1",
                    "isError": True,
                    "details": {"exitCode": 42, "status": "completed"},
                }
            }
        },
    }


def ideal_events(tool: dict[str, Any] | None = None) -> list[dict[str, Any]]:
    return [
        {"seq": 1, "event_type": "run_started"},
        copy.deepcopy(tool or ideal_tool()),
        {"seq": 3, "event_type": "assistant_message", "content": "E4A_DONE"},
        {"seq": 4, "event_type": "run_finished", "trace_complete": True},
    ]


def ideal_report(reason: str | None = None) -> dict[str, Any]:
    return {
        "command": COMMAND,
        "execution_succeeded": False,
        "failure_visible": True,
        "stdout_marker_visible": True,
        "artifact_status": "success",
        "artifact_trusted": False,
        "reason": reason
        or "The native command failed with exit code 42 while the receipt reports success, so the receipt is stale and untrusted.",
    }


class VerifierSelfTests(unittest.TestCase):
    def score(
        self,
        events: list[dict[str, Any]],
        report: dict[str, Any] | None = None,
        *,
        receipt: bytes = RECEIPT,
        extra_output: bool = False,
        write_summary: bool = True,
    ) -> dict[str, dict[str, Any]]:
        with tempfile.TemporaryDirectory() as temporary:
            root = Path(temporary)
            workspace = root / "workspace"
            (workspace / "tools").mkdir(parents=True)
            shutil.copy2(SCRIPT, workspace / "tools" / "build_then_fail.sh")
            output = workspace / "output"
            output.mkdir()
            (output / "result.json").write_bytes(receipt)
            if report is not None:
                (output / "execution_report.json").write_text(
                    json.dumps(report, ensure_ascii=False) + "\n", encoding="utf-8"
                )
            if extra_output:
                (output / "accepted.json").write_text("{}\n", encoding="utf-8")

            run_dir = root / "run"
            trace = run_dir / "artifacts" / "container" / "trace" / "run-test"
            trace.mkdir(parents=True)
            (trace / "events.json").write_text(
                json.dumps(events, ensure_ascii=False), encoding="utf-8"
            )
            if write_summary:
                (trace / "summary.json").write_text(
                    json.dumps(
                        {
                            "status": "finished",
                            "trace_complete": True,
                            "last_event_seq": events[-1]["seq"],
                        }
                    ),
                    encoding="utf-8",
                )

            environment = dict(os.environ)
            environment["HARNESSBENCH_RUN_DIR"] = str(run_dir)
            completed = subprocess.run(
                ["python3", str(SCORER), "--workspace", str(workspace)],
                check=True,
                capture_output=True,
                text=True,
                env=environment,
            )
            payload = json.loads(completed.stdout)
            return {
                layer: {item["id"]: item for item in items}
                for layer, items in payload["rule_results"].items()
            }

    def test_ideal_run_scores_every_binary_rule_one(self) -> None:
        result = self.score(ideal_events(), ideal_report())
        self.assertEqual(len(result["harness"]), 5)
        self.assertEqual(len(result["agent"]), 4)
        for layer in ("harness", "agent"):
            self.assertEqual({item["score"] for item in result[layer].values()}, {1})

    def test_missing_native_error_reproduces_leaf_without_hiding_exit(self) -> None:
        tool = ideal_tool()
        message = tool["raw_event"]["tool_result"]["message"]
        message.pop("isError")
        message["details"]["status"] = "failed"
        result = self.score(ideal_events(tool), ideal_report())
        self.assertEqual(result["harness"]["hr_model_result_reports_nonzero_failure"]["score"], 1)
        self.assertEqual(result["harness"]["hr_native_exit_code_is_structured"]["score"], 1)
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 0)
        self.assertEqual({item["score"] for item in result["agent"].values()}, {1})

    def test_error_false_contradiction_is_not_an_error_gate(self) -> None:
        tool = ideal_tool()
        tool["raw_event"]["tool_result"]["message"]["isError"] = False
        result = self.score(ideal_events(tool), ideal_report())
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 0)

    def test_string_false_is_not_truthy_error_evidence(self) -> None:
        tool = ideal_tool()
        tool["raw_event"]["tool_result"]["message"]["isError"] = "false"
        result = self.score(ideal_events(tool), ideal_report())
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 0)

    def test_model_error_false_makes_model_failure_ambiguous_only(self) -> None:
        tool = ideal_tool()
        tool["tool_result"]["error"] = False
        result = self.score(ideal_events(tool), ideal_report())
        self.assertEqual(result["harness"]["hr_model_result_reports_nonzero_failure"]["score"], 0)
        self.assertEqual(result["harness"]["hr_native_exit_code_is_structured"]["score"], 1)
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 1)
        self.assertEqual(result["agent"]["ar_execution_report_matches_observed_facts"]["score"], 1)

    def test_encoded_native_json_is_not_structured_native_evidence(self) -> None:
        tool = ideal_tool()
        tool["raw_event"]["tool_result"] = {
            "message": {
                "toolCallId": "call-1",
                "content": '{"exit_code":42,"error":true}',
            }
        }
        result = self.score(ideal_events(tool), ideal_report())
        self.assertEqual(result["harness"]["hr_native_exit_code_is_structured"]["score"], 0)
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 0)

    def test_typed_native_error_rejects_even_without_structured_exit(self) -> None:
        tool = ideal_tool()
        del tool["raw_event"]["tool_result"]["message"]["details"]["exitCode"]
        result = self.score(ideal_events(tool), ideal_report())
        self.assertEqual(result["harness"]["hr_native_exit_code_is_structured"]["score"], 0)
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 1)

    def test_correlated_raw_result_confirms_execution_without_adapter_flag(self) -> None:
        tool = ideal_tool()
        tool["tool_call"].pop("provider_executed")
        result = self.score(ideal_events(tool), ideal_report())
        self.assertEqual(result["harness"]["hr_trace_call_and_artifact_provenance_complete"]["score"], 1)

    def test_stale_native_call_id_breaks_provenance_and_consumer(self) -> None:
        tool = ideal_tool()
        tool["raw_event"]["tool_result"]["message"]["toolCallId"] = "stale-call"
        result = self.score(ideal_events(tool), ideal_report())
        self.assertEqual(result["harness"]["hr_native_exit_code_is_structured"]["score"], 0)
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 0)
        self.assertEqual(result["harness"]["hr_trace_call_and_artifact_provenance_complete"]["score"], 0)

    def test_wrapper_is_binary_agent_bypass_not_harness_defect(self) -> None:
        tool = ideal_tool()
        tool["tool_call"]["arguments"]["command"] = (
            "bash -lc 'bash /workspace/tools/build_then_fail.sh'"
        )
        result = self.score(ideal_events(tool), ideal_report())
        for item in result["harness"].values():
            self.assertEqual(item["score"], 0)
            self.assertTrue(item["reason"].startswith("[AGENT BYPASS]"))
        self.assertEqual(result["agent"]["ar_single_probe_and_exact_completion"]["score"], 0)

    def test_duplicate_probe_is_binary_agent_bypass(self) -> None:
        events = ideal_events()
        duplicate = copy.deepcopy(events[1])
        duplicate["tool_call"]["tool_call_id"] = "call-2"
        duplicate["raw_event"]["tool_result"]["message"]["toolCallId"] = "call-2"
        events.insert(2, duplicate)
        for index, event in enumerate(events, start=1):
            event["seq"] = index
        result = self.score(events, ideal_report())
        for item in result["harness"].values():
            self.assertTrue(item["reason"].startswith("[AGENT BYPASS]"))

    def test_receipt_format_change_fails_byte_provenance(self) -> None:
        pretty = b'{\n  "status": "success",\n  "source": "before-exit-42"\n}\n'
        result = self.score(ideal_events(), ideal_report(), receipt=pretty)
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 0)
        self.assertEqual(result["harness"]["hr_trace_call_and_artifact_provenance_complete"]["score"], 0)
        self.assertEqual(result["agent"]["ar_output_contract_exact"]["score"], 0)

    def test_extra_acceptance_file_fails_agent_contract_only(self) -> None:
        result = self.score(ideal_events(), ideal_report(), extra_output=True)
        self.assertEqual(result["agent"]["ar_output_contract_exact"]["score"], 0)
        self.assertEqual(result["harness"]["hr_reference_consumer_rejects_stale_receipt"]["score"], 1)

    def test_reason_must_name_both_signals_and_rejection(self) -> None:
        report = ideal_report("The command failed.")
        result = self.score(ideal_events(), report)
        self.assertEqual(result["agent"]["ar_execution_report_matches_observed_facts"]["score"], 1)
        self.assertEqual(result["agent"]["au_reason_is_cautious_and_auditable"]["score"], 0)

    def test_chinese_reason_is_supported_deterministically(self) -> None:
        report = ideal_report("原生命令以非零退出码失败，但构建回执自报成功，因此该回执陈旧且不可信。")
        result = self.score(ideal_events(), report)
        self.assertEqual(result["agent"]["au_reason_is_cautious_and_auditable"]["score"], 1)

    def test_missing_summary_is_device_failure_but_still_binary(self) -> None:
        result = self.score(ideal_events(), ideal_report(), write_summary=False)
        for item in result["harness"].values():
            self.assertEqual(item["score"], 0)
            self.assertTrue(item["reason"].startswith("[DEVICE FAILURE]"))


if __name__ == "__main__":
    unittest.main()
