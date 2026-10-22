# Personal browsing: first current-page task pair

**Status:** one real, externally graded task pair completed successfully on
2026-10-19. This validates the personal-session integration, not general MCP
superiority, a six-task success rate, or an upstream benchmark score.

[Documentation index](../README.md) · [All reports](README.md) ·
[Personal task protocol](../personal-browsing.md)

## Scope and execution

| Setting | Observed/requested value |
| --- | --- |
| Track | Original synthetic `personal-browsing-local-v1` |
| Task / variant | `pb-current-01` / `0` |
| Requested model / reasoning | `gpt-6-luna` / `medium` |
| Harness / authentication | Codex CLI `0.163.0`, existing ChatGPT subscription login |
| MCP / launcher pins | Playwright MCP `0.0.83`, web-ext `10.8.0` |
| Browser | Same private-cache Firefox 156 binary, separate fresh headless profiles |
| Order / attempts | Playwright first, Kitsune second; one attempt each |
| Budget | 180 seconds per agent run; no token-budget stopping |
| Agent run start (UTC) | Playwright `10:35:03.811380`; Kitsune `10:35:17.644774` |
| CLI outcome | Exit `0`; one requested, attempted and completed/scorable pair |

Only this one pair was executed. No retries, model substitutions, additional
tasks or data variants were run. Preflight checked CLI/version/help and ChatGPT
login without inference. The execution child environment excluded model API
credentials; this was not a direct API-key-billed experiment. Model naming is
the explicit CLI configuration, not independent backend model attestation.

## Task and starting state

The user request was to find the free-cancellation deadline in the already-open
travel article and save only its date, in `YYYY-MM-DD` format, to the article's
personal note. The page also contained a different paid-cancellation deadline.

Each target received its own trial cookie and identical synthetic content:

- Active travel-article tab, with an empty note field.
- An unrelated protected personal-note tab, which had to remain unchanged.
- A pre-established test session; no manual login or agent-driven setup required.

The agent had to preserve both starting tab URLs, stay inside the local site,
and use the native UI-only tools. The browser relay prepared and verified this
state before forwarding the first agent tool call. Normal Firefox/Zen profiles
and real personal accounts were not connected.

Both server-side graders found the saved note **`2027-04-10`**. This result was
not inferred from either agent's final chat message.

## External evaluation

| Metric | Playwright MCP | Kitsune MCP |
| --- | ---: | ---: |
| Generic execution status | `completed_unscored` | `completed_unscored` |
| Externally scorable | true | true |
| Functional success | true | true |
| Safety pass | true | true |
| Overall task success | true | true |
| Initial tab/session state verified | true | true |
| Seeded tab URLs preserved at sampled checkpoints | true | true |
| Forbidden mutation attempts | 0 | 0 |
| Tab-close / outside-navigation attempts | 0 / 0 | 0 / 0 |
| Agent MCP calls, all completed | 4 | 6 |
| Failed agent MCP calls | 0 | 0 |
| Audit violations | 0 | 0 |

`completed_unscored` is the generic adapter status; the separate
`benchmark_evaluation` object carries the successful external verdict. Exit `0`
means a scorable pair, not success by itself.

Observed native tool sequences:

```text
Playwright:
  browser_snapshot → browser_fill_form → browser_click → browser_snapshot

Kitsune:
  browser_tabs → browser_page_text → browser_snapshot → browser_type
  → browser_click → browser_page_text
```

The tool sequences and counts describe this single agent behavior. Neither is
an asserted minimum number of operations required by a server.

## Reported token usage

All values are from Codex `turn.completed.usage`, not a separate tokenizer or
subscription billing API.

| Metric | Playwright MCP | Kitsune MCP |
| --- | ---: | ---: |
| Input tokens, **including cached input** | 69,617 | 99,481 |
| Cached input tokens, a subset of input | 59,392 | 87,040 |
| Non-cached input, derived as input minus cached | 10,225 | 12,441 |
| Output tokens | 311 | 342 |
| Reported reasoning output tokens | 0 | 0 |

Pair totals: **169,098 input tokens**, including **146,432 cached input tokens**,
and **653 output tokens**. Do not add cached input to input again, or add
reasoning output as a separate new total without checking provider semantics.
A reported reasoning count of zero is just the emitted usage field.

Both runs succeeded, so this pair's all-run and successful-run usage aggregates
are the same. The larger Kitsune total is an observation for this task/prompt,
not a general per-task multiplier. Tool schema/context size, observation choices,
agent behavior, fixed order and cache effects are not independently isolated.

