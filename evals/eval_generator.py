"""
evals/eval_generator.py
=======================
Component-level evaluation of the GENERATOR, in isolation.

Faithfulness: of the claims in the generated answer, how many are supported
by the context it was given? (Did the generator make things up?)

ISOLATION: we feed the generator the GOLDEN context (the known-good chunks
from the faithfulness dataset), NOT the retriever's output. So a low score
is purely the generator's fault --- the context was already correct.

    python -m evals.eval_generator
"""

import os

from dotenv import load_dotenv

from deepeval import evaluate
from deepeval.evaluate.configs import AsyncConfig, CacheConfig
from deepeval.test_case import LLMTestCase
from deepeval.metrics import FaithfulnessMetric, AnswerRelevancyMetric

from src.generator import generate   # your generator: generate(query, context) -> answer
from evals.harness import load_goldens, summarize_by_metric, print_summary

from src.config import get_judge

load_dotenv()

# DeepEval's on-disk test-case cache uses file locks that collide with its own
# parallel async execution on Windows -- the lock fails, the cache object comes
# back None and the run dies mid-suite. We don't reuse cached judgements here
# anyway, so turn the cache off.
NO_CACHE = CacheConfig(write_cache=False)

# DeepEval fires 20 judge calls at once by default, which blows straight through
# a free-tier token-per-minute budget (Groq allows 8k TPM, and one retrieval
# judgement is ~3k tokens). Concurrency and the pause between tasks are env
# knobs -- raise EVAL_MAX_CONCURRENT once you are on a paid tier.
EVAL_ASYNC = AsyncConfig(
    max_concurrent=int(os.getenv("EVAL_MAX_CONCURRENT", "1")),
    throttle_value=float(os.getenv("EVAL_THROTTLE", "1")),
)

GOLDEN_PATH = "goldens/faithfulness_dataset.json"
# judge model name comes from JUDGE_MODEL in .env (was 'gpt-4o-mini' upstream)
JUDGE_MODEL = get_judge()
THRESHOLD = 0.7


def run():
    # 1. LOAD the faithfulness golden set (query + ideal_context)
    goldens = load_goldens(GOLDEN_PATH)

    # 2. RUN THE GENERATOR on the GOLDEN context (isolation), build one test case each
    test_cases = []
    for g in goldens:
        context = g["ideal_context"]              # known-good context (list of chunk strings)
        answer = generate(g["query"], context)    # RUN the generator -> actual_output

        test_cases.append(
            LLMTestCase(
                input=g["query"],
                actual_output=answer,             # the generated answer we're judging
                retrieval_context=context,        # faithfulness checks the answer against THIS
                # no expected_output --- faithfulness never reads it
            )
        )

    # 3. THE METRICS --- decompose actual_output into claims, attribute each to context
    metrics = [
        FaithfulnessMetric(
            threshold=THRESHOLD,
            model=JUDGE_MODEL,
            include_reason=True,   # prints WHY each score --- shows which claims were unsupported
        ),
        AnswerRelevancyMetric(
            threshold=THRESHOLD,
            model=JUDGE_MODEL,
            include_reason=True,
        ),
    ]

    # 4. EVALUATE --- runs the metrics on every case, prints a report
    result = evaluate(cache_config=NO_CACHE,
        async_config=EVAL_ASYNC, test_cases=test_cases, metrics=metrics)
    return summarize_by_metric(result)


if __name__ == "__main__":
    print_summary("generator", run())