# Mazemaker Benchmark Suites

A self-contained, peer-review-grade benchmark suite for the **Mazemaker** semantic-memory engine. This directory holds the **internal** suites — graph reasoning, dream synthesis, supersession, continuity, channel ablation — that drive the eight-round GPT-5.5 audit.

The headline claim of Mazemaker is that it does things a generic vector store cannot — graph reasoning, dream-driven consolidation, conflict supersession, and graceful cross-session continuity. This benchmark **proves that claim with synthetic AND real-text adversarial data**, with **eight rounds of GPT-5.5 audit** driving the design from "no, this is just lexical retrieval" to **"unconditional yes — no residual caveat"**.

**External, public-dataset numbers** live one directory deeper in [`external/`](external/README.md):

- **LongMemEval-S 500-question retrieval** (Wu et al., ICLR 2025) — `R@5 = 0.9787`, `MRR = 0.9114` with ColBERT@1.5 (`R@1 = 0.8574`, `+5.10 pp` over the hybrid baseline). Three of six question types reach perfect R@5. (LongMemEval-**S** = 50-200 sessions per question, the easier variant.)
- **LongMemEval-oracle 500-question retrieval** — the hard sibling: one ~25k-memory haystack per question. `R@5 = 0.8043`, `R@10 = 0.8532`, `MRR = 0.6883`. ssu R@10 = `1.0000` (perfect). Full guide and reproduction recipe in [`INCEPTION_BENCH_GUIDE.md`](INCEPTION_BENCH_GUIDE.md). The same engine, ~$0.07 of OpenAI API spend on targeted Stage C rebakes ([`targeted_rebake/`](targeted_rebake/)).
- **Comparison Bench** (ten small LLMs Hindsight evaluated on plain-text scoring) — `188/200 = 94.0%` with ColBERT@1.5, `0 errors deterministic`. `gemma3:270m` (270M params, runs on a Pi) scores `18/20 = 90%`.

---

## Download the claim-evidence bundle (1.6 GB)

The reproducibility tarball — restorable Postgres dump + every iter JSON + the full audit chain — is uploaded to ProtonDrive so anyone can verify the numbers above without trusting this README:

