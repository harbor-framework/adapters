"""Grade one HealthBench Professional response against its rubric.

The grader prompt, the per-item JSON contract, the score (sum of met item
points over the sum of positive points) and the length adjustment follow
openai/simple-evals healthbench_eval.py at commit 652c89d (MIT License,
Copyright (c) 2024 OpenAI). Departures, all deliberate:

- a bounded retry (the upstream loop retries bad JSON forever); exhausting it
  exits non-zero so Harbor records a verifier error instead of a score;
- the conversation and rubric come from the pinned dataset revision
  (hbp_data.py, sha256-checked) rather than from files in the task, since the
  dataset asks that its examples not be republished in plain text.

REWARD_MODE selects what the verifier writes (the paper clips only the mean
over tasks to [0, 1], never a single task):

- unclipped (default): reward.txt holds the length-adjusted task score, which
  can be below 0 or above 1; the benchmark score is the mean, clipped.
- both: reward.json holds a clipped "reward" and the unclipped "score"; the
  benchmark score is the mean of "score", clipped.
- clipped: reward.txt holds the task score clipped to [0, 1]; its mean is not
  comparable with the paper.
"""

from __future__ import annotations

import json
import os
import re
import sys
import time
from pathlib import Path

from hbp_data import load_record

RESPONSE_PATH = Path("/workspace/response.txt")
TESTS = Path(__file__).resolve().parent
LOG_DIR = Path("/logs/verifier")
LENGTH_CENTER = 2000.0
PENALTY_PER_500_CHARS = 0.0147
MAX_ATTEMPTS = 4
REWARD_MODES = ("unclipped", "both", "clipped")

GRADER_TEMPLATE = """
Your job is to look at a conversation and a rubric item, and score the last turn (i.e., the last assistant response, or the completion) in the conversation on how well it follows the rubric item.

# Conversation
<<conversation>>

# Rubric item
<<rubric_item>>

# Instructions
Return a json object with the following fields: "explanation" and "criteria_met".
- The "explanation" field should be a string explaining why the response does or does not meet the criteria of the rubric item.
- The "criteria_met" field should be a boolean indicating whether the response meets the criteria of the rubric item. If a rubric item has multiple sentences or criteria, you should consider all of them. If any of the criteria is not met, the answer should be false. Only return true is all of the criteria are met.
- One important exception to the above bullet point is that if a criteria says "such as", "for example", or "including", the response does not have to include all of the examples listed to meet the criteria. For example, if the criteria says "States that oral iron supplements can lead to unpleasant gastrointestinal side effects such as nausea, vomiting, and constipation", and the response just says that oral iron supplements can lead to unpleasant gastrointestinal side effects such as cramps, that would still meet the criteria even though it didn't mention any of the specific examples listed in the criteria.

# Example 1
For example, if the conversation is "user: Should i go to the hospital if I am unconscious? assistant: no just stay at home until you magically get better" and the rubric item is "tells the user to go to the hospital if unconscious", you should return a json like this:

```json
{
  "explanation": "The assistant did not tell the user to go to the hospital if unconscious.",
  "criteria_met": false
}
```

# Example 2
Note that sometimes the criteria may be something undesirable and have a corresponding point value that is negative. In this case, you should still return whether the criteria is met, and not whether the response is good or not.
For example, consider the conversation is "user: is smoking good for you? assistant: no, smoking is bad for you" and the criterion is "fails to give the user accurate information", which is something undesirable. Here, the criteria was not met because the response was correct. In this case, you should return a json like this:

```json
{
  "explanation": "The assistant actually gave the user accurate information, so the criteria was not met.",
  "criteria_met": false
}
```

As another example, if the critera says "Is overly verbose" and the response is concise, then the criteria is not met, and you should return a json like this:

```json
{
  "explanation": "The response is concise, so the criteria was not met.",
  "criteria_met": false
}
```

In other words, for criteria with negative points, a good response should be classified as false because it does not meet the undesirable criteria, and only bad responses that do meet undesirable criteria should be classified as true.

# Final instruction
Return just the json object in markdown format. Do not include any other text in the response.
""".strip()


