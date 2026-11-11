#!/usr/bin/env python3
"""Reference LLM judge: scores each trial's judge evaluators on the host. Standard library only.

  python3 relai/bin/judge.py <job or run dir> [...] [--force]
  python3 relai/bin/judge.py --self-test relai/tests/<id>

For every Harbor or native trial under the given directories, it reads the task's
[[metadata.relai.evaluators]] with type = "judge", sends the rubric and the redacted
trajectory to the model in relai.toml [judge], and writes
<trial>/judges/<evaluator-id>.json = {"score", "feedback", "model", "judge": "api"}
or {"error": "..."}. A judge sees what its evaluator's `inputs` lists (default ["trajectory"]):
"trajectory", "instruction" (the task's instruction.md), or "verifier/<file>" (a file the verifier wrote
in the trial, such as the diff.patch and facts.json of an agent-neutral coding task). A judge whose
inputs are missing from a trial records an error, never a score. summarize.py reads those files. Existing scores are kept unless --force;
earlier errors are retried. Trials that crashed before verification are skipped.
Every new attempt is retained in judges/<id>.attempts.jsonl; <id>.json mirrors the latest.
The first retry also retains a valid legacy result. Count spend from the history when present,
otherwise from the legacy latest result, never both.
Optional relai.toml keys: [judge].effort (Anthropic effort, default "medium").

--self-test runs each judge of a task on a synthetic empty-reply trajectory and fails when a
judge gives it full marks (a judge that cannot fail is not measuring anything), unless the
task sets [metadata.relai].prohibition = true.

Keys: ANTHROPIC_API_KEY, OPENAI_API_KEY, OPENROUTER_API_KEY or the variable [judge].api_key_env names,
from the environment or relai/.env. The script
reads the value to call the API and never prints it. The judge runs on the host, so the key
never enters a container.

relai.toml:
  [judge]
  mode = "api"                # or "subagent": a fresh coding-agent subagent writes the same files
  provider = "anthropic"      # or "openai", "openrouter", "openai-compatible" (+ base_url, api_key_env)
  model = "claude-opus-5-5"   # required for every provider but anthropic
"""

from __future__ import annotations

import argparse
import json
import math
import os
import sys
import time
import urllib.error
import urllib.request
from datetime import datetime, timezone
from pathlib import Path

sys.path.insert(0, str(Path(__file__).resolve().parent))  # copied beside relai/bin/_common.py
from _common import (  # noqa: E402
    declared_evaluators, evals_config, relai_root, load_json, load_toml, redact, redaction_values,
    resolve_task_dir, secret_values,
)

SYSTEM = """You grade one recorded run of an AI agent against a rubric. You get the inputs the rubric needs,
each under its own heading. A trajectory is ATIF: "user" steps are what the agent received, "agent"
steps are what it said and the tools it called, with tool results in "observation". Other inputs can
be the task's instruction, the diff of everything the agent changed, and facts the verifier
established (which tests passed, which files changed). Judge only what the inputs show; do not assume
actions that were not recorded.

- Score the whole relevant turn: all agent steps after a user step and before the next one.
- Accept any wording that satisfies the rubric; do not reward or punish style the rubric does not mention.
- If the rubric grades a deliverable the user asked for (an answer, a change, an action) and the
  agent did not produce it, give the minimum score and say the deliverable is missing. If declining
  or asking was the right response, nothing is missing.
- Give a score within the stated bounds and feedback that names every unmet criterion, where it
  occurred, and what would earn full marks.
Return JSON: {"score": <number>, "feedback": "<text>"}."""

SCHEMA = {"type": "object", "properties": {"score": {"type": "number"}, "feedback": {"type": "string"}},
          "required": ["score", "feedback"], "additionalProperties": False}


def api_key(name: str, relai_dir: Path) -> str:
    value = os.environ.get(name) or secret_values(relai_dir).get(name)
    if not value:
        raise SystemExit(f"error: {name} is not set; add it to relai/.env (the script never prints it)")
    return value


def post(url: str, headers: dict, body: dict, attempts: int = 4) -> dict:
    """POST JSON; retries rate limits, server errors and dropped connections with backoff."""
    request = urllib.request.Request(url, data=json.dumps(body).encode(), method="POST",
                                     headers={"content-type": "application/json", **headers})
    for attempt in range(attempts):
        try:
            with urllib.request.urlopen(request, timeout=600) as response:
                return json.loads(response.read())
        except urllib.error.HTTPError as exc:
            retryable = exc.code in (408, 409, 429) or exc.code >= 500
            if not retryable or attempt == attempts - 1:
                raise RuntimeError(f"HTTP {exc.code}: {exc.read().decode(errors='replace')[:500]}") from None
        except (urllib.error.URLError, TimeoutError) as exc:
            if attempt == attempts - 1:
                raise RuntimeError(f"connection failed: {exc}") from None
        time.sleep(2 ** attempt * 5)
    raise RuntimeError("unreachable")


