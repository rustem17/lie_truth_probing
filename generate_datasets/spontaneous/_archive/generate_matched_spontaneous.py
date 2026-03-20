import json
import re
import random
from collections import defaultdict
from pathlib import Path

import fire
from datasets import load_dataset

LETTERS = list("ABCDEFGHIJ")
HEDGING = re.compile(r"\b(I think|I'm not sure|I believe|not certain|might be|possibly|perhaps|I would guess)\b", re.I)
ANSWER_PATTERNS = [
    re.compile(r"(?:the\s+)?(?:correct\s+)?answer\s+is\s*:?\s*\(?([A-J])\)?", re.IGNORECASE),
    re.compile(r"\b([A-J])\.\s", re.MULTILINE),
    re.compile(r"\(([A-J])\)\s*$", re.MULTILINE),
]
FALLBACK = re.compile(r"(?<![a-zA-Z0-9*^/\\])([A-J])(?:\.|(?:\s*[\)\.])|$)")


def format_options(options):
    return "\n".join(f"{LETTERS[i]}. {opt}" for i, opt in enumerate(options))


def extract_answer(response):
    for pat in ANSWER_PATTERNS:
        matches = pat.findall(response)
        if matches:
            return matches[-1].upper()
    matches = FALLBACK.findall(response)
    if matches:
        return matches[-1].upper()
    return None


def is_confident(response):
    return not bool(HEDGING.search(response))


def main(n_samples=2000, seed=42, output="spontaneous_matched_dataset.json"):
    rng = random.Random(seed)
    ds = load_dataset("TIGER-Lab/MMLU-Pro", split="test")

    by_subject = defaultdict(list)
    for row in ds:
        by_subject[row["category"]].append(row)

    per_subject = n_samples // len(by_subject)
    subjects = sorted(by_subject.keys())

    dataset = []
    for subj in subjects:
        pool = by_subject[subj]
        k = min(per_subject, len(pool))
        sampled = rng.sample(pool, k)
        for row in sampled:
            n_opts = len(row["options"])
            dataset.append({
                "id": f"mmlu_pro_{row['category']}_{row['question_id']}",
                "condition": "spontaneous",
                "subject": row["category"],
                "n_options": n_opts,
                "system_prompt": "You are a helpful assistant.",
                "user_message": f"{row['question']}\n\n{format_options(row['options'])}",
                "ground_truth": row["answer"],
                "expected_behavior": "correct",
            })

    rng.shuffle(dataset)

    with open(output, "w") as f:
        json.dump(dataset, f, indent=2)

    print(f"{len(dataset)} samples -> {output}")
    subject_counts = defaultdict(int)
    for s in dataset:
        subject_counts[s["subject"]] += 1
    for subj in sorted(subject_counts):
        print(f"  {subj}: {subject_counts[subj]}")


if __name__ == "__main__":
    fire.Fire(main)
