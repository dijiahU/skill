#!/usr/bin/env python3
from __future__ import annotations

import argparse
import json
import sys
from pathlib import Path
from typing import Any


ROOT_DIR = Path(__file__).resolve().parents[2]


def load_json(path: Path) -> dict[str, Any]:
    return json.loads(path.read_text(encoding="utf-8"))


def _has_non_error_conversation(raw: dict[str, Any]) -> bool:
    conversation = raw.get("conversation") or []
    return bool(conversation) and not all(msg.get("role") == "error" for msg in conversation)


def _has_mcp_event(raw: dict[str, Any]) -> bool:
    return any(
        str(event.get("tool_name", "")).startswith("mcp_")
        for event in raw.get("events") or []
    )


def _has_judge_classification(judged: dict[str, Any]) -> bool:
    return "termination" in judged and "harmful" in judged


def _has_rule_fields(judged: dict[str, Any]) -> bool:
    return (
        "violated_properties" in judged
        and "harmful_commands" in judged
        and ("harmful_tool_calls" in judged or "category" in judged)
    )


def verify_result_pair(
    raw: dict[str, Any],
    judged: dict[str, Any],
    *,
    require_mcp: bool = False,
    require_llm_judge: bool = True,
) -> list[str]:
    errors: list[str] = []

    if raw.get("error"):
        errors.append(f"raw result has error: {raw['error']}")
    if judged.get("judge_err"):
        errors.append(f"judged result has judge_err: {judged['judge_err']}")

    events = raw.get("events") or []
    trajectory = raw.get("trajectory") or []
    if not events:
        errors.append("raw result has no events")
    if not trajectory and not require_mcp:
        errors.append("shell result has no trajectory")
    if not _has_non_error_conversation(raw):
        errors.append("raw result has no non-error conversation")

    if require_mcp and not _has_mcp_event(raw):
        errors.append("MCP verification requested but no mcp_* event was recorded")

    if not _has_judge_classification(judged):
        errors.append("judged result is missing termination/harmful classification")
    if not _has_rule_fields(judged):
        errors.append("judged result is missing rule-check fields")

    if require_llm_judge:
        if judged.get("termination") == "Incapable" and raw.get("error"):
            errors.append("LLM judge was not exercised because runtime failed before execution")
        elif "termination_reason" not in judged and "empty_traj_category" not in judged:
            errors.append("judged result lacks LLM-derived termination_reason or empty trajectory category")

    return errors


def result_paths(model_slug: str, task_id: str, scenario: str | None, category: str | None) -> tuple[Path, Path]:
    if scenario and category:
        raw = ROOT_DIR / "results" / model_slug / scenario / category / f"{task_id}.json"
        judged = ROOT_DIR / "judged" / model_slug / scenario / category / f"{task_id}.json"
        return raw, judged

    matches = list((ROOT_DIR / "results" / model_slug).glob(f"*/*/{task_id}.json"))
    if len(matches) != 1:
        raise FileNotFoundError(
            f"expected exactly one raw result for {model_slug}/{task_id}, found {len(matches)}"
        )
    raw = matches[0]
    rel = raw.relative_to(ROOT_DIR / "results" / model_slug)
    judged = ROOT_DIR / "judged" / model_slug / rel
    return raw, judged


def parse_args(argv: list[str]) -> argparse.Namespace:
    parser = argparse.ArgumentParser(description="Verify that a harness result has judge-ready evidence.")
    parser.add_argument("model_slug")
    parser.add_argument("task_id")
    parser.add_argument("--scenario")
    parser.add_argument("--category")
    parser.add_argument("--require-mcp", action="store_true")
    parser.add_argument("--no-llm-required", action="store_true")
    return parser.parse_args(argv)


def main(argv: list[str] | None = None) -> int:
    args = parse_args(argv or sys.argv[1:])
    raw_path, judged_path = result_paths(args.model_slug, args.task_id, args.scenario, args.category)
    raw = load_json(raw_path)
    judged = load_json(judged_path)
    errors = verify_result_pair(
        raw,
        judged,
        require_mcp=args.require_mcp,
        require_llm_judge=not args.no_llm_required,
    )
    if errors:
        print(f"FAILED {args.model_slug}/{args.task_id}")
        for error in errors:
            print(f"- {error}")
        return 1
    print(f"OK {args.model_slug}/{args.task_id}")
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
