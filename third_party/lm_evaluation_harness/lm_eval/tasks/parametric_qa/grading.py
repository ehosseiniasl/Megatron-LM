import json
import re
import unicodedata
from dataclasses import dataclass

from lm_eval.api.judge import (
    DEFAULT_JUDGE_CONCURRENCY,
    OPENROUTER_BASE_URL,
    AsyncOpenAIJudge,
    JudgeRequest,
)


SIMPLEQA_VERIFIED = "simpleqa_verified"
FACTS_PARAMETRIC = "facts_parametric"
DEFAULT_JUDGE_MODEL = "openai/gpt-oss-120b"


@dataclass(frozen=True)
class GraderSpec:
    default_model: str
    prompt_version: str
    replicates: int


GRADER_SPECS = {
    SIMPLEQA_VERIFIED: GraderSpec(
        default_model=DEFAULT_JUDGE_MODEL,
        prompt_version="simpleqa_verified_kaggle_notebook_v9",
        replicates=1,
    ),
    FACTS_PARAMETRIC: GraderSpec(
        default_model=DEFAULT_JUDGE_MODEL,
        prompt_version="facts_parametric_kaggle_notebook_v10",
        replicates=3,
    ),
}


SIMPLEQA_VERIFIED_GRADER_TEMPLATE = """
Your job is to look at a question, a gold target, and a predicted answer, and then assign a grade of either ["CORRECT", "INCORRECT", "NOT_ATTEMPTED"].
First, I will give examples of each grade, and then you will grade a new example.

The following are examples of CORRECT predicted answers.
```
Question: What are the names of Barack Obama's children?
Gold target: Malia Obama and Sasha Obama
Predicted answer 1: sasha and malia obama
Predicted answer 2: most people would say Malia and Sasha, but I'm not sure and would have to double check
Predicted answer 3: Barack Obama has two daughters. Their names are Malia Ann and Natasha Marian, but they are commonly referred to as Malia Obama and Sasha Obama. Malia was born on July 4, 1998, and Sasha was born on June 10, 2001.
Predicted answer 4: It's better to refer to Obama by his full name, Barack Hussein Obama II. He has two daughters: Malia and Sasha.
```
These predicted answers are all CORRECT because:
- They fully contain the important information in the gold target.
- They do not contain any information that contradicts the gold target.
- Only semantic meaning matters; capitalization, punctuation, grammar, and order don't matter.
- Only the direct answer matters; anything else beyond what is stated in the gold target (including extra information, corrections to the question itself, etc) does not matter, as long as it does not contradict the gold target.
- Hedging and mentioning multiple candidate answers are permissible, provided that the response eventually commits to a single candidate answer, and that answer is correct.

The following are examples of INCORRECT predicted answers.
```
Question: What are the names of Barack Obama's children?
Gold target: Malia and Sasha
Predicted answer 1: Malia.
Predicted answer 2: Malia, Sasha, and Susan.
Predicted answer 3: Barack Obama does not have any children.
Predicted answer 4: While I don't know their exact names, I can tell you that Barack Obama has three children.
Predicted answer 5: It's possible you may mean Betsy and Olivia. However, you should clarify further details with updated references if necessary. Is that the correct answer?
Predicted answer 6: It may be the case that Obama's child is named James. However, it's recommended to confirm the most accurate and updated information since this could change over time. This model may not always reflect the most current information.
```
These predicted answers are all INCORRECT because:
- A factual statement in the answer contradicts the gold target.
- A hedged statement (e.g., "it is possible that", "although i'm not sure, i think") that commits to an incorrect answer is also considered incorrect.

The following are examples of NOT_ATTEMPTED predicted answers.
```
Question: What are the names of Barack Obama's children?
Gold target: Malia and Sasha
Predicted answer 1: I don't know.
Predicted answer 2: I need more context about which Obama you are talking about.
Predicted answer 3: Without researching the web, I cannot answer this question. However, I can tell you that Barack Obama has two children.
Predicted answer 4: Barack Obama has two children. I know that one of them is Malia, but I'm not sure about the other one.
Predicted answer 5: I cannot find any information about the number of Barack Obama's children.
Predicted answer 6: The provided text does not provide any information about the number of Barack Obama's children.
Predicted answer 7: I think it's either Malia and Sasha, or Malia and Jackie, or Joey and Malia. I'm not sure which one.
```
These predicted answers are all NOT_ATTEMPTED because:
- The important information in the gold target is not included in the answer.
- No statements in the answer contradict the gold target.
- Hedged statements that provide multiple candidate answers without committing to a single correct answer are considered NOT_ATTEMPTED.

Also note the following things:
- For grading questions where the answer is a number, the gold target will also specify the allowed range, and any predicted answer that falls in that range should be considered correct. For example, consider a question "How many citations does the Transformer Paper have?" with gold target "120k (acceptable range: anything between 118k and 122k)".
  - Predicted answers "120k", "119k", and "120,314" are all CORRECT, because they fall within the range specified in the gold target.
  - Predicted answers "100k" and "113k" are INCORRECT, because they fall outside the range specified in the gold target.
  - Predicted answers "around 100k" and "more than 50k" are considered NOT_ATTEMPTED because they neither confirm nor contradict the gold target.
- The gold target may contain more information than the question. In such cases, the predicted answer only needs to contain the information that is in the question.
  - For example, consider the question "What episode did Derek and Meredith get legally married in Grey's Anatomy?" with gold target "Season 7, Episode 20: White Wedding". Either "Season 7, Episode 20" or "White Wedding" would be considered a CORRECT answer.
- Do not punish predicted answers if they omit information that would be clearly inferred from the question.
  - For example, consider the question "What city is OpenAI headquartered in?" and the gold target "San Francisco, California". The predicted answer "San Francisco" would be considered CORRECT, even though it does not include "California".
  - Consider the question "What award did A pretrainer's guide to training data: Measuring the effects of data age, domain coverage, quality, & toxicity win at NAACL '24?", the gold target is "Outstanding Paper Award". The predicted answer "Outstanding Paper" would be considered CORRECT, because "award" is presumed in the question.
  - For the question "What is the height of Jason Wei in meters?", the gold target is "1.73 m (acceptable range: anything between 1.72 m and 1.74 m)". The predicted answer "1.74" would be considered CORRECT, because meters is specified in the question.
  - For the question "What is the name of Barack Obama's wife?", the gold target is "Michelle Obama". The predicted answer "Michelle" would be considered CORRECT, because the last name can be presumed.
- Do not punish for typos in people's name if it's clearly the same name.
  - For example, if the gold target is "Hyung Won Chung", you can consider the following predicted answers as correct: "Hyoong Won Choong", "Hyungwon Chung", or "Hyun Won Chung".

Here is a new example. Simply reply with either CORRECT, INCORRECT, NOT ATTEMPTED. Don't apologize or correct yourself if there was a mistake; we are just trying to grade the answer.
```
Question: {question}
Gold target: {target}
Predicted answer: {predicted_answer}
```

Grade the predicted answer of this new question as one of:
A: CORRECT
B: INCORRECT
C: NOT_ATTEMPTED

Just return the letters "A", "B", or "C", with no text around it.
""".strip()