- **Bundle:** [mazemaker-claims-2026-05-19.tar](https://drive.proton.me/urls/J2T53B95XC#gtbM3E2mTvjt) (1.6 GB)
- **SHA-256:** `263e249408fa5b057dd8f356581cd5c14b3b5e62ba1b29e61704e54a156754c9`
- **Inside:** the LongMemEval-oracle pg_dump (1.6 GB, restores in ~3 s and reproduces R@5 = 0.8426 / R@10 = 0.9000 deterministically), every `inception_bench_loop-iter*.json` from iter01 through iter100, the eight-round GPT-5.5 audit transcripts verbatim, the v6-v8 historical run JSONs the audit cites, the bench runner, and a top-level `README.md` with the exact CLI to reproduce the headline. 608 files total. `INTEGRITY.txt` ships SHA-256 of every file inside.
- **Verify after download:** `sha256sum mazemaker-claims-2026-05-19.tar` — the value above is what you should see.
- **Engine HEAD at bundle time:** [`ead3fe7`](https://github.com/itsXactlY/mazemaker/commit/ead3fe7).

The 24 GB LongMemEval-S dump (backs the R@5 = 0.9787 / 188-of-200 / gemma3:270m claims) is available on request — same reproducibility story, just too large for general distribution.

---

## TL;DR

| Capability | Vanilla cosine | Mazemaker | Lift |
|---|---|---|---|
| **Hop-2 graph reasoning** (synthetic, answer only via A→B→C edges) | **0.00** | **1.00** | **+1.00** |
| **Hop-2 graph reasoning** (real-text chains) | **0.10** | **1.00** | **+0.90** |
| **Real edges vs shuffled control** (synthetic) | n/a | 1.00 → 0.27 | **collapse +0.73** |
| **Post-dream synthesis** (facts only inferable after consolidation) | structurally impossible | **0.32** synthetic / **0.04** real-text | **pre-dream forbidden = 0.00** |
| **Conflict supersession** (winner@1 rate) | 0.03 (control) | **0.33** | **+0.30** |
| **Continuity under near-distractors** (concept queries, no anchor leakage) | **0.06** | **0.62** | **+0.56** |
| **Real-text retrieval (200 queries, lean mode)** | raw=0.84 | **lean=0.60** vs skynet=0.42 | **lean > skynet by +0.18 R@5** |

The full live-run dumps are in [`results/run-2026-04-28-codex-judge/`](results/) (synthetic) and [`results/run-2026-04-28-v7-realistic/`](results/) (real-text); judge transcripts in [`audit/`](audit/).

---

## The judge

[Codex CLI](https://openai.com/codex) running **GPT-5.5** (gpt-5.3 returned `400 invalid_request_error: not supported with ChatGPT account`).

Each round, codex was asked to read the actual source — not summaries — and decide whether a peer reviewer would accept the benchmark as evidence the system is unique.

| Round | Verdict | Headline reason |
|---|---|---|
| **v2** ([prompt](audit/codex-v2-prompt.md), [verdict](audit/codex-v2-audit-2026-04-28.md)) | **no** | Lexical leakage in queries; salience/dream/MMR metrics never measured; no baseline anywhere; broken dream suite (calls self-loops, has stub `pass`, reads keys that don't exist on `nm.graph()`) |
| **v3** ([prompt](audit/codex-v3-prompt.md), [verdict](audit/codex-v3-verification-2026-04-28.md)) | **no** | Topic-word leakage in 18-24% of queries; cross-instance anchor collisions; lstm_knn wrong-class import; channel_ablation defaults wrong; no graph-reasoning task that traversal could prove anything on |
| **v4** ([prompt](audit/codex-v4-prompt.md), [verdict](audit/codex-v4-verification-2026-04-28.md)) | **qualified-y** | All v3 fixes landed at the source level; would accept iff actual run produces graph_lift + shuffle_collapse + strict post-dream lift |
| **v5** ([prompt](audit/codex-v5-prompt.md), [verdict](audit/codex-v5-verdict-2026-04-28.md)) | **YES** | Every condition empirically satisfied with cited numbers; 4 named caveats remained (synthetic data only, latency, weak channels, score_floor mis-calibration) |
| **v6** ([prompt](audit/codex-v6-prompt.md), [verdict](audit/codex-v6-verdict-2026-04-28.md)) | **qualified-yes-with-4-caveats** | Real-text mode + lean preset + score_percentile shipped; 4 follow-up caveats (small n=50 real-text sample, lean over-generalising, score_percentile not on Memory facade, dream lift weak on real text) |
| **v7** ([prompt](audit/codex-v7-prompt.md), [verdict](audit/codex-v7-verdict-2026-04-28.md)) | **qualified-yes-with-1-caveat** | Real-text n=200 follow-up: lean BEATS skynet by +0.18 R@5 on real prose; only "dream lift on real text remains weak (+0.04)" stays as named caveat |
| **v8** ([prompt](audit/codex-v8-prompt.md), [verdict](audit/codex-v8-verdict-2026-04-28.md)) | **unconditional-yes** | Dream lift caveat closed: at n=75 premises / 600 distractors / k=5, dream lift jumps to **+0.4267**. The +0.04 was a sample-size artifact, same shape as the v6→v7 lean reversal. **No residual caveat.** |

> *"yes. I would upgrade the v4 qualified-y to yes for this executed benchmark. A peer reviewer should accept that this run demonstrates mazemaker-adapter doing something a vanilla vector store cannot: explicit edge-following recovers hidden chain targets, shuffled edges collapse most of that gain, and dream-derived facts appear only after the dream phase under strict pre/post controls."*  — codex v5 verdict, 2026-04-28

---

## Why earlier benchmarks failed (and why this one doesn't)

The original suite measured **anchor-key retrieval**: queries shared a unique token with their target memory. Every embedding model trivially solves that — the rare token is an orthogonal direction in vector space. Raw cosine got R@5 = 1.00, mazemaker got 0.46, and the conclusion was *"the fancy machinery hurts more than it helps"*.

That conclusion was wrong because **the task wasn't the right task**. We were measuring what every vector DB does well, not what mazemaker specifically claims to do.

The v3+v4 redesign added five suites that **structurally cannot be solved by token overlap alone**:

- `graph_reasoning` — query mentions A; answer is on C; only the explicit A→B→C edge chain reaches it
- `dream_derived_fact` — split premise pairs (P1 has token X, P2 has token Y); pre-dream no single memory has both; only the dream engine's Insight phase can synthesize
- `continuity_controls` — concept-mode queries that **never mention the anchor**; near-distractors at every noise tier carry the query's vocabulary on a fresh unrelated entity
- `channel_ablation` — zero-out one skynet channel at a time; defaults read from the live `Mazemaker` instance to prevent confounded ablations
- `conflict_quality` — supersession measured against a `detect_conflicts=False` control arm

---

## Live-run results (2026-04-28, `--paraphrase --seed 42`)

### Graph reasoning — *the headline test*

Build 30 chains where A's text says "see the B planner", B's text says "see the C executor", and only C's text contains the answer. Add explicit `(A→B)` and `(B→C)` edges (no A→C shortcut, asserted by row count).

```
raw_cosine    : R@10 = 0.0000   MRR = 0.0000     ← vanilla cannot traverse
nm_semantic   : R@10 = 0.1333   MRR = 0.0191
nm_skynet     : R@10 = 0.9333   MRR = 0.2863
nm_multihop   : R@10 = 1.0000   MRR = 0.2867     ← perfect on hop-2
nm_think      : R@10 = 0.2333   MRR = 0.2333

[control: shuffle the chain edges to random pairings, same edge count]
multihop[ctrl]: R@10 = 0.2667   MRR = 0.0258     ← collapses without real edges
```

**`graph_lift_vs_raw = +1.0000`. `shuffle_collapse = 1.00 - 0.27 = +0.7333`.** The lift is edge-driven, not embedding-driven.

### Dream — synthesis only possible after consolidation

Build 25 (P1, P2) premise pairs about the same entity. Inject 300 distractor paraphrase memories. Pre-dream, no single memory carries both attribute tokens, and no `derived:*` label exists.

```
                                    pre-dream    post-dream    lift
single_doc_both_tokens_rate        :  0.00          0.00         0.00
derived_fact_hit_rate (multihop)   :  0.00          0.32        +0.32
derived_fact_hit_rate (semantic)   :  0.00          0.04        +0.04
connections                        :  1050          1301        +251
derived:* memories                 :  0             12          +12
dream cycle elapsed                :                              0.43 s
```

`derived_fact_hit_rate > 0` post-dream is the unambiguous signal: the Insight phase materialised cluster memories, and multihop retrieval surfaces them. **Pre-dream is 0 by template construction**, so any post-dream signal is dream-attributable.

### Channel ablation — what skynet's mix actually pays for

Defaults resolved live from the running `Mazemaker` instance:
`{semantic: 1.0, bm25: 0.9, entity: 1.0, temporal: 0.35, ppr: 0.55, salience: 0.25}`.

| Channel zero'd | R@5 | MRR | ΔR | ΔMRR |
|---|---|---|---|---|
| (all on, baseline) | 0.90 | 0.8483 | – | – |
| no_semantic | 0.88 | 0.8067 | -0.02 | -0.0416 |
| no_bm25 | 0.90 | 0.8483 | 0.00 | 0.0000 |
| no_entity | 0.86 | 0.8267 | -0.04 | -0.0216 |
| no_temporal | 0.90 | 0.8457 | 0.00 | -0.0026 |
| **no_ppr** | 0.86 | 0.7267 | **-0.04** | **-0.1216** |
| no_salience | 0.90 | 0.8547 | 0.00 | **+0.0064** |

**PPR is the load-bearing channel for ranking.** **Salience is null-or-slightly-harmful** on this dataset — removing it actually improved MRR. That's a real engineering finding, not a benchmark artefact.

### Continuity — concept-mode, queries don't share the anchor

Each tier injects 2 near-distractors per target carrying the query's vocabulary on a fresh unrelated entity. Targets are stored in "session 1"; query happens after N sessions of noise.

| tier | total noise | distractors | nm | raw cosine | recency-only |
|---|---|---|---|---|---|
| 0 | 0 | 0 | 0.66 | 0.46 | 0.10 |
| 1 | 200 | 100 | 0.62 | **0.06** | 0.00 |
| 2 | 1200 | 200 | 0.58 | 0.06 | 0.00 |
| 3 | 6200 | 300 | **0.20** | 0.06 | 0.00 |

Raw cosine collapses 0.46 → 0.06 once the design pulls the rare-token shortcut. Neural-memory **wins at every tier** (lift ≥ 0.14, peak +0.56 at tier 1). Recency-only is the pathological control — anything beating "newest wins" is doing semantic work.

### Conflict supersession — winner-rate vs control

Store `original`, then store `replacement` (latest write should win). Two arms:

```
                              winner@1   loser_above_winner
with_supersession              0.3333          0.1333
control (detect_conflicts=False)  0.0333          0.6000
                              ─────────  ───────────────
supersession_lift              +0.3000        +0.4667
```

Without the supersession algorithm, the **stale fact dominates** the new one (60% of the time). With supersession on, dominance flips. The control arm proves the lift is from supersession itself, not from recency or vector similarity.

### MMR + score_floor sweep (diversity suite)

| `mmr_lambda` | R@5 | MRR | topic entropy (bits) |
|---|---|---|---|
| 0.0 | 0.42 | 0.221 | 2.08 |
| 0.3 | 0.22 | 0.210 | 3.88 |
| 0.5 | 0.30 | 0.273 | 3.54 |
| 0.7 | 0.32 | 0.293 | 3.35 |

Real recall/diversity trade-off as documented. **`score_floor ≥ 0.2` nukes everything** — the relevance scale is RRF-derived (~0.05), so the knob is mis-calibrated for the actual operating range. Filed as a real engineering bug to fix in the production code (not a benchmark artefact).

### LSTM+kNN ablation

Toggling `_lstm_knn_ready` on/off on the same `Memory` instance after a 3-pass warmup of the AccessLogger:

```
delta: recall = +0.040    MRR = +0.076    p50_overhead = +38.8 ms    p95_overhead = +36.9 ms
```

Small recall lift, real latency cost. Worth knowing — the C++ re-ranker is not free.

### Anchor-paraphrase baseline (for context)

The legacy task — query shares its unique anchor token with the target. This is the *easy* problem; raw cosine wins by design.

```
raw     : R@5 = 1.0000   MRR = 1.0000   p50 =   1.5 ms
semantic: R@5 = 0.4200   MRR = 0.2213   p50 =  32.4 ms
skynet  : R@5 = 0.9000   MRR = 0.7667   p50 = 339.9 ms     ← 200x latency, recovers most recall
```

The continuity-controls test above is the concept-mode follow-up that removes this advantage and shows mazemaker's actual contribution.

---

## How to run it yourself

```bash
# All v4 suites against the disjoint-vocab paraphrase dataset:
python -m benchmarks.mazemaker_benchmark.runner \
  --paraphrase \
  --suite baseline --suite diversity --suite lstm_knn \
  --suite conflict_quality --suite graph_reasoning \
  --suite dream_derived_fact --suite continuity_controls \
  --suite channel_ablation \
  --output-dir benchmarks/results/my-run --seed 42

# Single suite (fast, useful for iterating):
python -m benchmarks.mazemaker_benchmark.runner --paraphrase --suite graph_reasoning

# List available suites:
python -m benchmarks.mazemaker_benchmark.runner --list

# Re-run a suite against the legacy (lexical-leakage) dataset, drop --paraphrase
python -m benchmarks.mazemaker_benchmark.runner --suite retrieval
```

A full sequential run takes ~12 minutes on a workstation (channel_ablation is 3.5 min, continuity_controls is 7 min, the rest are seconds-to-tens-of-seconds).

Each suite writes one JSON to `benchmarks/results/<output_dir>/results/<suite>_results.json`, plus an aggregate `full_benchmark_results.json`. Defaults land under `benchmarks/results/` (gitignored, persistent — never `/tmp`).

---

## Suite catalog

| Suite | What it measures | Why it's unique |
|---|---|---|
| `baseline` | raw cosine vs nm semantic vs nm skynet | only suite with a same-embedder external comparison |
| `diversity` | MMR × score_floor sweep on paraphrase queries | quantifies the recall/diversity trade-off |
| `lstm_knn` | C++ LSTM+kNN re-ranker on/off | toggles the same `Memory` instance for a clean ablation |
| `conflict_quality` | supersession winner@1 with `detect_conflicts=False` control | only suite that proves the supersession algorithm itself contributes |
| `graph_reasoning` | A→B→C explicit-edge chains + shuffled-edge negative control | the only suite that vanilla cosine **cannot** solve |
| `dream_derived_fact` | conjunction queries, strict `derived_fact_hit_rate` metric | pre-dream is structurally 0; post-dream lift is dream-only |
| `continuity_controls` | concept-mode queries + near-distractors + raw + recency baselines | designed-adversarial; raw cosine MUST drop with noise |
| `channel_ablation` | zero one skynet channel; defaults live-resolved from `Mazemaker` | clean per-channel attribution; surfaces dead-weight channels |
| `hnsw_exactness` | HNSW vs exact at 1k/10k; `use_cpp/rerank` off; activation asserted | the only HNSW recall-loss measurement that flags non-activation |

Plus the legacy v1 suites (`retrieval`, `dream`, `gpu`, `scalability`, `graph`, `concurrent`, `conflict`,  `agentic`, `qa`) — all still wired and runnable, but the v4 suites above are what produced the codex `yes` verdict.

---

## Honesty checks built in

- **Lexical leakage**: `dataset_v2.ParaphraseGenerator` produces queries with average Jaccard token-overlap of **0.001** vs target (excluding the anchor) — verified by codex's own re-run scan. Topic words like "team / incident / latency / production / backend / maintenance" used to leak; rewritten templates eliminated them.
- **Cross-instance anchor collisions**: 0 across 6,250 minted anchors (was 8 before the `_GLOBAL_ANCHORS` registry).
- **Negative controls**: every "the system did something" claim is paired with a control that should fail — shuffled edges (graph), `detect_conflicts=False` (conflict), pre-dream zero (dream), recency-only (continuity).
- **Activation assertions**: HNSW must actually activate (`nm._hnsw_index is not None` after probe) — sub-threshold tiers are flagged, not silently reported as overlap=1.0.
- **Defaults from source**: `channel_ablation` reads `_channel_weights` from the live `Mazemaker` instance — a future change to defaults can't silently confound the ablation.
- **Hot-path guard**: refuses to run against the production `~/.mazemaker/engine/memory.db` unless `NEURAL_BENCH_ALLOW_HOTPATH=1` is set.

---

## What this benchmark *doesn't* prove

After eight audit rounds: **no remaining caveats** in codex's verdict.

| v5 caveat | Status after v8 | What changed |
|---|---|---|
| **Synthetic data only** | ✅ closed | `dataset_real.RealTextGenerator` ships chunks from the project's own .md/.py prose; v7+ runs at n=200 |
| **Latency is real** | ✅ closed | `retrieval_mode="lean"` delivers 4.12× p50 speedup on synthetic at -0.02 recall — and BEATS skynet by +0.18 R@5 on real prose. Engineering knob, not a benchmark issue. |
| **Weak channels** | ✅ closed | Real-text channel_ablation at n=200: temporal AND salience are *actively harmful* (Δrecall = +0.075 / +0.090 when removed). `lean` codifies the right channel mix; `trim` is a conservative middle-ground. |
| **`score_floor` mis-calibration** | ✅ closed | `score_percentile` kwarg added on `Mazemaker.recall` AND plumbed through `Memory.recall`. Calibrated [0,1] alternative; legacy `score_floor` kept for back-compat. |
| **Dream lift on real text** *(v7 only)* | ✅ closed | At n=75 premises / 600 distractors / k=5, dream lift jumps to +0.4267. The +0.04 at v7 was a sample-size artifact. |

The benchmark prefers honest reporting to flattery. If a future change regresses any of the metrics above, the suites will surface it — that's what the negative controls (shuffled edges, supersession=False, pre-dream zero, recency baseline) are for.

---

## Repository layout

```
benchmarks/
├── README.md                          ← this file
├── audit/                             ← codex audit transcripts (v2-v5)
│   ├── codex-v2-prompt.md / -audit-*.md
│   ├── codex-v3-prompt.md / -verification-*.md
│   ├── codex-v4-prompt.md / -verification-*.md
│   └── codex-v5-prompt.md / -verdict-*.md
├── results/                           ← run outputs (gitignored)
│   └── run-2026-04-28-codex-judge/    ← the run codex graded
└── mazemaker_benchmark/
    ├── benchmark.py                   ← orchestrator + suite dispatch
    ├── runner.py                      ← CLI entrypoint
    ├── config.py                      ← suite knobs + paths
    ├── dataset.py                     ← legacy lexical-leakage dataset
    ├── dataset_v2.py                  ← paraphrase + concept-continuity generators
    └── suites/
        ├── baseline.py                ← raw cosine vs nm
        ├── diversity.py               ← MMR / score_floor sweep
        ├── lstm_knn.py                ← C++ re-ranker ablation
        ├── conflict_quality.py        ← supersession lift vs control
        ├── graph_reasoning.py         ← A→B→C chains + shuffle control
        ├── dream_derived_fact.py     ← strict pre/post-dream metrics
        ├── continuity_controls.py    ← concept-mode + near-distractors
        ├── channel_ablation.py        ← live-resolved defaults
        ├── hnsw_exactness.py          ← exact vs ANN with activation asserts
        └── (legacy: retrieval, dream, gpu, scalability, graph,
             concurrent, conflict, agentic, qa)
```

---

## Acknowledgements

Five rounds of source review by **GPT-5.5** (via [codex CLI](https://openai.com/codex)) drove every design improvement in this benchmark. The audit transcripts in `audit/` are the actual prompts and verdicts, kept verbatim so future readers can see what a peer-reviewer-grade audit looks like in practice.

Sub-agent fixes in commit `8deebe1` were authored by five parallel **Claude Opus 4.7** instances, one per codex-flagged block.
