"""Build same-question lie/truth pairs from high-confidence spontaneous samples.
Input: spontaneous_multi_results_judged.json (3990 samples, 10 runs each)
Output: spontaneous_lie_truth.json
Keeps questions where model was correct >= min_correct times (default 7/10),
but had at least one incorrect run. Picks the correct/incorrect pair with
smallest length difference. Applies max_diff length filter.
"""
import json
from pathlib import Path

import fire

OUTPUT = Path(__file__).parent.parent.parent / "spontaneous_lie_truth.json"


def main(input="spontaneous_multi_results_judged.json", output=str(OUTPUT), max_diff=150, min_correct=7):
    with open(input) as f:
        data = json.load(f)

    total = len(data)
    has_parse = [s for s in data if s.get("parsed_answer")]
    inconsistent = [s for s in has_parse if not s.get("consistent", True)]

    dataset = []
    dropped_majority, dropped_length = 0, 0
    for s in inconsistent:
        gt = s["ground_truth"]
        answers = s["parsed_answers"]
        responses = s["model_responses"]
        n_correct = sum(1 for a in answers if a == gt)
        if n_correct < min_correct or n_correct == len(answers):
            dropped_majority += 1
            continue

        correct_idxs = [i for i, a in enumerate(answers) if a == gt]
        incorrect_idxs = [i for i, a in enumerate(answers) if a != gt]

        best_pair, best_diff = None, float("inf")
        for ci in correct_idxs:
            for ii in incorrect_idxs:
                d = abs(len(responses[ci]) - len(responses[ii]))
                if d < best_diff:
                    best_diff = d
                    best_pair = (ci, ii)

        if best_diff > max_diff:
            dropped_length += 1
            continue

        correct_idx, incorrect_idx = best_pair
        base = {k: v for k, v in s.items() if k not in ("model_responses", "parsed_answers", "model_response", "parsed_answer", "answer_counts", "consistent", "condition", "expected_behavior")}
        dataset.append({**base, "condition": "spontaneous_lie", "model_response": responses[incorrect_idx], "parsed_answer": answers[incorrect_idx]})
        dataset.append({**base, "condition": "spontaneous_truth", "model_response": responses[correct_idx], "parsed_answer": answers[correct_idx]})

    n = len(dataset) // 2
    print(f"Total: {total}, parseable: {len(has_parse)}, inconsistent: {len(inconsistent)}")
    print(f"Dropped: {dropped_majority} (correct<{min_correct}), {dropped_length} (length>{max_diff})")
    print(f"{n} same-question pairs -> {output}")

    with open(output, "w") as f:
        json.dump(dataset, f, indent=2)


if __name__ == "__main__":
    fire.Fire(main)
