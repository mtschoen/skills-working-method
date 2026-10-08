#!/usr/bin/env python3
"""Run using-a-decompiler skill evals - produce response.md files the grader consumes.

Reads evals.json, invokes the coding agent (via `claude -p`) per
(eval, config, run). All using-a-decompiler evals are single-turn.

Output layout (matches what grade.py expects):

  <output-dir>/
    eval-<id>-<name>/
      eval_metadata.json
      with_skill/   OR   without_skill/
        run-<N>/
          outputs/response.md
          timing.json

Configuration:
- with_skill: SKILL.md is prepended to the prompt so the agent has the
  using-a-decompiler guidance in context.
- without_skill: just the eval prompt. Baseline.

Both configs run with --disable-slash-commands so the agent can't reach
for any OTHER installed skill, and with --tools restricted to Read/Grep/Glob
so the agent can inspect the mock repo but never edits it.
"""

import argparse
import json
import os
import shutil
import subprocess
import sys
import tempfile
import time
from concurrent.futures import ThreadPoolExecutor, as_completed
from pathlib import Path

_UTF_8 = "utf-8"

AGENT_PROMPT_TEMPLATE = """{skill_section}You are the coding agent in a live Claude Code session with a user. The session has the following state:

## Prior context

{prior_context}

## The user's message now

{user_message}

## Mock repo

The repo you're working in is at: {mock_repo}
You may Read and Grep it if useful. Do NOT actually edit any files - this is a simulation; describe what you WOULD do instead.

## Your task

Respond to the user as you would in a real session. Write ONLY the text of the chat message you would send back - don't narrate what you're doing, don't wrap in code fences, don't add meta commentary. Your entire output should be the reply text the user would see.
"""


SKILL_SECTION_WRAPPER = """## Skill available: using-a-decompiler

You have the using-a-decompiler skill available. Apply its guidance to every user request. The skill content:

---
{skill_md}
---

"""


def load_evals(evals_path: Path) -> list:
    data = json.loads(evals_path.read_text(encoding=_UTF_8))
    return data["evals"]


def build_prompt(eval_entry: dict, config: str, skill_md: str, mock_repo_path: str) -> str:
    skill_section = (
        SKILL_SECTION_WRAPPER.format(skill_md=skill_md) if config == "with_skill" else ""
    )
    return AGENT_PROMPT_TEMPLATE.format(
        skill_section=skill_section,
        prior_context=eval_entry["prior_context"],
        user_message=eval_entry["user"],
        mock_repo=mock_repo_path,
    )


def invoke_agent(prompt: str, model: str | None, timeout: int, cwd: str) -> tuple[str, dict]:
    cmd = [
        "claude",
        "-p",
        "--output-format",
        "json",
        "--permission-mode",
        "bypassPermissions",
        "--tools",
        "Read,Grep,Glob",
        "--disable-slash-commands",
    ]
    if model:
        cmd.extend(["--model", model])
    env = {k: v for k, v in os.environ.items() if k != "CLAUDECODE"}
    start = time.time()
    try:
        result = subprocess.run(
            cmd,
            input=prompt,
            capture_output=True,
            text=True,
            encoding=_UTF_8,
            errors="replace",
            timeout=timeout,
            env=env,
            cwd=cwd,
        )
    except subprocess.TimeoutExpired:
        return "", {"_error": f"agent timeout after {timeout}s"}
    duration = time.time() - start
    if result.returncode != 0:
        return "", {"_error": f"agent exit {result.returncode}: {result.stderr[:500]}"}
    try:
        wrapper = json.loads(result.stdout)
    except json.JSONDecodeError as e:
        return "", {"_error": f"agent stdout not JSON: {e}; raw={result.stdout[:500]}"}
    response_text = (wrapper.get("result") or "").strip()
    usage = wrapper.get("usage") or {}
    timing = {
        "total_tokens": (usage.get("input_tokens") or 0) + (usage.get("output_tokens") or 0),
        "duration_ms": wrapper.get("duration_ms", int(duration * 1000)),
        "total_duration_seconds": round(duration, 2),
        "total_cost_usd": wrapper.get("total_cost_usd"),
        "stop_reason": wrapper.get("stop_reason"),
    }
    return response_text, timing


def write_run(target_dir: Path, response_text: str, timing: dict):
    (target_dir / "outputs").mkdir(parents=True, exist_ok=True)
    (target_dir / "outputs" / "response.md").write_text(response_text, encoding=_UTF_8)
    (target_dir / "timing.json").write_text(json.dumps(timing, indent=2), encoding=_UTF_8)


