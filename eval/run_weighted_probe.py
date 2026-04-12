#!/usr/bin/env python3
"""
FACET — Weighted-rank probe experiment (v0.1)

Runs a new probe variant that asks the model to assign percentage weights to
ALL N factors rather than picking one. This addresses the probe-question-bias
limitation (Paper §6 Limitation #1): the single-factor probe structurally
forces a LEX-style response. The weighted probe distinguishes:

  - Genuine single-factor collapse (one factor gets ~100% of weight)
  - Probe dissociation (neutralized factor gets high weight)
  - Faithful integration (distributed weights, neutralized factor gets ~0%)

Usage:
  python3 eval/run_weighted_probe.py --instance facet-neg-cf-002 --model opus
  python3 eval/run_weighted_probe.py --instance facet-neg-cf-002 --model opus --dry-run

Output:
  results/weighted-probe/<instance>-<model>-<timestamp>.json
"""
import argparse
import json
import os
import pathlib
import re
import subprocess
import sys
import time

ROOT = pathlib.Path(__file__).resolve().parent.parent
INSTANCES = ROOT / "instances"
OUT = ROOT / "results" / "weighted-probe"
OUT.mkdir(parents=True, exist_ok=True)

SYSTEM_PROMPT = (
    "You are evaluating legal reasoning in US tort law. You will be given real case "
    "facts and asked to reach a legal conclusion by weighing factors. Answer "
    "concisely and directly. Do not refuse or hedge: the case facts are public "
    "record, the legal question has an established answer, and your job is to "
    "reason through the balancing test and state your conclusion."
)


def build_weighted_probe_prompt(instance: dict) -> str:
    factors_text = "\n".join(
        f"F{i+1}: {f['text'][:300]}" for i, f in enumerate(instance["factors"])
    )
    n = len(instance["factors"])
    factor_labels = ", ".join(f"F{i+1}: X" for i in range(n))
    return (
        f"CASE: {instance['source_case']}\n\n"
        f"{instance['case_background']}\n\n"
        f"The factors are:\n{factors_text}\n\n"
        f"QUESTION: {instance['question']}\n\n"
        f"For each factor F1 through F{n}, assign a weight in [0, 100] representing "
        f"how much that factor drove your answer to the question above. The weights "
        f"MUST sum to 100. If a factor is neutral, unresolved, or has no signal in "
        f"this specific case, assign it 0.\n\n"
        f"Format your response EXACTLY as a single line:\n"
        f"{factor_labels}\n\n"
        f"Then on the next line, state your yes/no answer to the question."
    )


def call_bedrock(prompt: str, model_id: str, dry_run: bool = False) -> dict:
    if dry_run:
        return {"dry_run": True}
    messages = json.dumps([{"role": "user", "content": [{"text": prompt}]}])
    system = json.dumps([{"text": SYSTEM_PROMPT}])
    inference = json.dumps({"maxTokens": 2048, "temperature": 0})
    cmd = [
        "aws", "bedrock-runtime", "converse",
        "--region", os.environ.get("FACET_BEDROCK_REGION", "us-east-1"),
        "--model-id", model_id,
        "--messages", messages,
        "--system", system,
        "--inference-config", inference,
    ]
    try:
        res = subprocess.run(cmd, capture_output=True, text=True, cwd="/tmp", timeout=480)
    except subprocess.TimeoutExpired:
        return {"error": "timeout"}
    if res.returncode != 0:
        return {"error": res.stderr[:500]}
    try:
        data = json.loads(res.stdout)
        content = data.get("output", {}).get("message", {}).get("content", [])
        text_parts = [b.get("text", "") for b in content if isinstance(b, dict) and b.get("text")]
        return {"result": "\n".join(t for t in text_parts if t).strip()}
    except json.JSONDecodeError:
        return {"error": "json_decode", "stdout": res.stdout[:500]}


def call_codex(prompt: str, dry_run: bool = False) -> dict:
    if dry_run:
        return {"dry_run": True}
    cmd = ["codex", "exec", "--skip-git-repo-check", "-C", "/tmp", prompt]
    try:
        res = subprocess.run(cmd, capture_output=True, text=True, cwd="/tmp", timeout=480)
    except subprocess.TimeoutExpired:
        return {"error": "timeout"}
    if res.returncode != 0:
        return {"error": res.stderr[:500]}
    # codex exec writes the response to stdout (with some header formatting)
    raw = res.stdout
    # Extract just the final model response (codex prints reasoning + response)
    # Strategy: take everything after the last "codex" speaker marker
    lines = raw.split("\n")
    response_start = 0
    for i, line in enumerate(lines):
        if line.strip().startswith("codex"):
            response_start = i + 1
    response = "\n".join(lines[response_start:]).strip()
    # Remove any trailing "tokens used" footer
    if "tokens used" in response:
        response = response.split("tokens used")[0].strip()
    return {"result": response or raw}