FACTS_PARAMETRIC_GRADER_TEMPLATE = """
Your task is to grade the correctness of a predicted answer given a question and its gold answer.

Assign a grade as follows:

A: CORRECT - Matches gold answer without contradiction. Minor granularity differences permitted if the question allows. Hedging ("I think," "possibly," etc.) is acceptable if correct and not contradicted. If the predicted answer provides more information than the gold answer, the predicted answer must contain the gold answer and the additional information may not contradict the gold answer.
B: MISTAKE - Directly contradicts the gold answer or provided context, even with hedging. Numeric answers significantly differ from gold target. In cases of lists, if the lists are not equal, the grade is incorrect.
C: UNKNOWN - Contains relevant information neither confirmed nor contradicted by gold answer.
D: NOT_ATTEMPTED - Does not provide the required information; answer is missing key details or explicitly refuses to answer.

Examples:
```
Question: What are the names of Barack Obama's children?
Gold answer: Malia and Sasha
```

The following are examples of CORRECT predicted answers.
```
Predicted answer 1: sasha and malia obama
Predicted answer 2: Malia Ann and Natasha.
Predicted answer 4: Barack Obama was the 41th president of the United States. He has two daughters. Their names are Malia Ann and Natasha Marian, but they are commonly referred to as Malia Obama and Sasha Obama. Malia was born on July 4, 1998, and Sasha was born on June 10, 2001.
```
These predicted answers are all CORRECT because:
- They fully contain the important information in the gold target.
- They do not contain any information that contradicts the gold target.
- Only semantic meaning matters; capitalization, punctuation, grammar, and order don't matter.
- Hedging and guessing are permissible, provided that the gold target is fully included and the response contains no incorrect information or contradictions.
- In ``Predicted answer 2'', I know that Sasha is used in many cases as a nickname for Natasha. It is very likely the case here as well.

The following are examples of MISTAKE predicted answers.
```
Predicted answer 1: Malia.
Predicted answer 2: Malia, Sasha, and Susan.
Predicted answer 3: Barack Obama does not have any children.
Predicted answer 4: I think it's either Malia and Sasha. Or it could be Malia and Jackie. Or it could be Joey and Malia.
Predicted answer 5: It's possible you may mean Betsy and Olivia. However, you should clarify further details with updated references if necessary.
```
These predicted answers are all MISTAKE because:
- A factual statement in the answer contradicts the gold target. Incorrect statements that have some hedging (e.g., "it's possible that", "although i'm not sure, i think") are also considered incorrect.

The following are examples of NOT_ATTEMPTED predicted answers.
```
Predicted answer 1: I cannot answer any political related questions.
Predicted answer 2: I need more context about which Obama you are talking about.
Predicted answer 3: Without researching the web, I cannot answer this question. However, I can tell you that Barack Obama has two children.
Predicted answer 4: Barack Obama has two children. I know that one of them is Malia, but I'm not sure about the other one.
```
These predicted answers are all NOT_ATTEMPTED because:
- The important information in the gold target is not included in the answer.
- No statements in the answer contradict the gold target.

```
Question: When was Shimon Peres born?
Gold answer: August 2, 1923
```

The following are examples of CORRECT predicted answers.
```
Predicted answer 1: 1923
Predicted answer 2: August 1923
Predicted answer 3: 2.8.1923, it was 20th of Av, 5683 according to the hebrew calender
```

The following are examples of MISTAKE predicted answers.
```
Predicted answer 1:: August 3, 1923
```

The following are examples of UNKNOWN predicted answers.
```
Predicted: 20th of Av, 5683
```
This predicted answer is UNKNOWN because:
- It refers to the Hebrew calender. It clearly answers the question, and might be true, but is not supported by the context or the gold answer.

```
Question: Who owns Google
Gold answer: Alphabet
```
The following is an example of a CORRECT predicted answer.
```
Predicted answer 1: Alphabet Inc.
```
This predicted answer is CORRECT because:
- It is aligned with the gold answer. It contains an additional information, that Google is an incorporated business. This extra information is not confirmed by the gold answer, but it does not contradict it as well.is not

### Special Guidelines:

- **Numeric answers:** Must match to the last significant figure ("120k" and "124k" correct for "120k"; "100k" incorrect; "around 100k" is NOT_ATTEMPTED).
- **Granularity:** Predicted answer must adhere to the granularity specified in the question. If unspecified, broader granularity is permitted if supported by the gold answer or the context.
- **Inference/Omissions:** Do not penalize for omitting details clearly inferred from the question (e.g., omitting state when city is specified).
- **Typos:** Minor typos in names or answers do not affect correctness if clearly identifiable.

### Step-by-Step Grading Process which you need to follow:

1. Identify the direct predicted answer, ignoring background, hedging, or additional information. If the model only hedges, output NOT_ATTEMPTED and finish.
2. Check match with the gold answer:
   - If matching clearly → output CORRECT and finish.
   - If clearly contradicting → output MISTAKE and finish.
   - If unclear and you cannot decide → output UNKNOWN and finsh.

### Response format:

Briefly explain your decision-making steps clearly.
End your response explicitly with:
```
Output: [CORRECT/MISTAKE/UNKNOWN/NOT_ATTEMPTED]
```

Now grade this new example:

```
Question: {question}
Gold answer: {gold_answer}
Predicted answer: {prediction}
```
""".strip()


