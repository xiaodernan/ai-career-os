# Algorithms horizon — Epics 132+

The product's loop is complete and the performance horizon (118–131) closed every
cost claim it made with a measurement. This horizon answers a different question
the operator actually pays for: **where does the algorithm come from, and is it
the cheapest one that gives the same answer?**

Epic 132 shipped a dependency-free algorithms package (`ai-service/app/algorithms`)
— an O(1) LRU/TTL, a stable O(n log k) heap top-K, dense/sparse cosine, Okapi BM25,
and the skill-gap/job-rank scorers — with 48 measured tests. A package nobody calls
is dead weight, so this horizon's rule is the repo's existing Definition of Done:
**an algorithm lands only when it replaces a live call site, and the replacement
is pinned by a test that fails if the old complexity sneaks back.**

| Epic | Claim | Verification |
|---|---|---|
| 132 | The primitives exist and are measured | `test_the_algorithms_module.py` (50) |
| 133 | The top-K helper uses the *right* heap for the scale | measurement + stability/streaming contract; fusion keeps its sort on purpose |
| 134 | A rerank that costs no model call is available and honest | `RERANK_MODE=bm25`, mode census, 10 offline rerank tests |
| 135 | (next) The lexical channel can be scored in-process without pg_trgm when the corpus is small | to be measured |

## Rules
- No placeholder endpoints. Every mode/config knob is read by real code and pinned by
  the env/RAG-doc censuses in the same change.
- Complexity claims are measured with `time.perf_counter`, not asserted in prose.
- An algorithm that changes ranking is a behaviour change: the old ordering is pinned
  first, then the replacement must reproduce it. A mode that skips the model must say
  so in `describe()`/logs and never fabricate a score.
- Offline harness: `LLM_PROVIDER=mock EMBEDDING_PROVIDER=hash`. Docker-dependent suites
  stay recorded as not-run on this host.

## Epic 133 — the top-K helper uses the right heap for the scale **DONE (measured 2026-11-11)**

**This epic changed shape when it was measured, and the change is the point.** The
first sketch was to replace the full sort in `_fuse_rrf` (`app/agents/tools.py`)
with the bounded-heap `top_k`. Two measurements killed that idea before it shipped:

1. **The candidates are already SQL-LIMITed.** Both the keyword and semantic legs
   carry `LIMIT $n` with n clamped to ~10, so the fused set is a small constant.
   At that size a heap's asymptotic advantage is invisible and its per-item Python
   overhead is pure cost — the right tool is Timsort. Replacing it would have been
   optimising a number the database had already made small.
2. **A hand-written Python heap is slower than the C sort at every size tested.**
   Measured on this host (median of 9, `key` on descending RRF-like scores):

   | n (k=10) | `sorted` | Python tuple-heap `top_k` | `heapq.nlargest` |
   |---|---|---|---|
   | 1,000 | 0.058 ms | 0.123 ms | 0.064 ms |
   | 50,000 | 4.775 ms | 9.556 ms | **3.497 ms** |
   | 200,000 | 35.072 ms | 41.208 ms | **27.109 ms** |

**Do (what actually shipped).** `top_k` now delegates to the C-level
`heapq.nlargest` / `nsmallest`, which is stable, byte-for-byte equal to
`sorted(..., reverse=True)[:k]`, keeps only k items (O(k) space), and is the only
variant that actually wins at large n (~1.3x at 200k). `_fuse_rrf` deliberately keeps
its sort and now carries a comment recording *why*, so a future reader does not
re-attempt the same non-optimisation. The algorithms tests pin: stability across
scales and heavy ties, equivalence with a full sort, and selection over a 50k
generator (no `__len__`), which a materialise-and-sort helper would handle differently.

**Honest bound recorded in the test:** selection is still O(n) — it must see every
input; only *space* drops to O(k). An unbounded source has no "top k" and the helper
does not pretend to answer one. The C-heap win is for places n is genuinely large,
which Epic 134 begins to exercise (scoring a candidate corpus in-process).