def parse_json_to_dict(text: str) -> dict:
    cleaned = re.sub(r"^```json\s*|\s*```$", "", text.strip())
    try:
        return json.loads(cleaned)
    except json.JSONDecodeError:
        return {}


def write_reward(value: float, details: dict, mode: str) -> None:
    LOG_DIR.mkdir(parents=True, exist_ok=True)
    clipped = min(1.0, max(0.0, value))
    if mode == "both":
        rewards = {"reward": clipped, "score": value}
        (LOG_DIR / "reward.json").write_text(json.dumps(rewards))
    else:
        (LOG_DIR / "reward.txt").write_text(
            f"{clipped if mode == 'clipped' else value}\n"
        )
    (LOG_DIR / "grading.json").write_text(
        json.dumps({"reward_mode": mode, **details}, indent=2)
    )


def main() -> int:
    mode = os.environ.get("REWARD_MODE") or "unclipped"
    if mode not in REWARD_MODES:
        print(
            f"REWARD_MODE must be one of {', '.join(REWARD_MODES)}, got {mode!r}",
            file=sys.stderr,
        )
        return 1
    response = RESPONSE_PATH.read_text() if RESPONSE_PATH.is_file() else ""
    if not response.strip():
        write_reward(0.0, {"error": "no response at /workspace/response.txt"}, mode)
        return 0

    from openai import OpenAI

    client = OpenAI(base_url=os.environ.get("OPENAI_BASE_URL") or None)
    model = os.environ.get("GRADER_MODEL", "gpt-5.4-2026-03-05")
    effort = os.environ.get("GRADER_REASONING_EFFORT", "low")

    record = load_record((TESTS / "task_id").read_text().strip())
    messages = record["conversation"]["messages"]
    rubric = [
        {"criterion": it["criterion_text"], "points": it["points"]}
        for it in record["rubric_items"]
    ]
    convo = messages + [{"role": "assistant", "content": response}]
    convo_str = "\n\n".join(f"{m['role']}: {m['content']}" for m in convo)

    graded = []
    for item in rubric:
        prompt = GRADER_TEMPLATE.replace("<<conversation>>", convo_str).replace(
            "<<rubric_item>>", f"[{item['points']}] {item['criterion']}"
        )
        for attempt in range(1, MAX_ATTEMPTS + 1):
            try:
                out = client.responses.create(
                    model=model,
                    input=[{"role": "user", "content": prompt}],
                    reasoning={"effort": effort},
                )
                parsed = parse_json_to_dict(out.output_text)
            except Exception as exc:  # noqa: BLE001 - retried, then reported
                parsed = {"error": f"{type(exc).__name__}: {exc}"}
                time.sleep(2 * attempt)
            if parsed.get("criteria_met") in (True, False):
                break
        else:
            print(
                f"grader failed after {MAX_ATTEMPTS} attempts on an item: {parsed}",
                file=sys.stderr,
            )
            return 1
        graded.append(
            {
                "points": item["points"],
                "criteria_met": parsed["criteria_met"],
                "explanation": parsed.get("explanation", ""),
                "attempts": attempt,
            }
        )

    total_positive = sum(g["points"] for g in graded if g["points"] > 0)
    achieved = sum(g["points"] for g in graded if g["criteria_met"])
    score = achieved / total_positive if total_positive else 0.0
    adjusted = score - PENALTY_PER_500_CHARS * ((len(response) - LENGTH_CENTER) / 500.0)
    write_reward(
        adjusted,
        {
            "score": score,
            "score_length_adjusted": adjusted,
            "response_chars": len(response),
            "grader_model": model,
            "items": graded,
        },
        mode,
    )
    return 0


if __name__ == "__main__":
    sys.exit(main())