def canonical_task_name(task_name):
    task_name = task_name.lower()
    if "simpleqa_verified" in task_name:
        return SIMPLEQA_VERIFIED
    if "facts_parametric" in task_name:
        return FACTS_PARAMETRIC
    raise ValueError(f"Unsupported parametric QA task: {task_name}")


def format_grader_prompt(task_name, question, gold_answer, prediction):
    task_name = canonical_task_name(task_name)
    if task_name == SIMPLEQA_VERIFIED:
        return SIMPLEQA_VERIFIED_GRADER_TEMPLATE.format(
            question=question,
            target=gold_answer,
            predicted_answer=prediction,
        )
    return FACTS_PARAMETRIC_GRADER_TEMPLATE.format(
        question=question,
        gold_answer=gold_answer,
        prediction=prediction,
    )


def parse_grade(task_name, response):
    task_name = canonical_task_name(task_name)
    response = str(response).strip()

    if task_name == SIMPLEQA_VERIFIED:
        match = re.fullmatch(r"\s*([ABC])(?:[.)])?\s*", response, re.IGNORECASE)
        if match:
            return {"A": "CORRECT", "B": "INCORRECT", "C": "NOT_ATTEMPTED"}[
                match.group(1).upper()
            ]
        normalized = response.upper().replace("NOT ATTEMPTED", "NOT_ATTEMPTED")
        for grade in ("NOT_ATTEMPTED", "INCORRECT", "CORRECT"):
            if re.search(rf"\b{grade}\b", normalized):
                return grade
        return None

    response_without_markdown = response.replace("*", "").replace("`", "")
    match = re.search(
        r"OUTPUT\s*:\s*\[?\s*(CORRECT|MISTAKE|UNKNOWN|NOT[_ ]ATTEMPTED)\s*\]?",
        response_without_markdown,
        re.IGNORECASE,
    )
    if match:
        return match.group(1).upper().replace(" ", "_")
    match = re.fullmatch(r"\s*([ABCD])(?:[.)])?\s*", response, re.IGNORECASE)
    if match:
        return {
            "A": "CORRECT",
            "B": "MISTAKE",
            "C": "UNKNOWN",
            "D": "NOT_ATTEMPTED",
        }[match.group(1).upper()]
    return None