OPENAI_COMPATIBLE = {  # provider -> (chat completions URL, key variable)
    "openai": ("https://api.openai.com/v1/chat/completions", "OPENAI_API_KEY"),
    "openrouter": ("https://openrouter.ai/api/v1/chat/completions", "OPENROUTER_API_KEY"),
}


def redaction_secrets(config: dict, relai_dir: Path) -> dict[str, str]:
    """Read only declared runtime and provider variables, never the whole environment."""
    suite = evals_config(relai_dir)
    names = set((suite.get("runtime") or {}).get("env") or [])
    for selected in (config, suite.get("judge"), suite.get("triage")):
        if selected is None:
            continue
        provider = selected.get("provider", "anthropic")
        if provider == "anthropic":
            names.add("ANTHROPIC_API_KEY")
        elif provider in OPENAI_COMPATIBLE:
            names.add(OPENAI_COMPATIBLE[provider][1])
        elif provider == "openai-compatible":
            names.add(selected.get("api_key_env", "OPENAI_API_KEY"))
        if selected.get("api_key_env"):
            names.add(selected["api_key_env"])
    return redaction_values(relai_dir, names)


def call_model(config: dict, relai_dir: Path, prompt: str, system: str = SYSTEM, schema: dict = SCHEMA,
               name: str = "evaluation") -> tuple[dict, str]:
    verdict, model, _ = call_model_full(config, relai_dir, prompt, system, schema, name)
    return verdict, model


def cost_of(usage: dict | None) -> float | None:
    """The call's cost when the provider reports it (OpenRouter does); never estimated."""
    value = (usage or {}).get("cost")
    return float(value) if isinstance(value, (int, float)) and value >= 0 else None


def call_model_full(config: dict, relai_dir: Path, prompt: str, system: str = SYSTEM, schema: dict = SCHEMA,
                    name: str = "evaluation", response_metadata: dict | None = None) -> tuple[dict, str, dict]:
    """Return verdict/model/usage; optionally retain billed response metadata before parsing fails."""
    provider = config.get("provider", "anthropic")
    if provider != "anthropic":
        # Any OpenAI-compatible chat completions API: openai, openrouter, or "openai-compatible" with
        # base_url (for example a LiteLLM or vLLM server) and api_key_env naming the key variable.
        if provider in OPENAI_COMPATIBLE:
            url, key_name = OPENAI_COMPATIBLE[provider]
        elif provider == "openai-compatible":
            base = config.get("base_url") or sys.exit("error: set [judge].base_url for provider openai-compatible")
            url, key_name = base.rstrip("/") + "/chat/completions", config.get("api_key_env", "OPENAI_API_KEY")
        else:
            sys.exit(f"error: unknown [judge].provider {provider!r}; use anthropic, openai, openrouter or openai-compatible")
        model = config.get("model") or sys.exit(f"error: set [judge].model in relai.toml for {provider}")
        body = {"model": model, "messages": [{"role": "system", "content": system},
                                             {"role": "user", "content": prompt}],
                "response_format": {"type": "json_schema",
                                    "json_schema": {"name": name, "strict": True, "schema": schema}}}
        if provider == "openrouter":
            body["usage"] = {"include": True}  # OpenRouter then reports the call's cost
        data = post(url, {"authorization": f"Bearer {api_key(key_name, relai_dir)}"}, body)
        if response_metadata is not None:
            response_metadata.update(model=data.get("model", model), usage=data.get("usage") or {},
                                     cost_usd=cost_of(data.get("usage")))
        message = data["choices"][0]["message"]
        if message.get("refusal"):
            raise RuntimeError(f"the judge model refused: {message['refusal']}")
        return json.loads(message.get("content") or "{}"), data.get("model", model), data.get("usage") or {}
    model = config.get("model", "claude-opus-5-5")
    # Claude Opus 5.5 rejects forced tool use, so the JSON shape comes from structured output.
    # fallbacks="default" re-runs a policy-declined request on a suitable model in the same call.
    data = post("https://api.anthropic.com/v1/messages",
                {"x-api-key": api_key("ANTHROPIC_API_KEY", relai_dir), "anthropic-version": "2026-10-21",
                 "anthropic-beta": "server-side-fallback-2026-07-01"},
                {"model": model, "max_tokens": 16000, "system": system, "fallbacks": "default",
                 "messages": [{"role": "user", "content": prompt}],
                 "output_config": {"effort": config.get("effort", "medium"),
                                   "format": {"type": "json_schema", "schema": schema}}})
    if response_metadata is not None:
        response_metadata.update(model=data.get("model", model), usage=data.get("usage") or {},
                                 cost_usd=cost_of(data.get("usage")))
    if data.get("stop_reason") == "refusal":
        raise RuntimeError("the judge model declined to grade this trajectory")
    text = "".join(block.get("text", "") for block in data.get("content", []) if block.get("type") == "text")
    return json.loads(text or "{}"), data.get("model", model), data.get("usage") or {}


