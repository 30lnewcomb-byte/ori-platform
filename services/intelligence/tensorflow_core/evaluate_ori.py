"""Evaluate an Ori checkpoint against a held-out behavior set."""

from __future__ import annotations

import argparse
import json
from pathlib import Path

import numpy as np
import tensorflow as tf

from ori_model import OriLMConfig, OriLanguageModel, OriTokenizer


def load_eval(path: Path) -> list[dict]:
    rows = []
    for line in path.read_text(encoding="utf-8").splitlines():
        if line.strip():
            rows.append(json.loads(line))
    if not rows:
        raise ValueError("Evaluation dataset is empty")
    return rows


def score_completion(model, tokenizer, prompt: str, expected: str) -> float:
    prefix = tokenizer.encode(prompt, add_bos=True, add_eos=False)
    target = tokenizer.encode(expected, add_bos=False, add_eos=True)
    ids = prefix[-model.config.context_length :]
    correct = 0
    total = 0

    for token in target:
        logits = model.next_logits(
            tf.constant([ids], dtype=tf.int32)
        )[0]
        prediction = int(tf.argmax(logits).numpy())
        correct += int(prediction == token)
        total += 1
        ids.append(token)
        ids = ids[-model.config.context_length :]

    return correct / total if total else 0.0


def main() -> None:
    parser = argparse.ArgumentParser()
    parser.add_argument("--data", default="data/ori_eval.jsonl")
    parser.add_argument("--artifact", default="artifacts/ori-small")
    parser.add_argument(
        "--report",
        default="artifacts/evaluation/ori_eval_report.json",
    )
    args = parser.parse_args()

    artifact = Path(args.artifact)
    tokenizer = OriTokenizer.load(artifact / "ori_tokenizer.model")
    config = OriLMConfig(
        **json.loads((artifact / "config.json").read_text(encoding="utf-8"))
    )
    model = OriLanguageModel(config, name="ori_language_model")
    model(tf.zeros((1, 2), dtype=tf.int32))
    model.load_weights(artifact / "model.weights.h5")

    rows = load_eval(Path(args.data))
    details = []
    for row in rows:
        score = score_completion(
            model,
            tokenizer,
            row["prompt"],
            row["expected"],
        )
        generated, finish_reason = model.generate(
            tokenizer,
            row["prompt"],
            max_new_tokens=24,
            temperature=0.0,
            top_k=0,
        )
        expected_fragments = [
            fragment.strip().lower()
            for fragment in row.get("expected_fragments", [])
            if isinstance(fragment, str) and fragment.strip()
        ]
        generation_match = (
            any(fragment in generated.lower() for fragment in expected_fragments)
            if expected_fragments
            else False
        )
        minimum = float(row.get("minimum_score", 0.0))
        require_generation = bool(row.get("require_generation_match", False))
        passed = score >= minimum and (
            generation_match if require_generation else True
        )
        details.append(
            {
                "prompt": row["prompt"],
                "expected": row["expected"],
                "score": float(score),
                "minimum_score": minimum,
                "generated": generated,
                "finish_reason": finish_reason,
                "generation_match": generation_match,
                "generation_required": require_generation,
                "passed": passed,
            }
        )

    scores = [item["score"] for item in details]
    passed = sum(item["passed"] for item in details)
    result = {
        "model": "ori-small",
        "examples": len(details),
        "mean_token_accuracy": float(np.mean(scores)),
        "median_token_accuracy": float(np.median(scores)),
        "passed": passed,
        "pass_rate": passed / len(details),
        "details": details,
    }

    report = Path(args.report)
    report.parent.mkdir(parents=True, exist_ok=True)
    report.write_text(json.dumps(result, indent=2), encoding="utf-8")
    print(json.dumps({k: v for k, v in result.items() if k != "details"}, indent=2))


if __name__ == "__main__":
    main()