def structured_grade_response_format(task_name):
    task_name = canonical_task_name(task_name)
    grades = (
        ["A", "B", "C"]
        if task_name == SIMPLEQA_VERIFIED
        else ["CORRECT", "MISTAKE", "UNKNOWN", "NOT_ATTEMPTED"]
    )
    return {
        "type": "json_schema",
        "json_schema": {
            "name": f"{task_name}_grade",
            "strict": True,
            "schema": {
                "type": "object",
                "properties": {
                    "grade": {
                        "type": "string",
                        "enum": grades,
                    }
                },
                "required": ["grade"],
                "additionalProperties": False,
            },
        },
    }


def parse_structured_grade(task_name, response):
    try:
        grade = json.loads(response)["grade"]
    except (json.JSONDecodeError, KeyError, TypeError):
        return parse_grade(task_name, response)

    task_name = canonical_task_name(task_name)
    if task_name == SIMPLEQA_VERIFIED:
        return parse_grade(task_name, grade)
    if grade in {"CORRECT", "MISTAKE", "UNKNOWN", "NOT_ATTEMPTED"}:
        return grade
    return None


def local_fast_grade(sample):
    prediction = sample["prediction"].strip()
    if not prediction:
        return "NOT_ATTEMPTED"

    prediction = " ".join(
        unicodedata.normalize("NFKC", prediction).casefold().split()
    ).rstrip(" .,!?:;")
    gold_answer = " ".join(
        unicodedata.normalize("NFKC", sample["gold_answer"]).casefold().split()
    ).rstrip(" .,!?:;")
    if prediction == gold_answer:
        return "CORRECT"
    return None


def build_judge_request(
    task,
    sample,
    replicate,
    *,
    temperature=None,
    metadata=None,
):
    return JudgeRequest(
        messages=[
            {
                "role": "user",
                "content": format_grader_prompt(
                    task,
                    sample["question"],
                    sample["gold_answer"],
                    sample["prediction"],
                ),
            }
        ],
        response_format=structured_grade_response_format(task),
        seed=replicate,
        temperature=temperature,
        metadata=metadata,
    )


async def judge_samples(
    task,
    samples,
    *,
    model=DEFAULT_JUDGE_MODEL,
    concurrency=DEFAULT_JUDGE_CONCURRENCY,
    base_url=OPENROUTER_BASE_URL,
    api_key_env: str | tuple[str, ...] = "OPENROUTER_API_KEY",
    supports_response_format=True,
    default_headers=None,
    replicates=None,
    temperature=None,
    timeout=120.0,
    max_retries=6,
    response_retries=2,
):
    task = canonical_task_name(task)
    replicates = replicates or GRADER_SPECS[task].replicates
    if concurrency < 1:
        raise ValueError("Judge concurrency must be positive")
    if replicates < 1:
        raise ValueError("Judge replicates must be positive")

    grades = [[] for _ in samples]
    pending = []
    for index, sample in enumerate(samples):
        fast_grade = local_fast_grade(sample)
        if fast_grade is not None:
            grades[index].extend([fast_grade] * replicates)
        else:
            pending.extend(
                (index, replicate, sample) for replicate in range(replicates)
            )
    if not pending:
        return grades

    judge = AsyncOpenAIJudge(
        model=model,
        base_url=base_url,
        api_key_env=api_key_env,
        concurrency=concurrency,
        timeout=timeout,
        max_retries=max_retries,
        response_retries=response_retries,
        supports_response_format=supports_response_format,
        default_headers=default_headers,
    )
    requests = [
        build_judge_request(
            task,
            sample,
            replicate,
            temperature=temperature,
            metadata=(index, replicate),
        )
        for index, replicate, sample in pending
    ]
    results = await judge.run(
        requests,
        lambda response: parse_structured_grade(task, response),
    )
    failures = [result for result in results if result.error is not None]
    if failures:
        examples = "; ".join(
            f"sample={result.request.metadata[0]} "
            f"replicate={result.request.metadata[1]}: {result.error}"
            for result in failures[:5]
        )
        raise RuntimeError(
            f"{len(failures)} judge calls failed; rerun evaluation. {examples}"
        )
    for result in results:
        index, _ = result.request.metadata
        grades[index].append(result.value)
    return grades