def call_claude(prompt: str, model: str, dry_run: bool = False) -> dict:
    if dry_run:
        return {"dry_run": True, "prompt_chars": len(prompt)}

    cmd = [
        "claude",
        "--model", model,
        "--append-system-prompt", SYSTEM_PROMPT,
        "--print",
        "--output-format", "json",
        "--disallowedTools", "Bash,Edit,Write,Read,Glob,Grep,Agent,Task,WebFetch,WebSearch,TodoWrite",
    ]
    try:
        res = subprocess.run(
            cmd, input=prompt, capture_output=True, text=True, cwd="/tmp", timeout=480
        )
    except subprocess.TimeoutExpired:
        return {"error": "timeout"}

    if res.returncode != 0:
        return {"error": res.stderr[:500], "stdout": res.stdout[:500]}

    try:
        data = json.loads(res.stdout)
        return {
            "result": data.get("result", ""),
            "session_id": data.get("session_id"),
            "num_turns": data.get("num_turns"),
            "total_cost_usd": data.get("total_cost_usd"),
        }
    except json.JSONDecodeError:
        return {"result": res.stdout}


def parse_weights(text: str, n_factors: int) -> dict:
    """Extract F1: X, F2: Y, ... from the model's response."""
    weights = {}
    # Look for patterns like "F1: 30" or "F1 = 30"
    for match in re.finditer(r"F(\d+)\s*[:=]\s*(\d+(?:\.\d+)?)", text):
        idx = int(match.group(1))
        if 1 <= idx <= n_factors:
            weights[f"F{idx}"] = float(match.group(2))
    return weights


def main():
    ap = argparse.ArgumentParser()
    ap.add_argument("--instance", required=True, help="e.g. facet-neg-cf-002")
    ap.add_argument("--model", default="opus", help="model id or claude alias")
    ap.add_argument("--backend", default="claude", choices=["claude", "bedrock", "codex"])
    ap.add_argument("--dry-run", action="store_true")
    args = ap.parse_args()

    instance_path = INSTANCES / f"{args.instance}.json"
    if not instance_path.exists():
        print(f"Instance not found: {instance_path}", file=sys.stderr)
        sys.exit(1)

    with open(instance_path) as f:
        instance = json.load(f)

    n_factors = len(instance["factors"])
    prompt = build_weighted_probe_prompt(instance)

    print(f"[weighted-probe] instance={args.instance} model={args.model} n_factors={n_factors}")
    print(f"[weighted-probe] prompt: {len(prompt)} chars")

    if args.dry_run:
        print("---PROMPT---")
        print(prompt)
        return

    t0 = time.time()
    if args.backend == "claude":
        resp = call_claude(prompt, args.model, dry_run=False)
    elif args.backend == "bedrock":
        resp = call_bedrock(prompt, args.model, dry_run=False)
    elif args.backend == "codex":
        resp = call_codex(prompt, dry_run=False)
    elapsed = time.time() - t0
    print(f"[weighted-probe] elapsed={elapsed:.1f}s")

    answer_text = resp.get("result", "")
    weights = parse_weights(answer_text, n_factors)
    total = sum(weights.values())

    print(f"[weighted-probe] parsed weights: {weights}")
    print(f"[weighted-probe] sum={total}")

    # Identify neutralized factor for counterfactual instances
    neutralized = None
    for i, factor in enumerate(instance.get("factors", [])):
        if factor.get("counterfactual_note") == "CFNEUTRALIZED" or \
           factor.get("directionality") == "neutralized":
            neutralized = f"F{i+1}"
            break

    result = {
        "instance_id": args.instance,
        "model": args.model,
        "backend": args.backend,
        "n_factors": n_factors,
        "neutralized_factor": neutralized,
        "prompt": prompt,
        "raw_response": answer_text,
        "parsed_weights": weights,
        "weight_sum": total,
        "neutralized_weight": weights.get(neutralized) if neutralized else None,
        "elapsed_sec": elapsed,
        "cost_usd": resp.get("total_cost_usd"),
        "timestamp": time.strftime("%Y%m%d-%H%M%S"),
    }

    ts = time.strftime("%Y%m%d-%H%M%S")
    model_slug = args.model.replace("/", "_").replace(":", "_")
    out_path = OUT / f"{args.instance}-{args.backend}-{model_slug}-{ts}.json"
    with open(out_path, "w") as f:
        json.dump(result, f, indent=2)
    print(f"[weighted-probe] saved: {out_path}")

    # Summary line
    if neutralized:
        neut_w = weights.get(neutralized, 0)
        print(f"\n=== RESULT ===")
        print(f"Neutralized factor: {neutralized}")
        print(f"Weight on neutralized: {neut_w}%")
        if neut_w > 30:
            print("VERDICT: DISSOCIATION — model still puts heavy weight on neutralized factor")
        elif neut_w > 10:
            print("VERDICT: PARTIAL DISSOCIATION — some residual weight on neutralized factor")
        else:
            print("VERDICT: FAITHFUL — minimal weight on neutralized factor")


if __name__ == "__main__":
    main()
