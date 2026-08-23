# Measurements

**Last Updated**: 2026-08-23

Every number this project's design rests on, with the hardware it was taken on,
the date, and the spread. Rule #10 in one page: **an unmeasured number is
labelled an estimate and may not be used to justify a design.**

Two rules govern this page:

- A figure is either **measured** - and then it carries hardware, date and
  spread - or it is listed under [Still unmeasured](#still-unmeasured) with the
  measurement that would settle it. There is no third category.
- **A laptop measures the laptop.** Every figure below taken on an i7-1265U is
  an order-of-magnitude check, not a runner figure. The runner has a different
  core topology, different memory bandwidth, and a shared host. Nothing here
  substitutes for `.github/workflows/measure.yml` running on `ubuntu-latest`.

## Inference throughput

`llama-bench -m <model> -p 730,1800,4850 -n 250 -t 4`, at the three input
lengths a short, medium and long article actually produce.

### On the runner (authoritative)

**Measured 2026-08-22** on `ubuntu-latest`: AMD EPYC 9V74 80-Core, 4 threads,
llama.cpp `b10580`, 3 repeats. These are the `llama-bench` numbers a design
decision may cite for article-length prefill and decode. They are not the
prompt-cache cost in the live digest path; use
[Prompt cache reuse](#prompt-cache-reuse) for that. The laptop tables below are
kept only to show how far a laptop misleads.

| Model | 730 tok | 1800 tok | 4850 tok | decode (250) |
| --- | --- | --- | --- | --- |
| Qwen3-4B-Q4_K_M | 22.1 +/- 0.2 | 20.8 +/- 0.0 | 17.1 +/- 0.1 | **13.00 +/- 0.03** |
| Qwen3-8B-Q4_K_M | 12.1 +/- 0.0 | 11.6 +/- 0.0 | 10.4 +/- 0.0 | **7.28 +/- 0.01** |

The spread collapsed against the laptop: stddev on the runner is 0.0-0.2 tok/s
where the laptop showed up to 4.49. A shared laptop with thermal throttling was
measuring its own scheduler as much as the model.

**The 8B is 1.8x slower to decode, not 3.3x.** The laptop's 3.3x was the
headline number behind "the 8B may not fit". On real hardware the gap is roughly
half that, and the 8B fits comfortably.

**Weight download, cache miss:** 4B 2.4 GB in 32s, 8B 4.7 GB in 180s. Both are
one-off per cache key; the 10 GB cache holds both.

### Derived seconds per article

Derived from the runner table by `backend/utilities/summarise_bench.py`, using
the **measured** length buckets in [Corpus shape](#corpus-shape). Derived, not
measured: they inherit both the throughput spread and the bucket error.

| Model | short | medium | long | blended | worst long |
| --- | --- | --- | --- | --- | --- |
| Qwen3-4B-Q4_K_M | 45s | 127s | 232s | **112s** | 363s |
| Qwen3-8B-Q4_K_M | 82s | 225s | 393s | **196s** | 597s |

The blended figures were first published as 128s and 196s -> corrected to 112s
and 196s when the bucket shares were replaced by the measured ones. A blended
number is a statement about a corpus; blending against a corpus that was
disproved the same day is arithmetic on a fiction.

**The shard timeout stays worst-case.** A 5-item shard drawing five long
articles on the 8B is 5 x 597s = 50 minutes. `digest.yml` sets 330 minutes,
which is generous - and a timeout should be. It must never be re-derived from
the 196s blend, which would set it at 17 minutes and kill healthy shards that
happened to draw long articles.

### On a laptop (kept only as a warning)

### Qwen3-4B-Q4_K_M

Hardware: Intel Core i7-1265U, 4 threads. Date: 2026-08-15. Repeats: 3.

| n_prompt | prefill tok/s | stddev |
| --- | --- | --- |
| 730 | 24.05 | 1.46 |
| 1800 | 18.35 | 4.49 |
| 4850 | 12.34 | 3.02 |
| decode (250) | 6.07 | 0.15 |

### Qwen3-8B-Q4_K_M

Hardware: Intel Core i7-1265U, 4 threads. Date: 2026-08-15. Repeats: 2.

| n_prompt | prefill tok/s | stddev | vs 4B |
| --- | --- | --- | --- |
| 730 | 9.30 | 0.80 | 2.6x slower |
| 1800 | 8.40 | 2.00 | 2.2x slower |
| 4850 | 6.30 | 0.30 | 2.0x slower |
| decode (250) | 1.84 | 0.17 | **3.3x slower** |

### Derived seconds per article, on the laptop

Superseded by the runner table above. Kept because the gap between the two is
the finding: this said the 8B cost 2.9x a short article, and the runner says
1.8x. Nothing here may be cited.
| bucket | 4B typical | 8B typical | multiple |
| --- | --- | --- | --- |
| short | 55 s | 160 s | 2.9x |
| medium | 131 s | 323 s | 2.5x |
| long | 435 s | 906 s | 2.1x |
| blended | 173 s | 399 s | 2.3x |

Worst case matters more than the blend for one decision: a single long article
on the 8B is 1223 s worst, so a five-URL shard that draws five long articles is
roughly 102 minutes. Job timeouts are set from that number, not from 399 s.

**Three findings that changed the design**, all of which contradicted an
estimate:

1. **Prefill tok/s degrades with context length** (24.1 -> 18.3 -> 12.3 on the
   4B). The estimate assumed a constant rate; attention is quadratic, so the
   long bucket came out 4.5x worse than predicted while short was only 1.9x
   worse. Any future length estimate has to model prefill as a function of
   context length.
2. **Decode degrades worse than prefill on the larger model** (3.3x against
   2.0x) despite roughly 2x the weights. Decode is memory-bandwidth-bound and
   4.68 GiB streams from RAM with no reuse, while prefill still gets arithmetic
   intensity from batching. Output length is therefore a first-class cost lever
   on the 8B: 250 tokens at 1.84 tok/s is 136 s of pure decode.
3. **Truncation is a performance lever, not only a safety cap.** Capping at
   2500 instead of 6000 input tokens takes a long 8B article from ~906 s to
   ~450 s and the blended figure from 399 s to ~308 s.

The stddev is ~25% of the mean at 1800 and 4850 tokens, which is thermal
throttling on a laptop. A shared-host runner may be better or worse; the CI run
must report its own spread rather than inherit this one.

## The summarizer prompt in tokens

**Measured 2026-08-23**, `llama-tokenize` against `Qwen3-8B-Q4_K_M.gguf` on a
developer machine, on the rendered prompt with LF line endings. Tokenization is
deterministic, so the spread is zero and the hardware does not matter - the
tokenizer does. A different model file gives a different count.

| Prompt | Words | Tokens |
| --- | --- | --- |
| Before the Title section | 653 | 864 |
| With the Title section | 781 | 1033 |
| **After the terseness pass** | **598** | **801** |

The terseness pass removed 183 words and **232 tokens, 22.5%**, without removing
a rule. What went was justification, restatement, and one line the decoder
already enforced. See
[../architecture/summarize/prompt.md](../architecture/summarize/prompt.md).

Against the 8192 `n_ctx` the pipeline runs at:

| Component | Tokens |
| --- | --- |
| System prompt | 801 |
| Article, at the 2500-token truncation cap | 2500 |
| Output budget | 900 |
| **Worst case** | **4201 of 8192** |

Three notes worth keeping:

- **Measure the prompt with the line endings the model is sent.** The same
  rendered prompt tokenizes at 801 with LF and 880 with CRLF - a 79-token, 10%
  difference from nothing but a file write. Python's default text mode
  translates on Windows, so a measurement taken that way overstates the prompt
  by a tenth.
- **The prompt-cost estimate is superseded for live digest runs.** The old
  derived value used 801 tokens at the `llama-bench` 730-token rate of 12.1
  tok/s, or 66.2 s. Run `32648218952` measured the live digest path at 34.23
  tok/s median, so the same 801 tokens cost 23.4 s median. Use the prompt-cache
  table below for prompt-reorder decisions.
- **`fits_context` over-reserves and does so on purpose.** It approximates the
  prompt as `words x 2`, which is 1196 against the measured 801. It errs by
  395 tokens in the safe direction, and the alternative - tokenizing the prompt
  per item to save context we are not short of - buys nothing.

## Prompt cache reuse

**Measured 2026-08-23** on GitHub-hosted `ubuntu-latest`, 4 vCPU, run
`32648218952`, job `work (3)`. The job log did not name the CPU model or the
llama.cpp build. It used `Qwen3-8B-Q4_K_M.gguf` through `llama-server` with
`--ctx-size 8192 --batch-size 512 --ubatch-size 512 --threads 4 --no-warmup`.

The run refutes the suspected context-splitting defect for this build. The log
said:

```text
srv load_model: initializing, n_slots = 4, n_ctx_slot = 8192, kv_unified = 'true'
```

Current llama.cpp source names the same quantity `n_ctx_seq`: when `kv_unified`
is true, `n_ctx_seq = n_ctx`; when it is false, `n_ctx_seq = n_ctx / n_seq_max`.
This log uses the older `n_ctx_slot` name. The value is still 8192 per slot, so
the 4201-token worst case fits. This is not a live defect in run `32648218952`.

The run does **not** settle whether the prompt prefix was reused. The grep
emitted no `kv cache rm [p0, end)` line. The only emitted instrument was
`prompt eval time = X ms / N tokens`, and `N` varies with article length and
band. Because `band_for()` changes the rendered prompt, only the roughly
315-token head is invariant across all bands. A same-band hit could reuse more,
but the log did not print the band or article token count beside each timing
line.

| Slot | Prompt-eval tokens, in task order |
| --- | --- |
| 2 | 2441, 580, 654, 781, 862, 621, 738, 1195, 1064, 1883 |
| 3 | 2485, 2545, 1146, 2284, 1035, 1423, 1945, 850, 373, 1260, 1015, 1131, 440, 1136, 636, 888, 572, 444, 1179, 1426, 485, 1380, 2565, 1687, 607, 730 |

No fixed subtraction of about 315 or 801 tokens is visible within either slot.
That is evidence that the current log cannot prove reuse, not evidence that a
cache miss happened. To settle it, log the slot id, item id, band id, rendered
system-prompt tokens, article tokens, full prompt tokens, evaluated prompt tokens
and any llama.cpp reused-prefix field such as `p0` or `n_past`.

| Quantity | Value |
| --- | --- |
| Sample | 36 `print_timing` lines from `work (3)` |
| Prefill throughput | min 29.24 tok/s, max 37.92 tok/s, median 34.23 tok/s |
| Spread | 8.68 tok/s |
| 801-token re-prefill cost | 23.4 s median; observed range 21.1-27.4 s |
| 315-token invariant-head cost | 9.2 s median; observed range 8.3-10.8 s |

This supersedes the derived 66.2 s per 801-token re-prefill above for live
`digest` runs. That older number came from `llama-bench` on an EPYC 9V74 runner
and remains useful history. This run measured the actual `digest` path on a
GitHub-hosted `ubuntu-latest` runner, and it was about 2.8x faster at the median.

The row 9 prize changes. The old arithmetic was `13 x 66.2 s = 14.4 min` of CPU,
or about 4.4 min wall clock across four shards. This run says `13 x 23.4 s =
5.1 min` of CPU for a full 801-token prefix, or about 1.3 min wall clock across
four shards. For the invariant head, the ceiling is `13 x 9.2 s = 2.0 min` of
CPU, or about 0.5 min wall clock. Row 9 should not reorder the prompt on the old
66.2 s premise. It should first add the instrumentation above, then run an A/B
measurement on the runner and keep the change only if the measured wall-clock
gain pays for the prompt risk.

Row 9 collapsed the prompt reorder on this measurement. It did not move the
band-varying numbers to the tail of the system prompt, because the live runner
showed a 1-2% wall-clock ceiling, and the existing log cannot prove the reuse
the change was meant to buy. Reopen the reorder only with runner A/B evidence
that logs slot id, item id, band id, rendered system-prompt tokens, article
tokens, full prompt tokens, evaluated prompt tokens, and a reused-prefix field
such as `p0` or `n_past`; the golden set's `output_digest` values must stay
unchanged.

### The prompt token counts, from the tokenizer

**Measured 2026-08-23.** Method: `backend/bin/llama-tokenize` against
`backend/models/Qwen3-8B-Q4_K_M.gguf`, over the system prompt rendered from the
committed `config/` for every band. A token count is a property of the tokenizer
and the text, so it does not vary with the machine that counted it.

Every earlier figure for this prompt came from a word-share count, not a
tokenizer, and every one of them was wrong:

| Quantity | Earlier estimate | Measured |
| --- | --- | --- |
| Full system prompt | 801 tokens | **877-879 tokens** |
| Invariant shared prefix | about 315 tokens | **381 tokens** (296 words) |
| Distinct rendered prompts | 3 | **4** |

The prefix ends exactly where `band_for()` substitutes the word range, at
`Length:\n\n- Write one summary of `. The fourth distinct prompt is the brief
band that row 8 added; the earlier count of three predates it.

Re-running the row 9 arithmetic on the measured head and the measured prefill
throughput of 34.23 tok/s: 381 tokens costs **11.1 s** per item, so 13
recoverable items is **2.4 min** of CPU, or about **0.6 min** of wall clock
across four shards. That is 21 percent more than the 315-token estimate implied,
and it does not change the decision - the ceiling is still 1-2 percent of a run.
**Row 9's collapse survives its own correction.**

## llama-server runtime sweep

**Status 2026-08-23:** harness added, sweep not yet run. No runtime flag is
adopted by this change. `startup_warmup = true` records the behaviour that PR
#24 already put in `digest.yml`; it is not a new adoption here.

The `runtime` job in `.github/workflows/measure.yml` runs one dispatch per
candidate flag. It creates a fixed five-article run plan for that dispatch, then
runs a same-dispatch baseline three times and the selected candidate three
times. It records wall-clock, startup time, per-item timings, server RSS samples,
cgroup memory peak, the full `server_argv`, and parsed server facts such as
`n_slots`, `n_ctx_slot` and `kv_unified`. It reports medians, spreads, and
whether the candidate beat the baseline outside the measured spread. It rejects a
candidate when any `output_digest` differs between repeats or from the baseline.

The baseline remains:

```text
--model --alias --ctx-size 8192 --batch-size 512 --ubatch-size 512 --threads 4 --port 8080
```

Each candidate is still pending unless a later runner artifact records hardware,
date and spread:

| Candidate | Flag under test | Status |
| --- | --- | --- |
| `np1` | `-np 1` | Defect half settled by PR #23: run `32648218952` logged `n_slots = 4`, `n_ctx_slot = 8192`, `kv_unified = 'true'`, so the measured 4201-token worst case still fits. Optimization value pending. |
| `batch2048` | `-b 2048` | Pending. Hypothesis: the current `--batch-size 512` may throttle prefill. Use the measured live-digest prefill median of 34.23 tok/s, range 29.24-37.92, spread 8.68 from run `32648218952`, not the older derived 12.1 tok/s figure. |
| `no_startup_warmup` | restore `--no-warmup` | Pending reversal check. PR #24 already made startup warmup the digest default after a golden-set check. The harness records server startup and shard wall-clock separately. |
| `flash_attention_on` | `-fa on` | Pending. Different attention math is allowed only if every golden `output_digest` is unchanged. |
| `load_mode_mmap_mlock` | `-lm mmap+mlock` | Pending. Hypothesis: pinning the 4.68 GiB weights may avoid page-out. The harness records RSS and cgroup memory peak. |
| `kv_q8` | `-ctk q8_0 -ctv q8_0` | Pending. Quantised KV changes numeric paths. It is rejected outright if the digest map changes. |
| `np2_inflight` | `-np 2` plus two in-flight workers and `-c 16384` | Pending composite scenario. It is labelled composite because it is not a pure one-flag test. |
| `prio_poll` | `--prio 2 --poll 100` | Pending. Hypothesis: higher priority and polling may help after install work stops competing for CPU. |
| `threads_batch` | `-tb N` | Pending. Only worth interpreting if `batch2048` shows prefill is the bottleneck. |

The current llama-server verbosity emits no `kv cache rm` lines, so this harness
does not claim to observe prompt-cache reuse directly. Absence of that line is a
logging limit, not evidence that reuse did or did not happen.

## Weights on disk

Hardware: local filesystem. Date: 2026-08-21. Method: `stat`.

| File | Bytes | GiB |
| --- | --- | --- |
| `Qwen3-4B-Q4_K_M.gguf` | 2,497,280,256 | 2.33 |
| `Qwen3-8B-Q4_K_M.gguf` | 5,027,783,488 | 4.68 |
| both | 7,525,063,744 | 7.01 |

This is why the weights are cached rather than committed: GitHub hard-rejects
any file over 100 MB, and both files sit inside the 10 GB repository cache with
under 3 GB to spare.

## Published payload size

### Prose compression

Hardware: Intel Core i7-1265U. Date: 2026-08-20. Method: gzip over 32 prose
files, 276,887 B -> 94,690 B.

**2.92x.** This is the ratio the day-payload arithmetic uses.

### The day payload

Hardware: Intel Core i7-1265U. Date: 2026-08-21. Method: gzip level 9 over
`tests/fixtures/contracts/digest-day/two-runs.json`.

| Quantity | Value |
| --- | --- |
| Fixture day, 3 items | 3,650 B raw, 1,078 B gzipped (3.39x) |
| Per item, raw | 1,217 B |

**Read this as the contract's overhead, not as a production day.** The fixture
carries three items with short summaries, and gzip over 3.6 KB has barely
warmed its dictionary. It replaces the earlier ~2.2 KB-per-item estimate as an
order-of-magnitude check on the *shape*; a real 17-item day is measured after
the first pipeline run, not before it.

### Days to the 1 GB Pages ceiling

Derived from the above plus the image estimates below, which are the weak link -
see [Still unmeasured](#still-unmeasured).

| Scenario | KB/day | days to 1 GB |
| --- | --- | --- |
| PNG, an image on every item | 8,537 | 123 (4 months) |
| WebP, an image on every item | 1,567 | 669 (22 months) |
| WebP, an image on one item in three | 547 | 1,917 (5.25 years) |
| no images | 37 | 28,340 |

The ordering of the levers falls straight out of this: encoding buys 5.6x,
honouring the visual rule buys another 2.9x, and retention is what remains
after both. See [../architecture/publishing/layout.md](../architecture/publishing/layout.md).

## Feed availability

**Measured** on a developer machine (i7-1265U, Windows, 2026-08-21) by running
the real plan stage against the ratified `ai` list - a better check than a
bespoke script, because it exercises the code that will do it daily.

| Quantity | Value |
| --- | --- |
| Feeds configured | 36 |
| Resolved on the first pass | 26 |
| Recovered by finding the real feed URL | 5 |
| **Live after correction** | **31, against a floor of 25** |
| Retired: `robots.txt` forbids or is unreadable | 4 |
| Retired: the publisher declares no feed at all | 1 |

Two of the retirements are permanent by the host's own instruction rather than
defects to fix. One publisher (`ai.meta.com`) is a JavaScript application that
declares no feed on any path, which is a category the plan did not anticipate:
a source can be real, active and unreachable by RSS.

Two figures from the same runs, both single observations and both a laptop
rather than a runner: **one feed read takes roughly 0.5-4 s including its
`robots.txt`**, and a whole 36-feed plan pass finishes in **under a minute**.
That matters only as a shape: the planning step loads no weights, so fanning out
afterwards is what costs, not deciding the day.

**Summarization, Qwen3-4B-Q4_K_M, 4 threads, i7-1265U, 2026-08-21, n=1:** a
2,557-token article took **89 s** end to end for 179 output tokens. One
observation on a laptop, recorded because it is the first real per-article
number this project has; it is not a runner figure and may not be used as one.

### What the robots policy cost

#### On the runner (authoritative)

**Measured 2026-08-23** on `ubuntu-latest`, by running the same day twice: run
1 (`32624081323`) on the old policy, run 2 (`32634191910`) on the new one, same
date, same config, same feed list. Comparing two real plan passes is a better
check than any script, because it exercises exactly what runs daily.

| Quantity | Before | After |
| --- | --- | --- |
| Feeds read | 115 | **132** |
| Feeds refused | 31 | **14** |
| Items published | 8 | 9 |
| Eval rows written | 0 | **9** |

**17 feeds recovered.** The 14 that still refuse are the check on the change:
the policy keeps refusing when a host serves a file that says no, and keeps
refusing when nobody answers at all.

The published count moved by only one because the daily cap, not the feed
count, decides how many items a reader gets. What a wider pool buys is
**choice**: 17 items are now selected from a larger candidate set, so the
ranking has more to rank. Feed count is an input to quality, not to volume.

The eval-row column measures a different fault fixed in the same commit: the
scorer had been disabled on every scheduled run, so the ledger had never once
been written by automation. Nine rows is the first time it has.

#### On a developer machine (kept for the IP contrast)

**Measured 2026-08-23** (i7-1265U, Windows), n=1 per feed, against the 26 feeds
run 1 recorded as `robots_denied`, driving the real fetcher.

| Outcome after the change | Feeds |
| --- | --- |
| **Recovered** | **19** |
| Still refused - a served `robots.txt` disallows the path | 2 |
| Still refused - the article itself answered HTTP 403 | 4 |
| Still refused - the host reset the `robots.txt` connection | 1 |

Ten of the nineteen serve no `robots.txt` at all and answered 404. Reading
"no such file" as a refusal was a rule we invented and the host never wrote,
and it was silently costing the digest most of its `business-economy` and
`world` candidates.

This page predicted the runner would recover fewer than 19 because a developer
IP is not a runner IP, and several of the 403s were a WAF answering a
datacentre address. The runner recovered 17. **The laptop over-counted by two,
in the direction predicted** - which is the reason the runner table sits above
this one and the laptop table is kept only for the contrast.

### Why the other items failed

**Measured 2026-08-23** on a developer machine (i7-1265U, Windows), by
re-fetching all 9 failures of run 1 and comparing what the extractor returned
against the prose actually present in the markup.

| Items | Source | Extracted | Cause |
| --- | --- | --- | --- |
| 2 | GitHub release tag | 51, 162 words | The page is a list of binary names. The largest prose block in the markup is GitHub's own "You signed in with another tab" furniture |
| 2 | NBER paper page | 128, 178 words | The extractor returned **the abstract, correctly**. The paper is a PDF |
| 1 | Marginal Revolution | 229 words | The post is 277 words. The extractor got 83% of it |
| 2 | Japan Times | 86, 111 words | Metered paywall |
| 2 | IAEA | never fetched | HTTP 403 at the WAF |

Fetches took **0.45-0.80 s**, and no item failed on a timeout or a retry
budget. Two hypotheses are ruled out by this table: the sources are not slow,
and they are not JavaScript shells hiding their text from the extractor.

**The extractor is behaving correctly.** The 250-word floor is rejecting
short-form sources that were extracted properly - a release tag, an abstract,
a short blog post. That makes the low count a **source-selection** result
rather than an extraction defect, and it is why raising the floor's pass rate
belongs in `config/sources.json` and not in `extract.py`.

## CI and publish wall-clock

**Measured 2026-08-23** on GitHub-hosted `ubuntu-latest`. Single observed run
per gate; values are rounded wall-clock durations. Spread is not available for
this row because each gate has one observation.

| Gate | Duration | Spread |
| --- | --- | --- |
| `ci` | about 2 min | n=1; not available |
| `site` | about 2 min | n=1; not available |
| `pages` | about 50 s | n=1; not available |
| `digest` | about 25 min | n=1; not available |

The publish path is the long pole. Orchestrators should not serialize
independent work on these gates; the merge gate still waits for green checks.

## Corpus shape

**Measured 2026-08-22**, `ubuntu-latest` (4 vCPU), the `corpus` job in
`.github/workflows/measure.yml`, over 20 live articles pulled from the
configured feeds and extracted the way the pipeline extracts them.

| Statistic | Words |
| --- | --- |
| mean | 1323.5 (+/- 1297.6) |
| p10 | 248 |
| p50 | 978 |
| p90 | 2769 |
| max | 5077 |

| Bucket | n | Share | Median words |
| --- | --- | --- | --- |
| short | 10 | 0.50 | 411 |
| medium | 5 | 0.25 | 1546 |
| long | 5 | 0.25 | 2769 |

**This contradicts the design's assumption, so the design moves.** The cost
model assumed 400 / 1200 / 3500 words at a 25 / 55 / 20 share. The real share is
50 / 25 / 25: the corpus is far more bimodal than assumed, with twice as many
short articles and a quarter rather than a fifth long. The standard deviation is
roughly the mean, so "the average article" is not a thing that exists here - any
per-article figure multiplied by a mean is describing a corpus we do not have.

Two consequences, stated before anyone re-derives them:

- **Blended throughput estimates were too pessimistic.** Half the corpus is in
  the cheapest bucket, not a quarter of it.
- **Worst-case shard timeouts were too optimistic.** The long bucket is bigger
  than assumed and p90 sits at 2769 words. The timeout must keep coming from the
  worst case, never from the blend.

Caveat, stated rather than buried: n=20, one sample, one day. It settles that
the old buckets were wrong. It does not settle what the right ones are.

## The image measurement killed the runner

**Attempted 2026-08-22**, `ubuntu-latest`, the `image` job timing Z-Image-Turbo
on CPU. It ran for 48 minutes inside a 120-minute budget and then:

```
##[error]The runner has received a shutdown signal.
```

That is not a timeout. The job had 72 minutes left. A shutdown signal with time
on the clock is the runner agent being taken down underneath the job, which on a
16 GB machine running CPU diffusion is what memory exhaustion looks like from
the inside.

**This is itself evidence for Row #9.** The question that row asks is whether
generated images fit the published budget. Before reaching the byte count, the
measurement could not survive the machine. A feature whose *benchmark* cannot
complete in a job is not a feature that belongs on a 4 vCPU runner without
something changing first.

It does not settle the byte question, and it must not be cited as if it did. It
settles that the current approach to answering it does not run.

## Still unmeasured

Each line names the measurement that would settle it. Nothing here may be cited
to justify a design decision.

| Quantity | Current basis | What settles it |
| --- | --- | --- |
| **Faithfulness scoring seconds per item** | **unmeasured** | **a timed pass over 20 fixture pairs at the three premise lengths; it decides whether the scorer is a census or is sampled** |
| **Whether the prompt prefix is reused at all** | **unmeasured, and currently unobservable** | a permanent instrument, not a one-off grep. `usage.prompt_tokens` reports the full prompt whether cached or not, and llama-server emits no `kv cache rm` line at our verbosity, so the question went blind again the moment row 3 closed. Log slot id, item id, band id, rendered system-prompt tokens, article tokens, full prompt tokens, evaluated prompt tokens, and `p0` or `n_past`. |
| **`max_output_tokens` and `truncation_cap_tokens` as wall-clock levers** | **unswept** | the `runtime` job in `measure.yml` sweeps llama-server runtime flags only. These two set how much text is prefilled and how much is decoded per item, which is the tail of a run rather than its median. Sweep them the same way: one value at a time, 3 repeats, fixed shard, golden `output_digest` unchanged. |
| Cache-restore time per job, cache-hit | ~90 s, asserted | the same artifact, on a second run |
| Image render seconds at 512 and 768 | the job cannot complete | a smaller model, a smaller resolution, or a machine that survives it |
| Image bytes, PNG at 768 | ~500 KB, estimate | the `image` job writes the file; measure it |
| Image bytes, WebP q80 at 768 | ~90 KB, estimate | re-encode the same file and measure |
| A production day payload | fixture figure above | the first real pipeline run |
| HHEM scoring seconds per item on CPU | unmeasured | lands with the eval harness |
| Whether 1-2 bit quantisation changes the fit | unevaluated | open question 4 in the plan-doc |

## How to add a row here

Run the measurement, then record the quantity, the value, the spread, the
hardware and the date. If a number arrives without those four, it is an
estimate and belongs in the table above rather than in the tables below it.

When a measurement contradicts a design, the design changes - that has already
happened three times on this page.

## See also

- [../../CLAUDE.md](../../CLAUDE.md) - Rule #2 (the runner is the architecture) and #10 (measured, not estimated).
- [../architecture/publishing/layout.md](../architecture/publishing/layout.md) - the published-size arithmetic these numbers feed.
- [../concepts/pipeline-loop.md](../concepts/pipeline-loop.md) - the batch-size rule these numbers set.
- [../architecture/summarize/prompt.md](../architecture/summarize/prompt.md) - the prompt the token count above measures.
- [../how-to/set-up-local-inference.md](../how-to/set-up-local-inference.md) - reproducing the local runs.