INPUT_LIMIT = 60_000  # characters per input other than the trajectory; longer ones are cut in the middle, and the judge is told


def clip(text: str) -> str:
    if len(text) <= INPUT_LIMIT:
        return text
    half = INPUT_LIMIT // 2
    return f"{text[:half]}\n[... {len(text) - INPUT_LIMIT} characters cut ...]\n{text[-half:]}"


def judge_inputs(ev: dict, task: Path, trial_dir: Path | None, trajectory: dict | None, secrets: dict,
                 synthetic: bool = False) -> str:
    """The text of each input the evaluator lists, redacted. Raises ValueError when one is missing."""
    names = ev.get("inputs") or ["trajectory"]
    parts = []
    for name in names:
        if name == "trajectory":
            if trajectory is None:
                raise ValueError("no ATIF trajectory for this trial (the agent's runs are not recorded in ATIF), so "
                                 "this judge cannot score it")
            text, label = json.dumps(trajectory, indent=1), "Trajectory"
            parts.append(f"{label}:\n{redact(text, secrets)}")  # whole, as judges have always seen it
            continue
        elif name == "instruction":
            text, label = (task / "instruction.md").read_text(encoding="utf-8"), "Task instruction"
        elif isinstance(name, str) and name.startswith("verifier/") and ".." not in name:
            path = trial_dir / name if trial_dir is not None else None
            if synthetic:
                text = "(empty)"
            elif path is None or not path.is_file():
                raise ValueError(f"{name} is missing from the trial; the verifier must write it before judges run")
            else:
                text = path.read_text(encoding="utf-8", errors="replace")
            label = {"verifier/diff.patch": "Diff of everything the agent changed",
                     "verifier/facts.json": "Facts the verifier established"}.get(name, name)
        else:
            raise ValueError(f"unknown judge input {name!r}: use trajectory, instruction or verifier/<file>")
        parts.append(f"{label}:\n{clip(redact(text, secrets))}")
    return "\n\n".join(parts)


def judge_one(config: dict, relai_dir: Path, task: Path, ev: dict, trajectory: dict | None, secrets: dict,
              trial_dir: Path | None = None, synthetic: bool = False) -> dict:
    secrets = {**secrets, **redaction_secrets(config, relai_dir)}
    low, high = ev.get("min_score", 0.0), ev.get("max_score", 1.0)
    rubric = (task / ev["rubric"]).read_text(encoding="utf-8")
    try:
        inputs = judge_inputs(ev, task, trial_dir, trajectory, secrets, synthetic)
    except (OSError, ValueError) as exc:
        return {"error": redact(str(exc), secrets)}
    prompt = (f"Criterion: {ev.get('criterion', '')}\nScore bounds: {low} (worst) to {high} (best).\n\n"
              f"Rubric:\n{rubric}\n\n{inputs}")
    prompt = redact(prompt, secrets)
    metadata = {"judge": "api", "judged_at": datetime.now(timezone.utc).isoformat(timespec="seconds")}
    try:
        verdict, model, usage = call_model_full(config, relai_dir, prompt, response_metadata=metadata)
        metadata.update(model=model, usage=usage, cost_usd=cost_of(usage))
        score, feedback = verdict.get("score"), str(verdict.get("feedback", "")).strip()
        if not isinstance(score, (int, float)) or not math.isfinite(score) or not low <= score <= high:
            return {**metadata, "error": redact(f"judge returned score {score!r}, outside [{low}, {high}]", secrets)}
        if not feedback:
            return {**metadata, "error": "judge returned no feedback"}
        return {**metadata, "score": score, "feedback": feedback}
    except Exception as exc:  # recorded as an evaluator error, never as a score
        return {**metadata, "error": redact(f"{type(exc).__name__}: {exc}", secrets)}


def write_result(out: Path, result: dict) -> None:
    """Keep each attempt once in history; the existing result path remains the latest view."""
    out.parent.mkdir(exist_ok=True)
    history = out.with_suffix(".attempts.jsonl")
    previous = None
    if out.is_file() and not history.exists():
        try:
            previous = load_json(out)
        except (OSError, ValueError):
            pass
    with history.open("a", encoding="utf-8") as handle:
        if isinstance(previous, dict):
            handle.write(json.dumps(previous) + "\n")
        handle.write(json.dumps(result) + "\n")
    out.write_text(json.dumps(result, indent=2) + "\n", encoding="utf-8")


