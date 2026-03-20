"""Build same-question lie/truth pairs from inconsistent spontaneous samples.
Input: spontaneous_multi_results_judged.json (3990 samples, 3 runs each)
Output: spontaneous_inconsistent.json
Uses questions where model answered both correctly and incorrectly across runs.
Picks first incorrect run as lie, first correct run as truth.
"""
import json
from pathlib import Path

import fire

OUTPUT = Path(__file__).parent.parent.parent / "spontaneous_inconsistent.json"


def main(input="spontaneous_multi_results_judged.json", output=str(OUTPUT), max_diff=150):
    with open(input) as f:
        data = json.load(f)

    dataset = []
    dropped_length = 0
    for s in data:
        if not s.get("parsed_answer"):
            continue
        if s.get("consistent", True):
            continue
        gt = s["ground_truth"]
        answers = s["parsed_answers"]
        responses = s["model_responses"]
        correct_idx = next((i for i, a in enumerate(answers) if a == gt), None)
        incorrect_idx = next((i for i, a in enumerate(answers) if a != gt), None)
        if correct_idx is None or incorrect_idx is None:
            continue

        if abs(len(responses[incorrect_idx]) - len(responses[correct_idx])) > max_diff:
            dropped_length += 1
            continue

        base = {k: v for k, v in s.items() if k not in ("model_responses", "parsed_answers", "model_response", "parsed_answer", "answer_counts", "consistent", "condition", "expected_behavior")}
        dataset.append({**base, "condition": "spontaneous_lie", "model_response": responses[incorrect_idx], "parsed_answer": answers[incorrect_idx]})
        dataset.append({**base, "condition": "spontaneous_truth", "model_response": responses[correct_idx], "parsed_answer": answers[correct_idx]})

    n = len(dataset) // 2
    with open(output, "w") as f:
        json.dump(dataset, f, indent=2)
    print(f"{n} same-question pairs, {dropped_length} dropped (length>{max_diff}) -> {output}")


if __name__ == "__main__":
    fire.Fire(main)