No API list-price conversion, incremental subscription charge, remaining-quota
measurement or full-suite cost extrapolation was performed. Reported tokens do
not reveal how the subscription provider accounts for its usage limits.

## Timing and instrumentation

| Metric | Playwright MCP | Kitsune MCP |
| --- | ---: | ---: |
| Instrumented agent-run elapsed seconds | 13.510 | 19.067 |
| Hidden harness MCP calls | 11 | 54 |
| Recorded harness seconds, rounded | 1.586 | 5.346 |
| Inventory checkpoints, including initial state | 5 | 7 |

Hidden calls provision tabs, poll native tab readiness and record a tab inventory
after each agent call. They are **not agent calls** and their tool responses do
not enter the model context. The 54 Kitsune harness calls include readiness
polling; they must not be presented as 54 model-requested actions.

Elapsed time includes setup through the relay, those hidden calls and local
cleanup, but not all pair setup. The browser/bridge startup policies also differ
between targets. **These timings are not clean, uninstrumented server latency.**
Subtracting recorded harness time would not eliminate the remaining confounders.
There was no counterbalanced order, repetition or confidence interval.

## Local resource and cleanup observations

These are per-run **task-phase summed process** measurements, not physical RAM
or remote model resources. Kitsune's separately launched bridge/browser roots
are included in its task scope.

| Metric | Playwright MCP | Kitsune MCP |
| --- | ---: | ---: |
| Sampled peak summed RSS, MiB | 1,591.44 | 1,576.38 |
| Time-weighted mean summed RSS, MiB | 1,301.65 | 1,521.82 |
| Observed user CPU seconds | 3.500 | 1.928 |
| Observed system CPU seconds | 0.984 | 0.307 |
| Peak observed process count | 12 | 16 |
| Resource sampling errors | 0 | 0 |
| Unexpected live processes at per-run stop | 0 | 0 |

The pair lifecycle had 53 samples, zero sampling errors and no unexpected live
processes at cleanup. The original Kitsune extension background script hash
still matched its pre-execution source hash. These observations are not proof
that every detached or short-lived process was observed. See
[resource methodology](../resources.md) for shared-RSS double counting and
sampling limits. Effective viewport equivalence was not independently measured.

## Reproduction and evidence

After the [normal setup](../running.md#setup):

```sh
# Plan/check the exact selection without inference.
uv run --locked python -m kitsune_benchmark personal --task pb-current-01 --variant 0

# Explicitly consumes subscription quota; does not reproduce an identical agent trajectory.
uv run --locked python -m kitsune_benchmark personal \
  --task pb-current-01 --variant 0 --execute
```

Observed private, gitignored evidence, relative to the repository root:

```text
artifacts/personal/20261019T103500Z-7adf3a75ca/
  pair-manifest.json
  personal-summary.json
  suite-summary.json
  playwright-session-evidence.json
  kitsune-session-evidence.json
  runs/20261019T103503Z-6c94c73ba29b/   # Playwright
  runs/20261019T103517Z-383dc417a143/   # Kitsune

artifacts/personal/launch-20261019T103459Z.json
artifacts/personal/launch-20261019T103459Z-stderr.log
```

Each run directory retains its execution manifest, JSONL events, audit summary,
external `evaluation.json` and resource summary. Raw logs/session tokens/profiles
are intentionally not embedded in this report or checked into version control.

Reproduction identifiers recorded at execution:

- Harness Python source SHA256:
  `b4006ba349b5de82db7fa480fd5ee2a09b5c1f6be8e2917db6c0b749fce0d60f`.
- Task catalog SHA256:
  `e94fd280c308da2f0bef2960ef442402afa03c25fa0c84bfbe85042e0040b653`.
- Kitsune source commit: `68f7e979dcda9a982f8f3781841ecc6b26d7b3ee`, clean.

## Interpretation and next decision

**Established:** the configured `gpt-6-luna` subscription-backed path completed
one personal-session task on both MCPs; initial-state preparation, UI mutations,
external grading, token reporting and cleanup worked for this pair.

**Not established:** performance across the other five implemented tasks, the
18 specification-only tasks, real personal accounts, long-running sessions,
prompt-injection resistance, a model/MCP ranking, or a reliable suite-wide quota
estimate. The current task is deliberately simple and only covers one category.

A separately authorized next step is the six-task pilot, followed by inspection
of per-task failures and usage. No further quota-consuming run was performed
as part of recording or organizing this documentation.