**Done when** `test_the_algorithms_module.py` 50/50 and `test_job_search_hybrid.py`
unchanged/green; `_fuse_rrf` still returns byte-for-byte the same order.

## Epic 134 — a rerank that costs no model call

**Measured.** `rag/rerank.py` offers two modes: `llm` (an LLM relevance pass, one model
call, tens of tokens per candidate) and `none` (skip entirely — fused RRF order). There
is no middle: on a host with no provider configured, or on a query where spending a
model call is not worth it, the reader gets either a bill or no lexical re-scoring at
all. Meanwhile `app.algorithms.Bm25` is a pure-Python ranker that scores the same
fused candidates against the query in microseconds and needs no network.

**Do.** Add `RERANK_MODE=bm25`: build a BM25 index over the fused candidate texts,
re-order down to `top_n` by `score(query, i)`, and inject a `rerank` field that is
*the normalized BM25 score* — the same field the LLM path writes, so `to_evidence`
and the citation path need no change. `none` still skips. Keep `llm` the default so
no deployment changes behaviour until an operator opts in.

**Done when** (a) the mode census (`test_the_rag_doc_names_what_the_code_ships.py`)
and env-declaration census pass with `bm25` named in config comment, `.env.example`
and `docs/RAG.md`; (b) offline tests prove `bm25` orders by lexical relevance, keeps
stable ties, injects finite normalized scores, and never calls `ask_json`; (c) the
existing six rerank degradation tests still pass; (d) a measured note records the
BM25 pass's wall time on a 40-candidate corpus.

**DONE (verified 2026-11-11, offline).** All four conditions met:
- **Shipped.** `RERANK_MODE=bm25` is the third mode alongside `llm` (still default)
  and `none`. `app/rag/rerank.py` scores the fused `rows[:25]` with the BM25 from
  Epic 132, min-max normalising to (0, 1] so `pipeline.to_evidence`'s
  `max(rerank, rrf)` keeps a single scale — an out-of-scale BM25 score would
  fabricate confidence, so this is pinned by an explicit `to_evidence` test.
  Both computed modes inject the same `rerank` field and trace a `mode` key; the
  citation/observability paths do not branch on the ranker. `eval/run_eval.py`'s
  `--rerank` choices, `.env.example`, `config.py`'s mode comment, and `docs/RAG.md`
  carry the new mode; the RAG-doc census was generalised from a hardcoded
  two-mode parse to `findall(RERANK_MODE=(\w+))` so a fourth mode is one doc edit.
- **Chinese actually works.** A tokeniser that only matched `[a-z0-9]+` would
  score every Chinese resume chunk zero and make the feature useless on a Chinese
  job platform. `_rerank_tokens` emits overlapping CJK character bigrams (plus
  Latin words) — the standard no-segmenter IR trick — so "机器学习" shares signal
  with "机器学习框架". Writing it surfaced a real bug in the first draft: a missing
  `\\u` on the Hangul range (`\\ufaffac00`) widened the character class to cover
  ASCII, so English was bigrammed too; the bigram test caught it and the escape is
  fixed. Bigrams cost time linear in text length.
- **Measured (this host, 2026-11-11).** BM25 fit+score over 40 candidate chunks of
  ~600 mixed Chinese/English characters: **median 9.60 ms, p95 22.5 ms** (300 runs,
  varied vocabulary). That is one in-process CPU pass — zero model call, zero
  network round trip, zero token billing, and available when no provider is
  configured. The `llm` path remains for relevance quality; `bm25` is the honest
  middle between a model call and no lexical re-scoring at all. An earlier
  measurement with an artificially repetitive corpus read 31.6 ms; the varied
  corpus above is the representative one (repetition inflated the term counts).
- **Verified.** `test_the_rerank_that_costs_no_model_call.py` 10/10 (ordering,
  normalisation, evidence-scale safety, zero-match + tie stability, Chinese
  bigrams, never-LLM, unknown-mode fallthrough); `test_core_modules.py` rerank
  degradation suite still green; RAG-doc + env-declaration censuses green
  (100/100 combined with core_modules). Full ai-service suite is the operator's
  offline-gate run; this host has no Docker for the live RAG eval.
