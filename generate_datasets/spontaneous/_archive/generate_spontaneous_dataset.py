import json
import random
from collections import defaultdict

import fire
from datasets import load_dataset

LETTERS = list("ABCDEFGHIJ")


def format_options(options):
    return "\n".join(f"{LETTERS[i]}. {opt}" for i, opt in enumerate(options))


def main(n_samples=500, seed=42, output="spontaneous_dataset.json"):
    rng = random.Random(seed)
    ds = load_dataset("TIGER-Lab/MMLU-Pro", split="test")

    by_subject = defaultdict(list)
    for row in ds:
        by_subject[row["category"]].append(row)

    per_subject = max(1, n_samples // len(by_subject))
    remainder = n_samples - per_subject * len(by_subject)

    samples = []
    subjects = sorted(by_subject.keys())
    for subj in subjects:
        pool = by_subject[subj]
        k = min(per_subject, len(pool))
        samples.extend(rng.sample(pool, k))

    if remainder > 0:
        used_ids = {s["question_id"] for s in samples}
        leftover = [r for r in ds if r["question_id"] not in used_ids]
        rng.shuffle(leftover)
        samples.extend(leftover[:remainder])

    rng.shuffle(samples)

    dataset = []
    for i, row in enumerate(samples):
        dataset.append({
            "id": f"mmlu_pro_{row['category']}_{i:04d}",
            "condition": "spontaneous",
            "subject": row["category"],
            "system_prompt": "You are a helpful assistant.",
            "user_message": f"{row['question']}\n\n{format_options(row['options'])}",
            "ground_truth": row["answer"],
            "expected_behavior": "correct",
        })

    with open(output, "w") as f:
        json.dump(dataset, f, indent=2)

    subject_counts = defaultdict(int)
    for s in dataset:
        subject_counts[s["subject"]] += 1
    print(f"{len(dataset)} samples -> {output}")
    for subj in sorted(subject_counts):
        print(f"  {subj}: {subject_counts[subj]}")


if __name__ == "__main__":
    fire.Fire(main)