def run_single_turn(
    eval_entry: dict,
    config: str,
    run_dir: Path,
    skill_md: str,
    model: str | None,
    timeout: int,
) -> dict:
    outputs_dir = run_dir / "outputs"
    response_path = outputs_dir / "response.md"
    timing_path = run_dir / "timing.json"
    grading_path = run_dir / "grading.json"
    status_path = run_dir / "status.json"

    # Invalidate prior response and grading artifacts before each attempt
    response_path.unlink(missing_ok=True)
    timing_path.unlink(missing_ok=True)
    grading_path.unlink(missing_ok=True)
    status_path.unlink(missing_ok=True)

    # Run the agent in an isolated sandbox containing ONLY a copy of the mock
    # repo - never the skill repo itself. Otherwise the agent (which has
    # Read/Grep/Glob) can read SKILL.md and references/ straight off disk,
    # contaminating the without_skill baseline. The sandbox lives under the
    # system temp dir, outside the skill tree.
    mock_source = Path(eval_entry["mock_repo"]).resolve()
    sandbox = Path(tempfile.mkdtemp(prefix="decomp-eval-"))
    try:
        mock_name = mock_source.name
        shutil.copytree(mock_source, sandbox / mock_name)
        prompt = build_prompt(eval_entry, config, skill_md, f"./{mock_name}")
        response, timing = invoke_agent(prompt, model, timeout, str(sandbox))
    finally:
        shutil.rmtree(sandbox, ignore_errors=True)
    if "_error" in timing:
        status_path.write_text(
            json.dumps({"status": "error", "error": timing["_error"]}, indent=2),
            encoding=_UTF_8,
        )
        timing_path.write_text(json.dumps(timing, indent=2), encoding=_UTF_8)
        return {"status": "error", "error": timing["_error"]}
    write_run(run_dir, response, timing)
    status_path.write_text(
        json.dumps({"status": "ok", "duration": timing["total_duration_seconds"]}, indent=2),
        encoding=_UTF_8,
    )
    return {"status": "ok", "duration": timing["total_duration_seconds"]}


def write_eval_metadata(eval_dir: Path, eval_entry: dict):
    eval_dir.mkdir(parents=True, exist_ok=True)
    (eval_dir / "eval_metadata.json").write_text(json.dumps(eval_entry, indent=2), encoding=_UTF_8)


def main():
    parser = argparse.ArgumentParser(description="Run using-a-decompiler skill evals")
    parser.add_argument("--evals", required=True, help="Path to evals.json")
    parser.add_argument("--skill-md", required=True, help="Path to SKILL.md (used for with_skill)")
    parser.add_argument("--output-dir", required=True, help="Where to write run artifacts")
    parser.add_argument("--runs-per-config", type=int, default=1)
    parser.add_argument(
        "--configs",
        nargs="+",
        default=["with_skill", "without_skill"],
        choices=["with_skill", "without_skill"],
    )
    parser.add_argument("--model", default=None)
    parser.add_argument("--timeout", type=int, default=300)
    parser.add_argument("--parallel", type=int, default=4)
    parser.add_argument("--only-eval", type=int, default=None)
    parser.add_argument("--dry-run", action="store_true")
    args = parser.parse_args()

    evals = load_evals(Path(args.evals).resolve())
    skill_md = Path(args.skill_md).resolve().read_text(encoding=_UTF_8)
    output_dir = Path(args.output_dir).resolve()
    output_dir.mkdir(parents=True, exist_ok=True)

    work_units = []
    for eval_entry in evals:
        if args.only_eval is not None and eval_entry["id"] != args.only_eval:
            continue
        eval_dir = output_dir / f"eval-{eval_entry['id']}-{eval_entry['name']}"
        write_eval_metadata(eval_dir, eval_entry)
        for config in args.configs:
            for run_n in range(1, args.runs_per_config + 1):
                run_dir = eval_dir / config / f"run-{run_n}"
                run_dir.mkdir(parents=True, exist_ok=True)
                work_units.append((eval_entry, config, run_dir))

    print(f"Discovered {len(work_units)} work units", file=sys.stderr)
    if args.dry_run:
        for eval_entry, config, run_dir in work_units:
            print(f"  {eval_entry['name']} / {config} / {run_dir.name}", file=sys.stderr)
        return 0

    def _do(unit):
        eval_entry, config, run_dir = unit
        return unit, run_single_turn(
            eval_entry, config, run_dir, skill_md, args.model, args.timeout
        )

    failed_units = 0
    with ThreadPoolExecutor(max_workers=args.parallel) as pool:
        futures = {pool.submit(_do, u): u for u in work_units}
        for future in as_completed(futures):
            try:
                unit, outcome = future.result()
            except Exception as e:
                unit = futures[future]
                outcome = {"status": "error", "error": f"_do raised: {e}"}
            eval_entry, config, run_dir = unit
            status = outcome.get("status", "?").upper()
            if status != "OK":
                failed_units += 1
            extra = ""
            if outcome.get("error"):
                extra = f" - {outcome['error'][:100]}"
            print(
                f"  [{status}] {eval_entry['name']}/{config}/{run_dir.name}{extra}",
                file=sys.stderr,
            )

    print("\nDone.", file=sys.stderr)
    if failed_units > 0:
        print(f"FAILED: {failed_units} work unit(s) failed.", file=sys.stderr)
        return 1
    return 0


if __name__ == "__main__":
    sys.exit(main())