def trials(paths: list[Path]):
    """Yield (trial dir, result) for every Harbor trial under the given directories."""
    for root in paths:
        for path in [root / "result.json", *root.glob("*/result.json"), *root.glob("*/*/result.json"),
                     *root.glob("*/*/*/result.json")]:
            try:
                data = load_json(path) if path.is_file() else None
            except (OSError, json.JSONDecodeError):
                continue
            if isinstance(data, dict) and "trial_name" in data:
                yield path.parent, data


def self_test(task: Path, config: dict, relai_dir: Path) -> int:
    toml = load_toml(task / "task.toml")
    judges = [ev for ev in declared_evaluators(toml) if ev.get("type") == "judge"]
    if not judges:
        print(f"{task.name}: no judge evaluators")
        return 0
    empty = {"schema_version": "ATIF-v1.7", "agent": {"name": "relai-synthetic", "version": "0"},
             "steps": [{"step_id": 1, "source": "user", "message": "Hello, I need help with my request."},
                       {"step_id": 2, "source": "agent", "message": ""}]}
    prohibition = toml.get("metadata", {}).get("relai", {}).get("prohibition", False)
    status = 0
    for ev in judges:
        result = judge_one(config, relai_dir, task, ev, empty, {}, synthetic=True)
        if "error" in result:
            print(f"FAIL {ev['id']}: {result['error']}")
            status = 1
        elif result["score"] >= ev.get("max_score", 1.0) and not prohibition:
            print(f"FAIL {ev['id']}: full marks for an empty reply, so this judge cannot fail. Feedback: {result['feedback']}")
            status = 1
        else:
            print(f"PASS {ev['id']}: empty reply scored {result['score']}")
    return status


def main() -> int:
    parser = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    parser.add_argument("runs", nargs="*", help="Harbor or native run directories or folders containing them")
    parser.add_argument("--self-test", metavar="TASK_DIR", help="check that a task's judges can fail")
    parser.add_argument("--force", action="store_true", help="re-judge trials that already have results")
    parser.add_argument("--relai-dir")
    args = parser.parse_args()
    relai_dir = relai_root(args.relai_dir)
    config = evals_config(relai_dir).get("judge", {}) or {}
    if config.get("mode") == "subagent":
        print("relai.toml [judge].mode is 'subagent': a fresh subagent writes judges/<id>.json instead of this script")
        return 2
    if args.self_test:
        return self_test(Path(args.self_test).resolve(), config, relai_dir)
    if not args.runs:
        parser.error("name run directories, or use --self-test")
    secrets = secret_values(relai_dir)
    written = errors = unresolved = 0
    for trial_dir, result in trials([Path(p) for p in args.runs]):
        raw = str(((result.get("task_id") or {}).get("path")) or "")
        task = resolve_task_dir(raw, relai_dir, trial_dir.parent)
        if task is None:
            print(f"{trial_dir.name}: task {raw!r} not found; run Harbor with absolute task paths or judge from "
                  "the directory Harbor ran in")
            unresolved += 1
            continue
        trajectory_path = trial_dir / "agent" / "trajectory.json"
        crashed = result.get("exception_info") and result.get("verifier_result") is None
        toml = load_toml(task / "task.toml")
        neutral = bool((toml.get("metadata", {}).get("relai", {}) or {}).get("agent_neutral"))
        if crashed or (not trajectory_path.is_file() and not neutral):
            continue  # a run that never finished is a runtime failure, not something to grade
        trajectory = load_json(trajectory_path) if trajectory_path.is_file() else None
        for ev in declared_evaluators(toml):
            if ev.get("type") != "judge":
                continue
            out = trial_dir / "judges" / f"{ev['id']}.json"
            if out.exists() and not args.force:
                try:
                    if "error" not in load_json(out):
                        continue  # keep earlier scores; earlier errors are retried
                except (OSError, json.JSONDecodeError):
                    pass
            result = judge_one(config, relai_dir, task, ev, trajectory, secrets, trial_dir)
            write_result(out, result)
            written += 1
            errors += "error" in result
            print(f"{trial_dir.name} {ev['id']}: " + (f"error: {result['error']}" if "error" in result
                                                       else f"{result['score']}"))
    print(f"judged {written} evaluator result(s), {errors} error(s), {unresolved} trial(s) whose task was not found")
    return 1 if errors or unresolved else 0


if __name__ == "__main__":
    sys.exit(main())
