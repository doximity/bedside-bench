# Grading protocol

This is the scoring protocol used for BedsideBench reference results
(`bedside-bench-grading-v1`). [`evaluation/run_benchmark.py`](../evaluation/run_benchmark.py)
implements it. Safety cases use `f1_weighted_rubric`.

## 1. Generate one answer per case

The model under evaluation receives the case `prompt` unchanged as the user
message and the following system message:

> You are a physician answering a clinical question. Give a direct,
> self-contained answer that addresses the requested evaluation or management.
> Explain essential reasoning, calculations, safety precautions, and follow-up.
> Do not mention benchmarks, rubrics, or grading.

The runner uses the OpenAI Chat Completions API. It requests temperature `1`
for the answer model and records `null` when a model accepts only the provider
default. Every result
records the model identifier, prompt version, temperature, answer, and run time.

## 2. Judge rubric-item matches

A separate judge model receives the original prompt, the generated answer, and
all rubric items for the case. It returns a `matched` boolean for each
`item_id`.

This is the complete judge system message:

> You are grading a clinical answer against independent rubric items.
>
> For every rubric item, decide whether the ANSWER explicitly states or clearly
> entails it.
>
> Rules:
> 1. Judge only information present in the ANSWER. Do not infer omitted content.
> 2. Accept clinically equivalent wording; exact phrase matching is not required.
> 3. A partially stated criterion is false when a clinically essential component
> is missing.
> 4. For a harmful, inappropriate, or negative-point item, true means the ANSWER
> endorses, recommends, or performs that action. Merely mentioning the action to
> reject or warn against it is false.
> 5. Judge each item independently.
> 6. Return exactly one decision for every supplied item_id and no other item_ids.
>
> Return JSON only:
> `{"decisions":[{"item_id":"item_0","matched":true},{"item_id":"item_1","matched":false}]}`

The judge user message labels the clinical prompt, answer, and rubric items.
Each rubric line has the following form:

```text
[item_id] points=+2 :: criterion text
```

Reference results use:

- the answer model named in the result file;
- `gpt-5.6-sol` as judge;
- one judge pass per answer;
- judge temperature `0` when supported by the model;
- exact validation of returned `item_id` values.

The runner rejects incomplete, duplicate, or unexpected judge decisions.

## 3. Case scoring

Let `m_i` be 1 when rubric item `i` is matched and 0 otherwise, and let `w_i`
be its signed `points` value.

### Points rubrics

The unbounded signed score is:

```text
raw = sum(m_i * w_i) / sum(max(w_i, 0))
```

The reported case score is:

```text
score = min(1, max(0, raw))
```

Thus positive criteria earn credit, matched negative criteria deduct credit,
and a case score remains in `[0, 1]`.

### F1-weighted rubrics

`safety_diagnostic` and `safety_therapeutic` use `f1_weighted_rubric`.
Signed `points` map to a 1–9 severity class, then to weights:

```text
points     +3  +2  +1   0  -1  -2  -3
class       9   8   7   5   3   2   1
weight     72  24   3   1   3  24  72
```

```text
recall    = Σ w for matched items with class ≥ 7
            / Σ w for all items with class ≥ 7

precision = Σ w for matched items with class ≥ 7
            / Σ w for all matched items

score     = 2PR / (P + R), or 0 when P + R = 0
```

An unmatched class 9 (omitted +3) or a matched class 1 (endorsed −3) zeros
the case. A matched equivocal item (class 5) can enter the precision
denominator; it does not enter recall. Unmentioned harmful actions are true
negatives and do not earn credit.

## 4. Aggregation and uncertainty

Each benchmark score is the arithmetic mean of its 50 case scores. The overall
BedsideBench score is the macro-average of the 10 benchmark means. Because all
benchmarks contain 50 cases, this also equals the mean of all 500 case scores.

The runner reports percentile 95% bootstrap confidence intervals using 10,000
resamples and seed 42:

- benchmark intervals resample cases within that benchmark;
- the overall interval uses a stratified bootstrap, independently resampling
  50 cases within each benchmark before macro-averaging benchmark means.

These intervals measure case-sampling uncertainty. They do not measure variation
from answer generation, judge calls, or later provider changes to a model.

## 5. Run the evaluation

Set an API credential in the environment:

```bash
export OPENAI_ACCESS_TOKEN="..."
python3 evaluation/run_benchmark.py \
  --answer-model gpt-5.4-mini \
  --judge-model gpt-5.6-sol \
  --output tmp/evaluations/gpt-5.4-mini.jsonl
```

Run one deterministic case from each benchmark first:

```bash
python3 evaluation/run_benchmark.py \
  --answer-model gpt-5.4-mini \
  --judge-model gpt-5.6-sol \
  --output tmp/evaluations/gpt-5.4-mini-smoke.jsonl \
  --smoke
```

The output is append-only JSONL. Rerunning the same command skips completed
cases. The runner writes the aggregate result to the same path with
`.summary.json` replacing `.jsonl`. `--summarize-only` prints the same summary
without API calls.

## 6. Report results

Report all of the following:

- answer and judge model identifiers;
- protocol version;
- dataset digest;
- number of completed and failed cases;
- each benchmark mean and 95% confidence interval;
- overall macro-average and 95% confidence interval;
- number of judge passes per answer.

`dataset_sha256` is SHA-256 over a compact, key-sorted JSON serialization of the
500 case objects in registry order. It excludes manifests, documentation, and
generated Parquet files. The runner computes this value and includes it in every
summary.

The runner's summary output is the artifact to publish for a full evaluation;
raw answers and item decisions remain in the local append-only JSONL output.

Model identifiers do not guarantee immutable behavior. Comparisons are strongest
when systems are evaluated in the same run with the same judge configuration.
