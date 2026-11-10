"""Rubric grader: one LLM judge call per rubric point, as in Surge AI's GDP.pdf harness.

The judge sees only the response and one criterion, never the question or the
document. It must return {"score": "0" | "1", "rationale": ...}. Output that
fails strict parsing is retried; a point that still fails is unscored.

Writes /logs/verifier/reward.json with
  reward         1.0 if every point passed, else 0.0   (Surge's `all_pass`)
  mean_criteria  fraction of points passed             (Surge's `mean_criteria`)
If any point is unscored the task is not scored either: Surge leaves such a
response out of `all_pass`, so this script exits non-zero instead of writing 0.
"""

from __future__ import annotations

import argparse
import asyncio
import json
import os
import re
import sys
from decimal import ROUND_HALF_UP, Decimal, InvalidOperation
from pathlib import Path

from openai import AsyncOpenAI

# Additional attempts after the first when the judge output fails to parse.
MAX_RETRIES = 4

# Judge prompt from surge-ai/gdp-pdf (src/gdp_pdf/scorer.py), unchanged.
JUDGE_PROMPT_TEMPLATE = """Read this json object:
{
  response: {{ rubric.response_to_grade }},
  criteria: {{ rubric.criterion }},
}

Score the response based on the criteria.
If the response perfectly satisfies the criteria, give it a score of "1".
If it does not satisfy the criteria at all, give it a score of "0".
Return the score and rationale in a JSON object with two keys, 'score' and 'rationale'.
'score' should be a string that's either "0" or "1".
'rationale' should be a description of why you gave the response that score.

Here are some examples of how to score a response:
{ score: "1", rationale: "The response is a perfect match for the criteria." }
{ score: "0", rationale: "The response does not satisfy the criteria at all." }
Unlike these examples, when you create a rationale, be specific and detailed. Give reasons specific to this response and criteria. Don't be generic."""

RESPONSE_FORMAT = {
    "type": "json_schema",
    "json_schema": {
        "name": "individual_criteria_score",
        "schema": {
            "type": "object",
            "required": ["rationale", "score"],
            "properties": {
                "rationale": {
                    "type": "string",
                    "description": "Text describing the evaluation criterion",
                },
                "score": {
                    "type": "string",
                    "enum": ["0", "1"],
                    "description": "Score value: '0' (does not satisfy) or '1' (perfectly satisfies)",
                },
            },
            "additionalProperties": False,
        },
    },
}


class ParseError(ValueError):
    pass


def judge_prompt(response_text: str, criterion: str) -> str:
    return JUDGE_PROMPT_TEMPLATE.replace(
        "{{ rubric.response_to_grade }}", response_text
    ).replace("{{ rubric.criterion }}", criterion)


def parse_verdict(raw_text: str) -> tuple[Decimal, str]:
    """Strict parse: strip code fences, valid JSON object, score coercible to a decimal."""
    cleaned = raw_text.strip()
    cleaned = re.sub(r"\A```(?:json)?\s*", "", cleaned, flags=re.IGNORECASE)
    cleaned = re.sub(r"\s*```\Z", "", cleaned)
    try:
        payload = json.loads(cleaned)
    except json.JSONDecodeError as e:
        raise ParseError(f"invalid JSON: {e}") from e
    if not isinstance(payload, dict):
        raise ParseError("judge output must be a JSON object")
    if "score" not in payload or "rationale" not in payload:
        raise ParseError("judge output must contain 'score' and 'rationale'")
    raw_score = payload["score"]
    if isinstance(raw_score, bool) or not isinstance(raw_score, (int, float, str)):
        raise ParseError("'score' must be a number or string")
    if not isinstance(payload["rationale"], str):
        raise ParseError("'rationale' must be a string")
    try:
        score = Decimal(str(raw_score).strip())
    except InvalidOperation as e:
        raise ParseError(f"'score' is not a decimal: {raw_score!r}") from e
    return score, payload["rationale"]


def passes(score: Decimal) -> bool:
    return score.quantize(Decimal("0.0001"), rounding=ROUND_HALF_UP) >= 1


async def score_criterion(client, model: str, response_text: str, criterion: str):
    """Return (score, rationale), or None if every attempt failed to parse."""
    prompt = judge_prompt(response_text, criterion)
    for _ in range(MAX_RETRIES + 1):
        result = await client.chat.completions.create(
            model=model,
            messages=[{"role": "user", "content": prompt}],
            response_format=RESPONSE_FORMAT,
        )
        try:
            return parse_verdict(result.choices[0].message.content or "")
        except ParseError:
            continue
    return None


async def grade(client, model: str, response_text: str, rubrics: list[dict]) -> dict:
    verdicts = await asyncio.gather(
        *(score_criterion(client, model, response_text, r["criterion"]) for r in rubrics)
    )
    grades = []
    for rubric, verdict in zip(rubrics, verdicts):
        if verdict is None:
            grades.append({"rubric_id": rubric["id"], "result": "unscored"})
            continue
        score, rationale = verdict
        grades.append(
            {
                "rubric_id": rubric["id"],
                "result": "pass" if passes(score) else "fail",
                "score": str(score),
                "rationale": rationale,
            }
        )
    return {"grades": grades}


def summarize(grades: list[dict]) -> dict | None:
    """Rewards for Harbor, or None if any point is unscored."""
    if not grades or any(g["result"] == "unscored" for g in grades):
        return None
    passed = sum(g["result"] == "pass" for g in grades)
    return {
        "reward": 1.0 if passed == len(grades) else 0.0,
        "mean_criteria": passed / len(grades),
    }


def main() -> int:
    parser = argparse.ArgumentParser()
    parser.add_argument("--answer", type=Path, required=True)
    parser.add_argument("--rubric", type=Path, required=True)
    parser.add_argument("--out-dir", type=Path, required=True)
    args = parser.parse_args()

    rubrics = json.loads(args.rubric.read_text())
    response_text = args.answer.read_text() if args.answer.is_file() else ""
    args.out_dir.mkdir(parents=True, exist_ok=True)

    if not response_text.strip():
        # No answer file: every point fails without calling the judge.
        grades = [{"rubric_id": r["id"], "result": "fail"} for r in rubrics]
        print("No answer found at", args.answer)
    else:
        client = AsyncOpenAI(
            api_key=os.environ.get("OPENAI_API_KEY"),
            base_url=os.environ.get("OPENAI_BASE_URL") or None,
        )
        model = os.environ.get("JUDGE_MODEL", "gemini-3.5-flash")
        grades = asyncio.run(grade(client, model, response_text, rubrics))["grades"]

    (args.out_dir / "grades.json").write_text(json.dumps(grades, indent=2))
    rewards = summarize(grades)
    if rewards is None:
        print("Some rubric points could not be scored; see grades.json", file=sys.stderr)
        return 1
    (args.out_dir / "reward.json").write_text(json.dumps(rewards))
    print(json.dumps(rewards))
    return 0


if __name__ == "__main__":
    sys.exit(main())
