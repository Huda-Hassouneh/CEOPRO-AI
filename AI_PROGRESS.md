# CEOPRO AI — AI/ML Engineering Progress Log

**Owner:** AI/ML Engineering
**Tracks:** implementation progress against `MASTER_SPEC_v4.md`'s AI phases (§18–§27, Phase 2 onward).
**Update convention:** append-only, date-stamped entries at the bottom. Don't edit or delete past
entries — if something is superseded, add a new entry that says so and link back. Mirrors the
convention in `AI_PLAN_AND_CONTRACT_UPDATES.md` and `src/infrastructure/CONTRACT_CHANGELOG.md`.

This file lives at the repo root so it stays alongside `MASTER_SPEC_v4.md` and
`AI_PLAN_AND_CONTRACT_UPDATES.md`. Module-level implementation detail lives in
[`src/ai/README.md`](src/ai/README.md); this file tracks status and history, not how the code works.
Anything that needs action from a different team or a human outside this track (schema asks,
ownership decisions, broken CI references, security flags) is **not** duplicated here — it's tracked
in [`PENDING_ACTIONS.md`](PENDING_ACTIONS.md) so it stays visible without digging through this log.

---

## Module status

| Spec phase | Module | Status | Notes |
|---|---|---|---|
| Phase 2 — Demand Intelligence (§18, §23, §25) | `src/ai/forecasting/` | 🟢 Built, tested (unit + integration) | Baselines, XGBoost + walk-forward validation, cold-start policy, evidence writers, Redis consumer. See entries below. |
| Phase 3 — RAG Chatbot (§21) | `src/ai/rag/` | 🟡 Hybrid (lexical + semantic) retrieval built/tested; chatbot itself not started | Document ingestion + BM25 + FAISS semantic retrieval + Reciprocal Rank Fusion, all against existing `rag_documents_metadata` + MinIO — none of it needs pgvector. Still missing: LLM reasoning step, chat history (needs a new table). A real fusion edge case found and documented (not fixed — inherent BM25 behavior on very short chunks). See entries below. |
| Phase 4 — Market Intelligence (§15, §16, §17) | `src/ai/extraction/`, `src/ai/sentiment/` | 🟡 Rule-based NER + persistence + sentiment analysis built/tested; MPI (§17) not started | Regex extraction (MONEY/CURRENCY/PERCENT/DISCOUNT/EMAIL/PHONE/INVOICE_ID/ORDER_ID/DATE) + catalog matching (PRODUCT/COMPETITOR) built, and now persisted to `extracted_entity` via `extraction/pipeline.py` (`extraction_status`-gated Pending/Processed/Failed, mirroring `rag/pipeline.py`'s convention). ORG/PERSON/GPE entity types not started — need world knowledge or a trained model. Sentiment analysis (`sentiment/`) built: XLM-RoBERTa-based classifier (`cardiffnlp/twitter-xlm-roberta-base-sentiment`), per-subject aggregation, LOW SAMPLE SIZE policy — `reviews`/`news_record`/`social_mention` tables are currently empty in prod, so the `UNKNOWN`-evidence / zero-pending-rows path is what runs today for both. Market Perception Index (§17, combines sentiment + source reliability + recency + volume + entity relevance) not started. See entries below. |
| Phase 5 — Price Intelligence (§9, §19) | `src/ai/pricing/` | 🟢 Built, tested (unit + integration) | Product matching, rule-based recommendation, price-change guardrail plus a margin guardrail (`products.cost`, `PENDING_ACTIONS.md` #14, resolved 2026-08-08), evidence + recommendation_outcomes writers, plus traceable currency conversion (`currency.py`) surfacing cross-currency competitor prices as reference-only context ([PR #5](https://github.com/Huda-Hassouneh/CEOPRO-AI/pull/5), merged 2026-08-07). See entries below. Real competitor price data still doesn't exist (`PENDING_ACTIONS.md` #5), so the cold-start/UNKNOWN path is what actually runs today, same as Phase 2. |
| Phase 6 — Competitor Ranking (§20) | — | ⚪ Not started | Same data gap as Phase 5 (`PENDING_ACTIONS.md` #5). |

Legend: 🟢 built and tested · 🟡 in progress · 🟠 blocked on another team · ⚪ not started.

---

## 2026-08-07 — Phase 2 Demand Forecasting: built, bug-fixed, and verified against a real database

**Built** `src/ai/forecasting/` (spec §18 Demand Forecasting, §23 Cold-Start Policy, §25 Model
Evaluation) — self-contained, no changes to `docker-compose.yml`, `Dockerfile.*`, schema, or
frontend. Reads `transactions`/`products`/`inventory`, writes `demand_forecasts`/
`evidence_records`/`model_versions` — all pre-existing tables, no migration needed.

- Baseline forecasters (naive, seasonal-naive, moving-average, previous-period) — spec requires the
  model to beat these before its forecast is trusted.
- XGBoost forecaster with expanding-window walk-forward validation (MAE/RMSE/MASE).
- Cold-start policy (§23): below a configurable history threshold (default 30 days), the pipeline
  stays on the best-backtested baseline and reports `confidence_status: BUILDING` instead of
  training/serving a model on insufficient data.
- Evidence writers: every forecast produces a `demand_forecasts` row plus an `evidence_records` row
  (category `PREDICTION`, per spec §22's shared evidence schema) explaining which source was used
  and why.
- Redis consumer (`consumer.py`) for the `demand_forecast_requested` event contract (topic
  `ceopro:stream:forecast_requested`, already provisioned by `src/infrastructure/init_broker.py`).
  This is a separate consumer from `src/infrastructure/messaging/ai_consumer.py` (market-intelligence
  stream) — that file's ownership is a separate open question tracked in
  `AI_PLAN_AND_CONTRACT_UPDATES.md`, not touched here.

**Testing surfaced two real bugs**, both fixed:
1. `features.py` set a missing `current_stock` to `pd.NA`; pandas/XGBoost can't cast that to
   `float` (`TypeError: float() argument must be ... not 'NAType'`). Fixed to `np.nan`.
2. `pipeline.py` double-nested a dict lookup building the XGBoost explanation string
   (`metrics["baseline_scores"]["scores"]` when `metrics["baseline_scores"]` was already the scores
   dict) — a `KeyError` that only fired on the path where the model actually won.

Neither bug was visible from a `py_compile` syntax check or code review alone — both only surfaced
once the code actually ran (`test_model.py`'s walk-forward correctness test, and `test_pipeline.py`'s
mocked-DB run of the XGBoost-wins branch).

**Verified against a real PostgreSQL instance**, not just mocks: spun up an isolated, disposable
`postgres:15-alpine` container (port 5433, separate from the existing long-running `ceopro_postgres`
dev container — that one was left untouched), loaded the actual `init_schema.sql`, and ran
`test_integration_db.py` against it. This exercises the raw SQL in `data_access.py`/`evidence.py`
that unit tests with a mocked connection cannot validate: column types, JSONB round-tripping,
foreign key constraints, and `demand_forecasts.expected_demand` being an `INT` column (confirmed
`12.7` rounds to `13`, not silently truncated or rejected). All 5 integration tests passed; the test
file is skipped automatically (`AI_TEST_DATABASE_URL` unset) everywhere else, so it doesn't affect
CI or require Docker on every machine.

**Full local verification, Python 3.11.9 (matching `Dockerfile.backend`'s target)**:
- `pytest src/ai/tests`: 31 passed (26 unit/offline + 5 live-DB integration), 0 failed.
- `flake8 --select=E9,F63,F7,F82` (the CI's blocking check): 0 errors.
- `flake8 --max-complexity=10 --max-line-length=127` (CI's non-blocking check): 0 issues after
  cleanup (11 line-length violations fixed).

**Commits:** `4d812fc` (initial module), `f5f9e7a` (bug fixes + model/pipeline test coverage). This
entry's integration test work lands in the next commit.

**Still open / blocked (not fixed here, flagged for the owning team — see
`AI_PLAN_AND_CONTRACT_UPDATES.md` for the full list):**
- pgvector / `knowledge_chunks` / Row-Level Security / `currency_rates` — infra-owned, blocking
  Phases 3 and cross-currency logic.
- `model_versions.artifact_path` column doesn't exist yet, so trained model binaries aren't
  persisted to MinIO (`ceopro-ai-artifacts`) — metrics/version metadata are still recorded on every
  training run, just not the binary itself.
- `src/infrastructure/messaging/ai_consumer.py` ownership collision — unresolved, needs a decision
  from whoever owns both sides.
- No real transaction volume anywhere yet (`mocks/sales_transactions_mock.csv` has 3 rows) — the
  cold-start path is what actually runs until real data lands; the XGBoost path is validated against
  synthetic data (`test_model.py`) and a seeded integration DB (`test_integration_db.py`), not yet
  against production data because none exists.

## 2026-08-07 — Redis consumer verified against a real Redis instance

Extended the same "verify against real infra, not mocks" approach from the earlier entry today to
`consumer.py`: `ForecastRequestConsumer.__init__` calls `xgroup_create` eagerly against a real Redis
connection (a `ConnectionError` there isn't caught), so it can't be constructed against a mocked
client the way `pipeline.run_forecast`'s DB calls could be mocked in `test_pipeline.py`.

Spun up an isolated, disposable `redis:7-alpine` container (port 6380 — separate from the existing
long-running `ceopro_redis` dev container, which was left untouched, same as the Postgres container
in the earlier entry). Added `src/ai/tests/test_consumer.py`, 6 tests:
- Consumer group is actually created on the stream at construction time.
- Payload validation (`_handle_message`) rejects messages missing `tenant_id`/`product_id`.
- `horizon_days` is correctly parsed from the payload string and defaults to 7 when absent.
- A full publish → `xreadgroup` → handle → `xack` cycle — the same sequence `listen()`'s loop uses —
  leaves zero pending messages afterward, confirmed via `XPENDING`.

All 6 passed on the first run — no bugs found this time (the consumer's logic is small and the
earlier `pipeline.py`/`features.py` fixes had already been exercised by `test_pipeline.py`).

Skipped automatically unless `AI_TEST_REDIS_HOST` is set, so this doesn't affect CI or require
Docker on every machine, matching the `test_integration_db.py` convention.

**Full suite after this addition:** 37 tests total (26 fully offline, 5 live-Postgres, 6 live-Redis).
Confirmed via two runs: all 11 integration/consumer tests skip cleanly with no env vars set
(26 passed, 11 skipped), and all 37 pass when both `AI_TEST_DATABASE_URL` and `AI_TEST_REDIS_HOST`
are set against disposable containers. `flake8` (both the CI's blocking and non-blocking checks):
0 issues.

**Still not covered by any test:** the `listen()` method's own `while True` loop, `KeyboardInterrupt`
handling, and its `finally`-block cleanup — only the per-message handling logic it calls is tested.
Low risk (it's a thin wrapper around already-tested pieces) but worth naming explicitly rather than
leaving it implied.

## 2026-08-07 — `listen()` loop coverage gap (flagged in the previous entry) closed

The previous entry named an explicit gap: `listen()`'s own `while True` loop, `KeyboardInterrupt`
handling, and `finally`-block cleanup weren't tested, only the per-message logic it calls. Closed
that with 4 more tests in `test_consumer.py`, using the already-live disposable Redis container plus
`psycopg2.connect` mocked out (no live Postgres needed for these):

- `xreadgroup` raising `KeyboardInterrupt` (simulating Ctrl+C during the blocking read) is caught
  internally — `listen()` doesn't raise — and both the DB connection and the Redis client get
  `.close()`d in the `finally` block.
- An empty `xreadgroup` response (`[]`, i.e. the poll timed out with nothing new) doesn't stop the
  loop — it just polls again.
- A malformed message (missing `tenant_id`) inside the loop triggers a rollback and the loop
  continues to the next poll, without the bad message ever being acked.
- A successfully processed message is acked exactly once, with the right stream/group/message-id
  arguments, and does not trigger a rollback.

All 4 passed. Full suite is now 41 tests (26 offline, 5 live-Postgres, 10 live-Redis). Verified: with
only Redis available (no `AI_TEST_DATABASE_URL`), 36 pass and 5 skip; with neither live-infra env var
set, all 26 offline tests pass and the remaining 15 skip cleanly. `flake8` clean on both checks.

No further known test gaps in `src/ai/forecasting/` as of this entry.

## 2026-08-07 — Phase 5 Price Intelligence built and tested: `src/ai/pricing/`

Built `src/ai/pricing/` (spec §19 Price Intelligence, relevant parts of §20's normalization
principle, §23 cold-start, §24 recommendation outcomes) against the existing `products`,
`competitors`, `competitor_prices`, `evidence_records`, and `recommendation_outcomes` tables — again
no schema changes, no infra/UI files touched.

- `matching.py` — name-similarity product matching (`difflib.SequenceMatcher`, no new dependency).
  `competitor_prices.product_name_captured` is free text with no `product_id` FK, so matching to our
  own catalog can't be a join; spec §37's cold-start guidance for product matching ("use rules and
  fuzzy matching with more manual confirmation") calls for exactly this, with a conservative default
  threshold (0.82) that trades recall for not silently comparing different products.
- `data_access.py` — reads own product price/currency, and competitor prices filtered to
  same-currency, `ALLOWED` source status, exact data, and a freshness window (default 30 days).
  Cross-currency comparison is explicitly out of scope here — it needs `currency_rates`
  (`PENDING_ACTIONS.md` #3), which doesn't exist. This only ever does spec §19's "LOCAL MARKET
  COMPARISON", never "CROSS-COUNTRY COMPARISON".
- `recommendation.py` — transparent, rule-based market-average comparison (raise/lower/hold),
  deliberately not a learned model: spec §19 says "Learned pricing must remain disabled until enough
  historical price-change data exists," and `recommendation_outcomes` is currently empty, so there
  is no such history yet.
- `guardrails.py` — bounds how far a suggested price can move from the current price (default 15%).
  **This is not the margin guardrail spec §19 also asks for** — that needs a cost/COGS basis, and
  `products` has no cost column. Flagged as a new item, `PENDING_ACTIONS.md` #14.
- `evidence.py` — reuses `insert_evidence_record` from `forecasting.evidence` directly rather than
  duplicating it (spec §22: "one consistent evidence architecture," and the function was already
  generic, not forecast-specific). Adds `insert_recommendation_outcome`, writing a
  `recommendation_outcomes` row at recommendation time per spec §24 ("every recommendation must
  create a RECOMMENDATION_OUTCOME record"), `action_taken` left at the table's `ignored` default
  until a human actually acts on it.
- `pipeline.py` — orchestrates: load own product → load same-currency competitor prices → match by
  name → no matches: `UNKNOWN` evidence (cold-start path, same pattern as forecasting) → matches:
  rule-based recommendation → guardrail → persist evidence + outcome row.

**Testing:** 23 offline tests (matching, guardrails, recommendation math, pipeline with DB mocked
out) plus 4 live-Postgres integration tests (real schema, seeded competitor prices, checks the
`RECOMMENDATION`/`UNKNOWN` evidence category and the `recommendation_outcomes` row land correctly,
including the `ignored` default). All 27 passed — no bugs found this time, unlike the forecasting
module's first pass; the pattern established there (mocked unit tests + a real seeded database) may
simply be catching more before code is even run for the first time.

**Full combined suite verified**: 68 tests total (forecasting 41 + pricing 27). Ran three ways: no
live-infra env vars (49 pass, 19 skip), Postgres only (58 pass, 10 skip — Redis-only tests skip), and
both Postgres + Redis up (all 68 pass). `flake8` clean on both checks after fixing 9 line-length
violations introduced by this addition.

**Commit:** lands in the next commit after this entry.

**Known limitations (flagged in `PENDING_ACTIONS.md`, not fixed here):**
- Margin guardrails are weaker than spec'd — no `cost` column on `products` (#14).
- Nothing to actually run this against yet — `competitor_prices` is empty; the cold-start/`UNKNOWN`
  path is what executes today, same situation forecasting is in with real transaction volume (#5).
- Cross-currency comparison isn't implemented — blocked on `currency_rates` (#3), same as before.

## 2026-08-07 — Pinball Loss added; Phase 3 RAG retrieval groundwork built (CPU-only, no pgvector)

Asked to prioritize and build everything possible without needing heavy compute (no GPU, nothing
"super computer"-scale). Two pieces landed:

**Pinball Loss** (`forecasting/evaluation.py`, spec §25's "Pinball Loss where applicable"): standard
quantile-loss metric, added alongside MAE/RMSE/MASE. Not currently wired into `pipeline.py` — the
forecaster produces point forecasts, not quantile forecasts, so there's nothing to score with it yet.
It's there for when/if quantile regression is added. 5 new tests, all offline.

**`src/ai/rag/`** (spec §4/§6/§21): document ingestion + BM25 lexical retrieval, deliberately **not**
the full RAG chatbot. This is retrieval-only groundwork:

- `chunking.py` — word-boundary overlapping chunking, works for Arabic and English without a
  language-specific tokenizer.
- `bm25_index.py` — BM25 index, `rank_bm25` (pure Python, no trained model, the lightest possible
  tier).
- `data_access.py` — reads/updates `rag_documents_metadata` (existing table), fetches raw bytes from
  the `ceopro-rag-knowledge` MinIO bucket (existing, AI-owned per `MINIO_STORAGE_ARCHITECTURE.md`).
  Plain-text only for now — PDF/DOCX extraction not implemented (new item, `PENDING_ACTIONS.md`).
- `pipeline.py` — ingest (fetch → chunk-check → mark Processed/Failed, spec §12's "never silently
  discard invalid data") and retrieval (rebuild a BM25 index from every Processed document's current
  MinIO content). No `knowledge_chunks` table exists, so chunk text isn't persisted anywhere - the
  index is recomputed from MinIO on every call. Documented plainly as a scaling limitation, and as a
  concrete argument *for* the pgvector ask rather than a reason it's unnecessary.

**A key finding: none of this needed pgvector.** `MASTER_SPEC_v4.md` §4 and §6 name **FAISS + BM25**
as the platform's default retrieval stack - standalone libraries, not a Postgres extension. The
pgvector/`knowledge_chunks` ask comes from the still-missing `AI_CONTRACT_CHANGES_AND_CLARIFICATIONS.md`,
not the master spec itself. So lexical (BM25) retrieval was buildable today; semantic (embedding +
FAISS) retrieval is a separate, still-open follow-up - lighter than an LLM, but not done in this pass.

**Testing caught a real bug, again by running against real infra rather than mocks:** with only 2
documents in the corpus, `rank_bm25`'s default `BM25Okapi` computed an IDF of exactly `0.0` for every
term (each term appeared in precisely 1 of 2 documents, and Okapi's classic IDF formula
`log((N-df+0.5)/(df+0.5))` is exactly zero at that ratio) - meaning **obviously relevant results
scored zero and were silently dropped**. This is a real risk for the actual use case: SME tenants
with only a handful of uploaded documents is a realistic cold-start state, not a test artifact.
Switched to `BM25Plus`, which adds a delta term guaranteeing strictly positive IDF regardless of
corpus size. Caught by `test_rag_integration.py` (live Postgres + live MinIO), not by the 14 offline
unit tests, which used corpora too small to trigger it until the integration test's realistic
2-document scenario.

**Full suite: 91 tests** (forecasting 46, pricing 27, rag 18). Verified passing/skipping correctly
with no live infra (68 pass, 23 skip), and with Postgres + MinIO up (all applicable tests pass).
`flake8` clean.

**New/updated items in `PENDING_ACTIONS.md`:** PDF/DOCX extraction not implemented (new); the
pgvector ask (#1) now has a concrete efficiency argument attached, not just the semantic-search one.

## 2026-08-07 — Phase 4 rule-based NER built: `src/ai/extraction/`

Third item off the "no heavy compute" prioritized list. Implements spec §15's own explicitly-named
low-resource option — "NER may use: ... EntityRuler. Regex patterns. Fuzzy matching. Domain-specific
rules." — not a placeholder ahead of a transformer, but the spec's sanctioned starting tier.

- `regex_patterns.py` — MONEY, CURRENCY, PERCENT, DISCOUNT, EMAIL, PHONE, INVOICE_ID, ORDER_ID, DATE.
  Currency list is configuration-driven (spec §9), defaulting to spec's own 14-currency list.
- `catalog_matching.py` — PRODUCT/COMPETITOR entity types, matched against a tenant's own known
  names (candidate spans from capitalized word runs, scored via `pricing.matching.similarity()` —
  reused directly rather than reimplemented, spec §22's "one consistent approach" principle applied
  beyond just evidence records).
- `data_access.py` — reads known product/competitor names from existing tables. Writes nothing —
  there's no `extracted_entity` table (`PENDING_ACTIONS.md` #4), so results have nowhere to persist.
- `extractor.py` — combines both into one call.

Out of scope: ORG, PERSON, GPE, ADDRESS (spec §15's other target types) — these need world knowledge
or a trained model; regex/catalog-matching can't do them justice. Sentiment analysis (spec §16) also
not started this round — both are the "medium compute" tier flagged when this prioritized list was
first laid out, deliberately after the lighter items.

**Testing caught a real bug**, this time in the very first full test run rather than needing live
infra to surface it: `extract_order_id("Your order #A4821X has shipped")` returned nothing. The
regex required the `-`/`#` separator to immediately follow `ORDER` with no space
(`(?:ORD|ORDER)[-#]?\s?(...)`), but real text has the separator *after* a space (`"order #A4821X"`,
not `"order#A4821X"`). Fixed by allowing optional whitespace before the separator too, in both the
`INVOICE_ID` and `ORDER_ID` patterns (the latter's test happened not to exercise this, but the same
bug was latent there).

**Full suite: 119 tests** (forecasting 46, pricing 27, rag 18, extraction 28: 25 offline + 3
live-Postgres). Verified passing/skipping correctly with no live infra (93 pass, 26 skip) and with
Postgres up (all applicable pass). `flake8` clean.

No new `PENDING_ACTIONS.md` items — the `extracted_entity` table gap was already implied by item #4,
now made concrete: the extraction logic itself is no longer the blocker, only the persistence table.

## 2026-08-07 — Semantic (FAISS) retrieval + hybrid fusion added to `src/ai/rag/`

Fourth and final item off the original no-heavy-compute prioritized list (item 5, sentiment, is a
separate, heavier follow-up — see note at the end of this entry). Confirmed feasibility first: a real
multilingual embedding model (`sentence-transformers/paraphrase-multilingual-MiniLM-L12-v2`, 384-dim,
~470MB) downloads and runs on CPU in this environment — ~140s first download, ~20-30s per fresh
process even cached (still checks the HF Hub), fast for repeat calls within one process. Confirmed
cross-lingual understanding directly: English "Sunscreen is our best selling product" vs. Arabic
"واقي الشمس هو المنتج الأكثر مبيعا لدينا" (same meaning) scored 0.64 cosine similarity — clearly
higher than an unrelated sentence in either language.

Built:
- `embeddings.py` — thin wrapper, lazy-loaded and cached per model name.
- `faiss_index.py` — flat inner-product index (embeddings are L2-normalized, so this is cosine
  similarity; exact search, no approximate-index tuning needed at per-tenant corpus sizes).
- `hybrid_retrieval.py` — Reciprocal Rank Fusion, unweighted, combining BM25 + FAISS rankings.
- `pipeline.py` extended with `build_hybrid_index()`/`retrieve_hybrid()` alongside the existing
  BM25-only path (kept, for callers that don't need the embedding model at all).
- Deduplicated `ScoredChunk` (previously defined identically in both `bm25_index.py` and the new
  `faiss_index.py`) into a shared `retrieval_types.py`.

**A real, documented (not "fixed") limitation found via the live-embeddings integration test**: with
very short chunks (single sentences, 10-13 tokens) and a query with exactly one genuine keyword match
to one document, BM25's own document-length normalization can rank a *zero-match* document above the
one-match document — completely standard, correct BM25 behavior (shorter documents get a length-norm
boost), but counterintuitive at sentence-length chunks where BM25's normalization assumptions (tuned
for paragraph/page-length documents) have an outsized effect. When this happened, FAISS ranked the
opposite way, and unweighted Reciprocal Rank Fusion produced a near-tie that didn't reliably surface
the "obviously correct to a human" answer. This isn't a coding bug — verified BM25Plus's `idf`/`delta`
math by hand — it's a property of applying paragraph-tuned BM25 to sentence-length chunks. **Not
fixed** (would mean either a length-normalization tweak or a weighted, tuned fusion — both real design
decisions, not obvious defaults, and out of scope for what was asked). Documented in `rag/README`
(`src/ai/README.md`) and in the integration test itself, with a query chosen to demonstrate hybrid
retrieval's real value (zero-lexical-overlap query, letting FAISS's semantic ranking pass through
cleanly) rather than one that happened to hit the fragile case.

**Full suite: 136 tests** (forecasting 46, pricing 27, rag 35, extraction 28). Verified three ways: no
live infra/opt-in flags (104 pass, 32 skip), Postgres+MinIO+embeddings all up (126 pass, 10 skip —
only the Redis consumer tests, not requested this round), confirming nothing regressed. `flake8`
clean.

**On item 5 (sentiment) from the original prioritized list**: not started this round. It needs a
noticeably heavier pretrained transformer (~250-550M params, vs. the ~470MB/fast-CPU embedding model
here) and — more fundamentally — there's no source text to run it on yet (`reviews`, `news_record`,
`social_mention` tables don't exist, `PENDING_ACTIONS.md` #4). Building the classifier wrapper alone
without any real text to validate it against would be much lower-confidence work than everything
built so far, all of which was verified against real data through real infra.

## 2026-08-07 — Rechecked repo for team changes; two schema blockers closed, two new issues found

`git fetch` showed 2 new commits on `main` since last checked (`537a207` watchdog.py, `01d7d43`
init_schema.sql), from the infra track — not this branch. Audited both directly rather than assuming
from the commit messages. No AI/ML code was written this round; investigation and doc updates only.

**Schema update (`01d7d43`) — good news first:**
- `currency_rates` table landed. **`PENDING_ACTIONS.md` #3 closed.** Cross-currency pricing is now
  schema-buildable (not yet wired into `src/ai/pricing/`, which still only does same-currency
  comparison — that's now unblocked future work, not a pending action anymore).
- `reviews` and `sentiment_results` tables landed. **`PENDING_ACTIONS.md` #4 partially closed** —
  sentiment analysis (spec §16) is now fully unblocked: there's source text to run it on and a table
  to write results to. `extracted_entity`, `news_record`, `social_mention` are still missing, so NER
  persistence and news/social-based intelligence remain blocked.
- `pgvector` extension + a `rag_document_chunks` table (with a `VECTOR(1024)` column) were added,
  aimed at `PENDING_ACTIONS.md` #1. **Tested this directly rather than trusting it works**: loaded
  the new `init_schema.sql` against a real, plain `postgres:15-alpine` container (the same image
  `docker-compose.yml` still references) and got `ERROR: extension "vector" is not available` —
  `docker-compose.yml`'s postgres service was never switched to a pgvector-enabled image (e.g.
  `pgvector/pgvector:pg15`). The schema change alone doesn't make item #1 deployable; logged as new
  item #17. `products`/`competitors` also gained audit columns (`source`, `created_by_user_id`,
  soft-delete on products, `is_active` on competitors) and a new `product_price_history` table —
  none of these change anything in `src/ai/`, no action needed.

**watchdog.py update (`537a207`) — mixed:**
- The hardcoded Postgres password fallback flagged in `PENDING_ACTIONS.md` #10 is fixed —
  `DATABASE_URL` is now required, no embedded credential. **#10 closed.**
- But the same commit broke the file: it literally committed the PowerShell here-string wrapper used
  to write it (`@'` as line 1, `'@ | Out-File -FilePath ... -Encoding utf8` as the last line) instead
  of just the Python content inside it. Confirmed with `ast.parse()`:
  `SyntaxError: invalid non-printable character U+FEFF` at line 1 — the file won't import or run at
  all. This isn't cosmetic: `.github/workflows/staging-deployment.yml` runs
  `python src/infrastructure/monitoring/watchdog.py` directly as a deploy step. Logged as new item
  #16.

**Still open, unchanged**: RLS (#2), `ai_consumer.py` ownership question (#6), `model_versions.artifact_path`
(#7), `Dockerfile.ai`/CI reference (#8), root `requirements.txt` (#9), `products.cost` (#14), PDF/DOCX
extraction (#15, self-flagged), the three missing AI planning docs (#11), `MASTER_SPEC_v4.md`/
`AI_PLAN_AND_CONTRACT_UPDATES.md` still unmerged to `main` (#12, `noorhassouneh-patch-1` unchanged),
Orange infra confirmation (#13, deferred).

**PR #2** (this branch's work) is still open on GitHub, mergeable, no reviews or comments yet.

**No implementation started this round** per instruction — newly-unblocked work (wiring
`currency_rates` into pricing, building the sentiment classifier now that `reviews`/`sentiment_results`
exist) is real future work, not done here, since this was a status check, not a build round.

## 2026-08-07 — Fixed real conflicts from the team's schema update; PR #2 confirmed merged

Since the last entry, PR #2 was merged into `main` (2026-08-07 16:04 UTC, merge commit `d908fd3`) — all
of `src/ai/` is now on `main`. Went looking for bugs/conflicts the team's schema update (previous
entry) might have introduced against our existing queries, rather than assuming the additive-looking
columns were harmless.

**Found real ones**: the schema update added `products.deleted_at` (soft-delete) and
`competitors.is_active`, with partial indexes on both (`WHERE deleted_at IS NULL`,
`WHERE is_active = TRUE`) signaling the intended query pattern. None of our existing `SELECT` queries
against `products`/`competitors` filtered on either column, meaning a soft-deleted product or a
deactivated competitor would silently still show up in forecasting context, price recommendations, and
NER catalog matching — not a crash, a quiet correctness bug that would only surface as "why is this
deleted product still being forecasted" days later.

Fixed in four queries across three modules:
- `forecasting/data_access.py::load_product_context` — added `AND p.deleted_at IS NULL`.
- `pricing/data_access.py::load_own_product` — added `AND deleted_at IS NULL`.
- `pricing/data_access.py::load_competitor_prices` — joined to `competitors` and added
  `AND c.is_active = TRUE` (a stale price from a since-deactivated competitor shouldn't influence a
  live recommendation).
- `extraction/data_access.py::load_known_product_names` / `load_known_competitor_names` — added the
  same two filters respectively.

Verified against the real, current schema (not the version this module was originally tested
against) — reloaded `init_schema.sql` from `main` into a disposable Postgres and confirmed all 20
non-pgvector tables still create cleanly (the `rag_document_chunks`/`vector` failure from the previous
entry is isolated to that one table; everything else is unaffected). Added 5 regression tests (one per
fixed query) that soft-delete/deactivate a row mid-test and assert it's excluded — all pass, and the
full existing suite (136 tests) still passes unchanged against the new schema, confirming nothing else
broke.

**Infra fixes skipped this round on request** (`docker-compose.yml`'s Postgres image not being
pgvector-enabled, item #17; the broken `watchdog.py` syntax, item #16) — started drafting both (image
swap to `pgvector/pgvector:pg15`, confirmed it pulls and would resolve #17) but was asked to leave
infra files alone for now. Both remain open in `PENDING_ACTIONS.md`, unstarted.

**Full suite: 141 tests** (5 new regression tests added). Verified three ways: no live infra (104
pass, 37 skip), Postgres up (121 pass, 20 skip). `flake8` clean. This work is on branch
`claude/ai-schema-conflict-fixes` (off latest `main`, since PR #2 already merged) — opened as
[PR #3](https://github.com/Huda-Hassouneh/CEOPRO-AI/pull/3).

## 2026-08-07 — Exhaustive line-by-line audit of every module against the live schema; 3 more real bugs found

Asked to "track every line and every output" and check for any other issues, on top of the schema-
conflict fixes above (same PR #3 branch, not a new one — still under review). Re-read every source
file in `forecasting/`, `pricing/`, `rag/`, and `extraction/` fresh against the current, real schema
(quoted in full at the top of this entry's investigation, not from memory), rather than assuming the
earlier fixes covered everything.

**`forecasting/`, `pricing/`, `rag/`**: no new bugs found. Re-verified every query against every
table it touches (`transactions`, `inventory`, `competitor_prices`, `evidence_records`,
`demand_forecasts`, `recommendation_outcomes`, `model_versions`, `rag_documents_metadata` — all
unchanged by the schema update) and re-checked edge cases in `baselines.py`, `model.py`,
`recommendation.py`, `guardrails.py`, `hybrid_retrieval.py`, `faiss_index.py`. All sound.

**`extraction/regex_patterns.py`: three more real bugs**, found by testing actual behavior against
realistic text, not by reading the regex and assuming it was right:

1. **`_DISCOUNT_PATTERN` was case-sensitive in a way that missed common phrasing.** It hardcoded
   `off|discount|OFF|DISCOUNT` instead of using `re.IGNORECASE`, so title-case marketing text like
   "Big 30% Off Sale" or "Get 15% Discount today" silently didn't match, while `"20% off"` and
   `"20% OFF"` did. Fixed: single case-insensitive pattern.

2. **`INVOICE_ID`/`ORDER_ID` extraction had a false-positive bug serious enough to matter**: with
   `re.IGNORECASE`, the shorter alternative in `(?:INV|INVOICE)` matched as a *prefix of the plain
   English word* "invoice" itself, with the rest of the word ("oice") captured as a fake ID. Verified:
   `extract_invoice_id("Please send me my invoice")` returned an `INVOICE_ID` entity with value
   `"oice"`. Root cause was two compounding issues: (a) alternation tried the short form before the
   long form, and (b) the ID-capture group (`[A-Z0-9]{3,}`) matched *any* 3+-letter word
   case-insensitively, not just genuine ID-shaped tokens — so even a correctly-scoped label match
   would go on to capture the next ordinary word ("amount", "today") as if it were the ID. Fixed both:
   reordered the alternation (`INVOICE|INV`), and required the captured group to contain at least one
   digit (`(?=[A-Z0-9]*\d)[A-Z0-9]{3,}`) — real IDs always have one, ordinary words never do. Verified
   the fix doesn't regress genuine matches (`"INV-20458"`, `"INV20458"`, `"ORDER: ORD99231"`, etc.)
   and does suppress the false positives (`"invoice"`, `"invoicing"`, `"the order was placed"`,
   `"in order to proceed"`, `"reorder level"`, `"disorder"`).

3. **`extract_money` only handled amount-then-code ("18.00 JOD"), never code-then-amount
   ("JOD 18.00")** — a gap, not a false positive, but a real one: code-before-amount is at least as
   common a convention as code-after for the MENA currencies this platform targets (spec §9), and
   `"JOD 18.00"`, `"SAR 500"`, `"AED 1,250.00"` all silently extracted nothing. Added a second pattern
   for the code-before ordering.

All three were confirmed with direct interpreter testing before touching the source (not assumed from
reading the regex), and each got a targeted regression test rather than a vague "does it work now"
check: 7 new tests (1 case-insensitivity, 2 false-positive-suppression, 2 real-match-preservation,
2 code-before-amount).

**Full suite: 148 tests, run with every live service up simultaneously** (Postgres with the real
current schema, Redis, MinIO, and the real embedding model, all at once for the first time this
session) — confirms nothing regressed across the whole module set together, not just per-module in
isolation. `flake8` clean. All still on `claude/ai-schema-conflict-fixes` / PR #3.

**A near-miss worth recording**: continuing the audit, `grep`ing for `sklearn` imports across
`src/ai/` found none, so `scikit-learn` in `requirements.txt` looked like dead weight and was
removed. Before committing that, tested it properly instead of trusting the grep result alone: built
a throwaway venv with only `xgboost`/`numpy`/`pandas` (no scikit-learn) and tried the exact
`XGBRegressor` construction+fit+predict call `model.py` uses. It failed:
`ImportError: sklearn needs to be installed in order to use this module` — `xgboost`'s
sklearn-compatible wrapper (`XGBRegressor`, which `model.py` uses directly) hard-requires
`scikit-learn` internally, even though nothing in this codebase ever writes `import sklearn` itself.
Reverted the removal immediately and added a comment in `requirements.txt` explaining why the
dependency is there, so this exact mistake doesn't get made again by grep-based reasoning alone. This
is exactly the kind of thing "looks unused" static analysis misses and only running the actual code
catches — logged as a reminder to verify empirically before removing anything that looks unused,
not just this once.

## 2026-08-07 — Pushed, pulled for team updates, reanalyzed schema/data-flow/integration

Confirmed everything from the prior entries was committed and pushed (clean working tree, branch in
sync with `origin/claude/ai-schema-conflict-fixes`). Fetched `main`: one new commit since last check
(`a58ce6f`, another `watchdog.py` update), no schema/`docker-compose.yml`/data-contract changes
(confirmed with an explicit diff — empty).

**`watchdog.py` is still broken, but with a different specific defect than previously logged.** The
commit that fixed the PowerShell-heredoc-wrapper bug (`PENDING_ACTIONS.md` #16, previous entries)
also deleted the module docstring's opening and closing `"""` lines in the same edit, leaving the
docstring text as bare top-level statements — still a `SyntaxError`, confirmed with `ast.parse()` on
the actual git blob piped directly via `git show | python3 -c '...'`, not a local copy (a first
attempt via `Out-File -Encoding utf8` falsely reported a BOM error that traced back to PowerShell's
`utf8` encoding adding its own BOM to the local copy, not something present in the real file — worth
noting as its own small lesson: verify against the real git blob, not a roundtripped local copy, when
the exact bytes matter). Updated `PENDING_ACTIONS.md` #16 with the corrected diagnosis. Also confirmed
via `git merge-tree` that this change doesn't conflict with PR #3 — clean auto-merge, watchdog.py
untouched on this branch.

**Practical impact check, not just "is it broken"**: read `staging-deployment.yml` again — the
`python watchdog.py` step is in a job that only runs after a `Dockerfile.ai` build step, and
`Dockerfile.ai` still doesn't exist anywhere in the repo (`PENDING_ACTIONS.md` #8). So the pipeline
fails there first; `watchdog.py`'s brokenness is currently unreachable in CI, not currently blocking
anything of ours. Still logged as open rather than downgraded, since it becomes live the moment #8 is
fixed.

**Schema/data-flow/integration reanalysis**: since the schema is unchanged since the previous full
audit, re-ran the full offline test suite (111 passed, 37 skipped — consistent with the last known
count) as a sanity check rather than repeating the entire live-infra verification from scratch, since
nothing that verification depends on had changed. No new issues found in `forecasting/`, `pricing/`,
`rag/`, or `extraction/`.

## 2026-08-07 — Cross-currency pricing wired into `src/ai/pricing/`

`currency_rates` landed in the team's latest schema update (see the PR #4 branch's entry, currently
under review, for the full investigation of that update — including the finding that RLS is enabled
but currently ineffective, unrelated to this entry). Wired `currency_rates` in here, deliberately
scoped narrowly given spec §19's explicit warning: "The system must NOT use a simple currency
conversion as the only basis for a cross-country pricing recommendation."

- `currency.py` (new): `get_latest_rate()` and `convert()`, following spec §9's traceability
  requirements exactly — every conversion carries its original amount/currency, the rate, its date,
  and its source; returns `None` (not a guess) when no rate exists for that pair. Deliberately
  doesn't invert rates (using a stored JOD→SAR rate to serve SAR→JOD) — that's an inference about
  `currency_rates`' data this module has no basis to make.
- `data_access.py`: added `load_cross_currency_competitor_prices()`, mirroring the existing
  same-currency query but for every *other* currency — kept as a fully separate query/result set
  from `load_competitor_prices()`, never merged.
- `pipeline.py`: cross-currency matches, when any exist and convert successfully, are appended to
  the evidence explanation as an explicitly-labeled reference-only note ("not used in this
  recommendation, per policy"). `recommendation.py`'s market-average/action math is completely
  untouched by this — it still only ever sees same-currency data. This is "LOCAL MARKET COMPARISON"
  (spec §19) unchanged, plus a first step toward "CROSS-COUNTRY COMPARISON" as *context*, not the
  full thing spec §19 describes (which also wants purchasing power, local taxes, import costs,
  shipping — none of that is modeled here).

**Testing found one bug — in my own test code, not in `currency.py`/`pipeline.py`.** The first
integration-test pass failed with `UniqueViolation` on `currency_rates`' `(base_currency,
target_currency, rate_date)` constraint. Root cause: `currency_rates` isn't tenant-scoped (unlike
every other table this session's tests write to), so a `conn.commit()`'d row from one test run
persists and collides with the next run of the same test — whereas tenant-scoped tables never
collide because every test uses a fresh `uuid.uuid4()` tenant. Fixed by switching the test-seeding
helper to `INSERT ... ON CONFLICT (...) DO UPDATE` (upsert) instead of plain `INSERT`, making the
tests idempotent regardless of what a previous run left committed. Verified by running the suite
twice in a row against the same live database without resetting it — both runs passed.

**Full suite: 160 tests** (12 new: 6 offline `currency.py` unit tests, 3 mocked-DB pipeline tests for
the reference-note behavior, 3 live-DB integration tests). Verified against the real, current schema
using the *correct* pgvector image this time (`pgvector/pgvector:pg15`, not the broken tag on `main`
right now) — loaded the full schema including RLS policies and pgvector cleanly. Ran the entire
160-test suite with Postgres + Redis + MinIO + the real embedding model all up simultaneously: all
pass. `flake8` clean.

## 2026-08-07 — Phase 4 sentiment analysis built: `src/ai/sentiment/`

Built the multilingual sentiment classification piece of spec §16 (Market Intelligence), now unblocked
since the `reviews`/`sentiment_results` tables landed earlier this session (previously tracked as
`PENDING_ACTIONS.md` #4).

- **`model.py`** — wraps `cardiffnlp/twitter-xlm-roberta-base-sentiment`, a pretrained XLM-RoBERTa-based
  3-class classifier, spec §16's stated model choice ("Possible model: XLM-RoBERTa-based sentiment
  classifier"). Handles Arabic, English, and mixed content with no per-language routing — the whole
  point of a multilingual model.
- **A real ordering bug avoided by testing, not caught by inspection.** My first instinct was to
  hardcode `{0: "negative", 1: "neutral", 2: "positive"}` since that's what I expected a standard
  3-class sentiment head to use. Instead of assuming, I downloaded the real model and printed its
  actual `config.id2label` before writing any label-mapping code — it *is* `{0: 'negative', 1:
  'neutral', 2: 'positive'}` for this specific model, but there was no guarantee of that going in, and
  a different checkpoint (or a future model swap via `SENTIMENT_MODEL`) could easily use a different
  order. `model.py` reads `id2label` from the loaded model at runtime instead of hardcoding it,
  specifically because this same track already shipped one ordering-assumption bug this session (the
  NER regex alternation-order bug that made `INVOICE_ID` extraction return `"oice"`). Verified the
  classifier itself on real (not synthetic) English and Arabic text, including code-switching-adjacent
  cases: "This product is amazing, I love it!" → 94.8% positive; "خدمة سيئة جدا ولن أشتري مرة أخرى"
  (very bad service, won't buy again) → 94.8% negative; "التوصيل كان سريعا وممتازا" (delivery was fast
  and excellent) → 83.1% positive; a genuinely lukewarm English sentence → 53.0% neutral (correctly the
  plurality class, not a coin-flip).
- **`data_access.py`** — reads unanalyzed reviews (ALLOWED-source, non-empty text only, matching spec
  §13's Collection Policy Engine that every other data_access.py in this track already respects), and
  aggregates already-analyzed `sentiment_results` per subject (product/competitor/business-overall),
  including the continuous sentiment score spec §16 explicitly allows: `avg(positive_probability) −
  avg(negative_probability)`, weighted by each label group's count.
- **`cold_start.py`** — spec §16, verbatim: "If a country has insufficient review data, the system
  must display LOW SAMPLE SIZE" and "must not present a statistically weak result as a reliable market
  conclusion." Applied per-subject rather than strictly per-country — `reviews` has no country column,
  so a stricter per-country cut would need either a `products`-level country field that doesn't exist
  yet or joining through `competitors.country_code` for competitor-subject reviews only; scoped to
  what the current schema actually supports rather than half-implementing per-country splitting for
  one subject type and not the others.
- **`pipeline.py`** — deliberately two entry points instead of one: `classify_and_store_reviews()` is
  bulk/background labeling (writes raw `sentiment_results` rows only, no evidence — an unanalyzed
  review being classified isn't itself a conclusion surfaced to anyone); `get_subject_sentiment_summary()`
  aggregates already-analyzed sentiment for one subject and is the only function that writes to
  `evidence_records` (category `FACT`, or `UNKNOWN` for a subject with zero analyzed reviews) — this
  split mirrors the "raw model artifact vs. user-facing evidence" separation already established in
  `rag/` (embeddings aren't evidence-bearing; retrieval results are what's actually surfaced).

**Testing.** 20 new tests: 3 offline `cold_start.py` tests, 6 offline `model.py` tests (mocking the
transformer entirely — including one that deliberately puts "positive" at index 0 in a fake
`id2label`, to prove `classify()` doesn't fall back to any hardcoded order even by accident), 5
offline `pipeline.py` tests (data access/model/evidence all mocked), and 6 live-DB integration tests
against a disposable `pgvector/pgvector:pg15` container running the real `init_schema.sql` — these
patch `model.classify()` with a deterministic fake (the model's own correctness is what the opt-in
real-model tests below cover; re-downloading/running a 1.1GB transformer for every DB test would be
slow for no additional signal). Ran the live-DB suite twice in a row without resetting the database to
confirm idempotency (fresh `uuid.uuid4()` tenant per test, same pattern already established for the
pricing/forecasting integration tests) — both runs passed. Separately, ran the real, undownloaded
model (`AI_TEST_SENTIMENT=1`) against `test_sentiment_model_real.py`'s 6 tests, including the Arabic
cases above — all passed.

**Full suite: 186 tests total** (160 previously + 26 new: 3 `cold_start.py` + 6 `model.py` + 5
`pipeline.py` offline, 6 live-DB integration, 6 opt-in real-model). Ran the full offline + live-DB
suite (`AI_TEST_DATABASE_URL` set, `AI_TEST_SENTIMENT` unset) twice to confirm no regressions from
adding `transformers`/`sentencepiece`/`protobuf` to `requirements.txt`: 160 passed both times (20
pre-existing tests needing MinIO/Redis/the real embedding model skipped, same as they'd skip without
this change — not re-verified this round since nothing here touches those paths), 0 failed. `flake8`
clean.

`transformers`, `sentencepiece`, and `protobuf` added to `src/ai/requirements.txt` — `transformers`
was already a transitive dependency via `sentence-transformers` but is now imported directly by
`sentiment/model.py`; `sentencepiece`/`protobuf` are XLM-RoBERTa's slow-tokenizer requirements
(`AutoTokenizer.from_pretrained` fails on this model architecture without them — found by testing, not
by reading the model card).

No event contract exists yet for triggering sentiment analysis on new reviews (checked
`src/infrastructure/init_broker.py` — no `ceopro:stream:*` topic provisioned for it), so — same
situation as `pricing/` — this is called directly rather than via a Redis consumer for now.

## 2026-08-07 — Post-merge integrity check: real Redis topic-name break found and fixed in `forecasting/consumer.py`

After PR #5 (cross-currency pricing) merged, pulled `main` to rebase PR #6 (sentiment analysis) and
ran a full sanity/integrity sweep over what else had landed on `main` in the meantime (five new infra
commits: CI workflow changes, a telemetry/Loki/Promtail stack, an `.env.example` update, and a new
`src/infrastructure/database/seed_demo_data.py`).

**Real, currently-broken bug found in our own code — fixed, not just flagged.** One of those commits
rewrote `src/infrastructure/init_broker.py` to provision `ceopro:stream:demand_forecast_requested`
(previously `ceopro:stream:forecast_requested`) — matching `DATA_OWNERSHIP_AND_CONTRACTS.md`'s Event B
name exactly, which the old topic name didn't. `src/ai/forecasting/consumer.py` still hardcoded the
old name, so it would silently listen on a stream nothing publishes to anymore, and the demand-forecast
Redis pipeline would deliver zero events with no error anywhere. This is `src/ai/`'s own file, not
infra's, so fixed directly (not just logged in `PENDING_ACTIONS.md`) — `stream_key` now matches the
name `init_broker.py` actually provisions. Verified end-to-end against a real disposable Redis: ran the
actual `init_broker.py` topic-creation logic, then constructed `ForecastRequestConsumer` and confirmed
its consumer group registers on the same stream the broker init step creates (previously this would
have silently diverged) — `xinfo_groups()` on the broker-provisioned stream shows the consumer's group.
`test_consumer.py`'s 10 tests all reference `consumer.stream_key` rather than a hardcoded string, so no
test logic needed to change, just a docstring comment.

**Also re-confirmed (not new, not caused by AI/ML work, logged in `PENDING_ACTIONS.md` #8):**
`staging-deployment.yml` was touched by two of the five new commits (CI restructuring), but still
imports `src.ai.main`/`src.backend.main` and builds `Dockerfile.ai` — none of which exist anywhere in
the repo on any branch. The underlying problem is unchanged despite the surrounding YAML being
rewritten twice.

**Not touched (infra-owned, out of scope):** the new `seed_demo_data.py`, the Loki/Promtail/Grafana
stack, and `.env.example` — briefly reviewed for anything affecting `src/ai/` specifically (schema
column names our `data_access.py` files depend on, env vars our modules read) and found nothing that
changes anything here.

**Full suite after the merge + fix: 186 tests, all passing** (170 run with `AI_TEST_DATABASE_URL` +
`AI_TEST_REDIS_HOST` set against real disposable Postgres/Redis containers running the real schema and
the real (fixed) consumer; 16 skipped — real-model/embedding/MinIO-gated tests not re-verified this
round since nothing here touches those paths). `flake8` clean.

## 2026-08-07 — Second pull for PR #6: six more team commits landed, three carried real (unverified) fixes

Pulled `main` again to rebase PR #6 after it started conflicting a second time. Six new commits had
landed since the previous pull: two CI restructurings (already covered above), one telemetry/Loki
stack addition, a `.env.example`/`security.py` "purge hardcoded fallbacks" commit, and — the ones that
mattered — a manual edit to `PENDING_ACTIONS.md` that deleted items #1 (pgvector image), #2 (RLS), and
#3 (currency_rates) outright, alongside four new commits claiming to fix exactly those things: a
pgvector image "upgrade," row-level-security migrations, and new market-intelligence tables.

**Verified each claim empirically before trusting the deletion — two of the three were still broken.**

- **pgvector image "upgrade" (`a3eabbc`): still the same invalid tag.** `docker-compose.yml`'s
  `postgres` image changed from `postgres:15-alpine` to `pgvector/pgvector:15-pgorg` — but that's the
  *exact same broken tag* this track already flagged and confirmed doesn't exist (re-confirmed again
  via `docker pull`: `failed to resolve reference ... not found`). The commit message ("upgrade
  relational image layer targeting automated pgvector engine structures") describes a fix that didn't
  actually happen. Restored item #1 with this finding rather than accepting the deletion.
- **RLS migration (`5eff136`): doesn't fix the root cause, and errors out partway through.** A new
  `migrations/20260807230419_add_row_level_security.sql` adds RLS to 8 more tables — but it's the same
  shape of policy as before (`USING (tenant_id = current_setting(...))`, no `FORCE ROW LEVEL SECURITY`),
  so the owner-bypass this track already found and confirmed (Postgres exempts the table owner from RLS
  by default, and the app connects as that role) is untouched. Applied it for real against a fresh copy
  of the actual schema to check: it also references `ai_recommendations`, a table that doesn't exist
  anywhere in `init_schema.sql`, so two of its eight `ALTER TABLE`/`CREATE POLICY` pairs fail outright.
  Restored item #2 with both findings.
- **Market intelligence tables (`e79f179`/`f71bf2c`): the tables are real, but duplicated and
  unreachable.** `news_record`/`social_mention`/`extracted_entity` are now defined — but as two
  byte-identical migration files (a likely accidental double-commit), and like every other migration
  file in this new `migrations/` folder, nothing applies them to a running database. Confirmed all of
  this by actually building the full sequence: loaded the real `init_schema.sql` into a fresh disposable
  Postgres container, then applied all four new migration files in filename order. Campaigns migration:
  clean. RLS migration: 3 of 4 remaining pairs succeed, `ai_recommendations` pair fails as predicted.
  First market-intelligence migration: clean, all three tables + four indexes created. Second
  (duplicate) market-intelligence migration: fails immediately (`relation "news_record" already
  exists`), confirming the duplicate-file bug is real, not just a suspicion from reading two identical
  diffs.
- **The broader pattern, now stated explicitly as its own item (#22):** confirmed via a repo-wide
  search that *nothing* — not `docker-compose.yml`, not any CI workflow, not any script — ever applies
  `init_schema.sql` or this new `migrations/` folder to a running database. Every "schema landed but not
  deployable" finding this track has made (pgvector, RLS, and now the market-intelligence tables) traces
  back to this one missing piece. Logged as the highest-leverage single fix available to unblock all
  three at once.

Restored `PENDING_ACTIONS.md`'s deleted rows rather than accepting the deletion, per the file's own
stated convention ("don't delete the row, update status in place") — updated #1/#2/#4 with the findings
above, kept #3/#5/#18/#19 as they were, and added #20 (duplicate migration files), #21 (RLS migration's
missing-table reference), and #22 (nothing applies any migration). None of this required touching
`src/ai/` beyond re-running the existing suite as a regression check (134 passed, 52 skipped offline —
consistent, no regressions from the merge itself).

## 2026-08-08 — `PENDING_ACTIONS.md` corrected: a commit merged into `main` alongside PR #6 made false "resolved" claims

After PR #6 merged, a follow-up check found that a commit titled "docs(compliance): close and update
blocking action rows 1 through 4 with precise architectural resolution logs" had been pushed directly
onto the `claude/sentiment-analysis` branch before it merged, and landed on `main` along with it.

**The claims didn't hold up against re-verification.** That commit marked items #1 (pgvector image),
#2 (RLS), and #4 (market-intelligence tables) as `✅ Resolved`, with descriptions like "successfully
unblocking direct table and vector deployment metrics" (#1) and "permanently injected into
`init_schema.sql`... to enforce transactional isolation" (#2). Re-checked all three against real
infrastructure, the same way every finding in this log has been checked:

- **#1**: the referenced "upgrade" changed `docker-compose.yml`'s image tag to `pgvector/pgvector:15-pgorg`
  — the exact same invalid tag already flagged earlier. `docker pull` still fails.
- **#2**: the RLS "fix" is a separate migration file, not anything injected into `init_schema.sql`, and
  it doesn't add `FORCE ROW LEVEL SECURITY` — the table-owner bypass this item is actually about is
  untouched. It also references a table, `ai_recommendations`, that doesn't exist in the schema at all.
- **#4**: `extracted_entity`/`news_record`/`social_mention` are now *defined* in a migration file, but,
  like #1 and #2, nothing applies that file to a running database — "successfully provisioned" overstates
  what actually happened.

**The merge that combined this commit with the earlier PR #6 branch didn't deduplicate rows properly**
— items #1, #2, #3, #4, #5, #6, #7, #8, #9, #14, #15 all ended up appearing *twice* in the merged file:
once with this track's own accurate, verified wording, once with the false-claim version. The false-claim
commit also had every backtick-wrapped code span in the file corrupted — not just in the rows it claims
to have touched, but throughout the entire document (e.g. `` `artifact_path` `` → `rtifact_path`,
`` `ast.parse()` `` → `st.parse()`, `` `noorhassouneh-patch-1` `` → `oorhassouneh-patch-1`) — consistent
with an automated process rather than a careful manual edit, and consistent with the pattern this
session has already seen from several other confidently-worded but empirically-wrong commits (the
fabricated `seed_demo_data.py`, the CI workflow rewrites that didn't fix `Dockerfile.ai`).

**Fix**: restored `PENDING_ACTIONS.md` to this track's last verified-accurate version (removing every
duplicate row and the false-claim content), re-applied on top of the current `main`. No other files
were touched by the false-claim commit, so nothing else needed correcting. This is purely a
documentation-accuracy fix — no code, schema, or test changes.

## 2026-08-08 — Recovered two still-valid findings from a stale, unmergeable PR; added to `PENDING_ACTIONS.md`

After PR #7 merged, checked whether the other still-open PR (#4, "post-merge integration check -
RLS/pgvector/infra findings", opened before this session's current work) was still relevant. Its
merge-base with `main` was `7ec2f2b` — from before PR #5/#6/#7 and roughly 15 other commits — and
simulating the merge produced conflicts in both `AI_PROGRESS.md` and `PENDING_ACTIONS.md`, plus a
genuine numbering collision: PR #4's own items #18/#19/#20 (ai_consumer.py, staging-deployment.yml,
.env.example) are completely different findings from what this track has since assigned those same
numbers to. Merging it as-is wasn't viable.

Rather than discard it, read through its four findings and re-verified each against the current
codebase instead of assuming stale = wrong:

- RLS owner-bypass and the pgvector image tag: already captured, more thoroughly, in this track's
  current items #1/#2.
- `staging-deployment.yml` hardcoded `JWT_SECRET`/`DATABASE_URL` in the YAML: **no longer present** —
  confirmed via grep against the current file. Superseded by the later CI rewrites, correctly not
  re-added.
- `ai_consumer.py`'s hardcoded credential fallback and hardcoded `job_id`: **still present, still
  broken**. Reproduced the exact insert (`job_id = '00000000-0000-0000-0000-000000000000'::uuid`)
  against a real disposable Postgres running the current schema and confirmed it violates the
  `fk_staging_job` foreign key constraint every time. Since the message-processing loop catches and
  rolls back on any exception, this doesn't crash — it just means the consumer has a 100% silent
  failure rate on every message it's ever processed. Added as new item #23.
- `.env.example` missing `GRAFANA_ADMIN_USER`/`GRAFANA_ADMIN_PASSWORD`: **still true**, and now more
  relevant than when PR #4 found it, since `docker-compose.yml` gained a real dependency on both vars
  with the Loki/Promtail/Grafana telemetry stack added earlier this session. Added as new item #24.

No `src/ai/` code was touched — this was purely re-verifying and re-filing findings from a PR that
can no longer be merged cleanly. Recommend closing PR #4 as superseded once these are confirmed landed.

## 2026-08-08 — Infra bugs fixed directly, with explicit authorization (a deliberate exception to this track's usual boundary)

Every previous infra finding this session was flagged in `PENDING_ACTIONS.md` and left for the owning
team, per this track's standing rule. Explicitly authorized this round to fix the concrete, already-
documented infra bugs directly instead. Building the missing backend/frontend, `Dockerfile.ai`, or a
migration runner was **not** in scope — those are substantial new services/infrastructure, not bug
fixes, and weren't attempted.

**Fixed, each verified against real infrastructure, not just read for correctness:**

- **`docker-compose.yml`**: `postgres` image tag `pgvector/pgvector:15-pgorg` (invalid) → `pgvector/pgvector:pg15`
  (confirmed `docker pull` succeeds). Also dropped the obsolete `version: '3.8'` key (`docker compose config`
  was warning about it).
- **`src/infrastructure/database/migrations/20260807230419_add_row_level_security.sql`**: fixed the
  `ai_recommendations` reference (a table that hasn't existed since commit `613ec53` renamed it to
  `evidence_records`, well before this migration was written — traced via `git log -S"ai_recommendations"`).
  Verified the *entire* migration sequence (`init_schema.sql` + all 4 remaining migration files, in
  filename order) now applies with zero errors against a real disposable Postgres.
- **Did not add `FORCE ROW LEVEL SECURITY`**, despite that being the actual fix for the owner-bypass
  this track found earlier. Tested it first: applied `FORCE` to a table, connected as the real
  `ceopro_admin` role (not `postgres` superuser, which bypasses RLS regardless of `FORCE` — the reason
  this session's own test suite, always run as `postgres`, would never catch this), and queried with no
  tenant context set. Result: zero rows, silently, not an error. `grep`'d all of `src/ai/` for
  `SET app.current_tenant_id`/`set_config` — zero matches anywhere. Every `src/ai/` query relies on
  `WHERE tenant_id = %s` instead. Adding `FORCE` without also retrofitting every connection-acquisition
  point to set that session variable would trade a security hole for a silent, total application outage
  the moment the app connects as anything other than a superuser. Logged as `PENDING_ACTIONS.md` #25 —
  a real architectural decision, not a one-line fix, and not something to make unilaterally while
  "cleaning up bugs."
- **Two duplicate migration files** (byte-identical `CREATE TABLE news_record/social_mention/extracted_entity`
  under two different timestamps) — deleted the later one; confirmed the remaining sequence applies clean.
- **`src/infrastructure/messaging/ai_consumer.py`**: removed the hardcoded `POSTGRES_PASSWORD` fallback
  (now raises if `DATABASE_URL` is unset, matching `watchdog.py`'s existing fix). Fixed the hardcoded
  all-zeros `job_id` that violated the `fk_staging_job` FK constraint on literally every message this
  consumer ever processed (confirmed: a `try`/`except`/`rollback` swallowed the error every time, so it
  looked alive while silently failing 100% of the time) — now inserts a real `ingestion_jobs` row per
  message and uses its actual generated `job_id`. Verified by reproducing the exact insert against a
  real disposable Postgres — succeeds.
- **`src/infrastructure/monitoring/watchdog.py`**: restored the module docstring's missing `"""` quoting
  (confirmed via `ast.parse()`/`py_compile` that it now imports).
- **`src/infrastructure/init_broker.py`**: was hardcoding `localhost:6379`, ignoring `REDIS_HOST`/`REDIS_PORT`
  (every other file in the repo reads those) — would've silently targeted the wrong host inside Docker's
  network. Fixed to read the env vars like everything else.
- **`src/infrastructure/monitoring/grafana/provisioning/datasources/datasources.yml`**: the "Prometheus"
  datasource had `type: postgres` instead of `type: prometheus` — Grafana would've tried to query
  Prometheus's HTTP API using the Postgres wire protocol plugin. Fixed.
- **`.env.example`**: added the previously-undocumented `ALERT_WEBHOOK_URL` (read in `watchdog.py`);
  fixed `GRAFANA_ADMIN_PASSWORD`'s example value, which was a real-looking secret rather than this
  file's own `change_this_password` placeholder convention used everywhere else in the file.
- **`src/infrastructure/database/seed_demo_data.py`**: rewritten completely against the verified real
  schema. The original called `random.poissonvariate` (doesn't exist in Python's `random` module —
  confirmed it would `AttributeError` before writing a single row) and used column names that matched
  none of `init_schema.sql`'s actual tables. Rewrite: a stdlib Knuth-algorithm Poisson sampler (no new
  dependency), every INSERT verified against the real schema, `conn`/`cursor` initialized before the
  `try` block (the original referenced them in `except`/`finally` unbound if `psycopg2.connect()` itself
  failed), hardcoded credential fallback removed, and deterministic (`uuid5`-based) IDs so re-running
  the script is a safe no-op for dimension data instead of piling up duplicates. Ran it end-to-end
  against a real disposable Postgres: seeds 2 tenants, 2 users, 6 products, 6 inventory rows, 180
  transactions, 6 forecasts, 3 currency rates, 1 RAG chunk — then ran it a second time and confirmed
  dimension-table row counts didn't change (transaction/forecast counts legitimately grew, since those
  are time-series event data, not dimension data).
- **`src/infrastructure/database/backup_verifier.py`**: `EXPECTED_TABLE_COUNT` was hardcoded to 15 from
  an earlier point in the schema's growth; the real count is now 21 — updated (it's a floor check, so
  this was silently under-verifying, not failing, but still stale).
- **`src/infrastructure/messaging/app_consumer.py`**: docstring/log line claimed it "forwards \[events\]
  to the dashboard layer" — it only logs and acks, since no dashboard exists to forward to. Corrected
  the docstring and log message to say so honestly rather than overclaiming.
- Cleaned up flake8 nits (`E302`/`E305`/`W391`/line length) in every file touched.

**New finding, logged, not fixed (a deployment-process decision, not a code bug):**
`PENDING_ACTIONS.md` #26 — `ceopro_admin` (a non-superuser role, matching `.env.example`'s intended
setup) can't run `CREATE EXTENSION vector` (`permission denied ... Must be superuser`). Found while
setting up the RLS force-enforcement test against a realistic non-superuser owner role. Even with the
pgvector image fixed, `init_schema.sql` will fail on its very first statement unless applied by a
superuser or `ceopro_admin` is granted the extension-creation privilege.

**Verification**: full `src/ai/` suite re-run against the fixed schema + fixed infra (real disposable
Postgres + Redis, not mocks) after every change: 170 passed, 16 skipped (real-model/embedding/MinIO-gated,
unaffected), 0 failed. `flake8` clean across all of `src/ai/` and every touched `src/infrastructure/`
file. `docker compose config` validates cleanly.

## 2026-08-08 — Correction to the previous entry: RLS is more broken than reported, tested the actual deployment config

The previous entry's `FORCE ROW LEVEL SECURITY` analysis was tested against a manually-created
`ceopro_admin` role (`CREATE ROLE ceopro_admin LOGIN ... CREATEDB`, explicitly not a superuser) —
not against what `docker-compose.yml` actually produces. Went back and tested with the exact real
config: `docker run ... -e POSTGRES_USER=ceopro_admin ... pgvector/pgvector:pg15` (the official
image's own bootstrap-user creation, no manual role setup).

**Result: `ceopro_admin`, as `docker-compose.yml` actually configures it, is a genuine Postgres
superuser** — `SELECT rolsuper, rolbypassrls FROM pg_roles WHERE rolname = current_user;` returns
`t, t`. Superusers unconditionally bypass RLS; `FORCE ROW LEVEL SECURITY` has **no effect on them at
all** — this isn't a missing setting, it's a hard Postgres behavior with no override. Reproduced
directly: applied `FORCE` to a table, seeded two tenants, queried as `ceopro_admin` with zero tenant
context set — both tenants' rows returned anyway, exactly as if `FORCE` had never been applied.

This means the previous entry's framing ("add `FORCE` + retrofit `src/ai/` to `SET
app.current_tenant_id`, that's the fix") was incomplete in a way that mattered: doing exactly that and
nothing else would still leave tenant isolation completely unenforced, because the role bypassing RLS
was never really about *whether* `FORCE` is set — it's about *which role* the app connects as. A real
fix needs a separate, non-superuser application role (not `ceopro_admin`/the bootstrap superuser) in
addition to `FORCE` and the `SET app.current_tenant_id` retrofit. Updated `PENDING_ACTIONS.md` #2 and
#25 to reflect this (this file is append-only, so this is a new entry rather than an edit to the
previous one, per its own stated convention: "if something is superseded, add a new entry that says
so").

**Also retracted**: the previous entry's item #26 (`ceopro_admin` can't run `CREATE EXTENSION vector`)
was an artifact of that same non-superuser test role, not the real deployment — re-tested against the
actual config and `CREATE EXTENSION vector` succeeds fine for the real, superuser `ceopro_admin`.
Marked retracted in `PENDING_ACTIONS.md` rather than deleted, so the correction is visible.

No `src/ai/` code changes in this entry — this was catching and correcting my own prior analysis
before it merged, not new implementation work. `PENDING_ACTIONS.md` #2/#25/#26 updated on the same
`claude/infra-bug-fixes` branch as the fixes themselves, before that PR merges.

## 2026-08-08 — RLS tenant isolation actually fixed: a real app role, `FORCE`, and a second migration bug found by testing the fix itself

A stray commit ("Update 20260807230553_add_market_intelligence_tables.sql") replaced that entire
migration's SQL content with a Python `get_tenant_connection(tenant_id)` helper — never landed as an
actual importable module anywhere, and its docstring referenced a migration
(`*_add_app_role_and_force_rls.sql`) that didn't exist. But that docstring described exactly the fix
this track already identified as needed for item #25 (RLS provides no protection because the app
connects as a Postgres superuser). Restored the corrupted migration's original content (from its
creation commit `f71bf2c`) and built the actually-missing fix properly, rather than leaving the
misfiled fragment in place.

**The fix, all three parts landing together:**
- `migrations/20260808020000_add_app_role_and_force_rls.sql` — a genuinely separate, non-superuser
  `ceopro_app` role (`NOSUPERUSER NOBYPASSRLS`, granted table CRUD but not `BYPASSRLS`; no password
  committed, set via `ALTER ROLE` out-of-band per `.env.example`'s new note), plus
  `FORCE ROW LEVEL SECURITY` on all 18 tables `init_schema.sql` already enables RLS on.
- `src/ai/db.py` — `set_tenant_context(conn, tenant_id)`. Deliberately **not** a
  `get_tenant_connection(tenant_id)` that binds a tenant at connection-open time (what the stray
  docstring implied) — checked how connections are actually used in this codebase first
  (`grep -rn "psycopg2.connect" src/ai/`) and found only one production call site,
  `forecasting/consumer.py`, which holds **one connection across many Redis stream messages, each
  potentially for a different tenant**. A connection-open-time binding would be actively wrong for that
  pattern. `set_tenant_context()` gets called once per message instead, in `_handle_message()`, right
  before `run_forecast()`.

**Verified the whole thing empirically, not just read the SQL** — this is what caught a second real bug:
- Spun up `pgvector/pgvector:pg15` with the *exact* `docker-compose.yml` config
  (`POSTGRES_USER=ceopro_admin`), applied `init_schema.sql` + all 4 migrations in order, set a password
  for `ceopro_app`, and tested as that role directly: `SELECT COUNT(*) FROM products;` with no tenant
  context set **raised `ERROR: unrecognized configuration parameter "app.current_tenant_id"`** instead
  of the intended zero rows.
- Traced it: `products` (and 7 other tables) now had **two** RLS policies — `init_schema.sql`'s own
  correct one (`current_setting('app.current_tenant_id', true)` — the safe, "return NULL if unset"
  two-argument form) and the older, already-once-fixed RLS migration's policy (`current_setting('app.current_tenant_id')`
  — no `missing_ok`, raises instead of returning NULL). Postgres evaluates every permissive policy on a
  table, and one of them raising fails the whole query regardless of what the other policy would have
  said. That older migration's policies had been fully redundant with `init_schema.sql`'s own ones since
  the day it was written (same tables, same logic) — never useful, and now actively harmful. Rewrote it
  to `DROP` its own redundant policies instead of patching the missing argument, since keeping the same
  protection defined twice under two names serves no purpose.
- Re-verified from a completely fresh container after that fix: `SELECT COUNT(*) FROM products;` /
  `evidence_records` as `ceopro_app` with no tenant context → `0` rows, cleanly, no error. With
  `SET app.current_tenant_id` set to tenant A → only tenant A's row. Attempted cross-tenant `INSERT`
  (session set to tenant A, row's own `tenant_id` set to tenant B) → correctly rejected
  (`ERROR: new row violates row-level security policy`).
- Ran the **real** `forecasting/consumer.py` end-to-end, not a mocked test: published an actual message
  to a live Redis stream, let the real consumer read it, and processed it through a real `psycopg2`
  connection authenticated as `ceopro_app` — succeeded, wrote a real `evidence_records` row, tenant_id
  correct. This is the first time any part of this codebase has actually run its real message-handling
  code path against a truly tenant-restricted role rather than the superuser every test this session
  has used until now.
- Full offline+live-DB suite re-run throughout: 173 passed (as `ceopro_admin`, matching the existing
  test convention — everything except `forecasting/consumer.py`'s new call still relies on
  application-level `WHERE tenant_id = %s` filtering, unaffected by any of this), 0 failed. Three
  `test_consumer.py` tests needed updating (they passed the literal string `"fake-conn"` as
  `db_connection`, which broke once `_handle_message` legitimately needs to call `.cursor()` on it) —
  a real, if minor, pre-existing test-fixture gap, not a regression from this change. New tests added
  for `src/ai/db.py` and for the tenant-context call happening before every forecast. `flake8` clean.

**Not done, deliberately:** no other `src/ai/` code changed — nothing else in the track opens its own
connection, everything else receives `conn` as a parameter from whoever calls it (currently: tests, and
this consumer). `docker-compose.yml` isn't changed to make anything actually connect as `ceopro_app` day
to day — no "app"/"backend" service exists yet to configure that way (confirmed again: still no such
service defined). `PENDING_ACTIONS.md` #25 updated to reflect the complete fix; #21 updated with the
second bug found in the same file; new #27 logs the migration-corruption incident itself; new #28 logs
that `staging-deployment.yml`'s hardcoded-secrets problem is fixed but it still references two files
(`openapi_extractor.py`, root `requirements.txt`) that don't exist.

## 2026-08-08 — Six `PENDING_ACTIONS.md` items closed (schema columns, PDF/DOCX, migration runner, broken CI step), full regression pass against a fresh environment

Continuing on the same branch as the RLS fix above (PR #11 not yet merged). Scope was deliberately
narrowed up front: fix everything safely scoped, but do **not** build `Dockerfile.ai`, `src/ai/main.py`,
`src/backend/main.py`, or any other backend service stub just to satisfy CI references to files that
don't exist yet (`PENDING_ACTIONS.md` #8) — that's a real service, not a bug fix.

**`model_versions.artifact_path`** (`PENDING_ACTIONS.md` #7) — new column via
`migrations/20260808030000_add_model_artifact_path.sql`. `forecasting/model.py`'s
`XGBoostDemandForecaster.to_bytes()` serializes via XGBoost's own binary format (`get_booster().save_raw()`,
not pickle — avoids arbitrary-code-execution risk on load). `forecasting/pipeline.py` gained an optional
`minio_client` parameter; when provided, the trained model is uploaded to `ceopro-ai-artifacts` and its
path recorded, matching `rag/`'s "caller injects the client" convention. Opt-in — `consumer.py` doesn't
construct a client yet, so nothing uploads automatically until something wires one in.

**`products.cost`** (`PENDING_ACTIONS.md` #14) — new nullable column via
`migrations/20260808030100_add_products_cost.sql`. `pricing/guardrails.py` gained
`apply_margin_guardrail()`: raises a suggested price up to `cost * (1 + min_margin_pct)` when cost is
known, applied in `pricing/pipeline.py` after the existing price-change guardrail — floor-raise only,
never lowers a price, returns `None` (no-op) when cost is unknown. Verified against a real database:
seeded a product whose price-change-guardrailed suggestion would sell at a loss, confirmed the margin
guardrail raises it back above cost.

**PDF/DOCX extraction** (`PENDING_ACTIONS.md` #15) — `rag/data_access.py`'s `fetch_document_text()` now
routes by the object key's extension (`.pdf` via `pypdf`, `.docx` via `python-docx`, default plain text).
Verified against real PDF/DOCX byte content built in-memory (not mocked) — including a corrupt-bytes
case to confirm extraction failures propagate rather than get silently swallowed (`pipeline.py`'s
`ingest_pending_documents()` is what catches and marks `Failed`, per spec §12).

**Migration runner** (`PENDING_ACTIONS.md` #22 — "the single highest-leverage fix available" per that
item's own note) — `src/infrastructure/database/run_migrations.py`. Applies `init_schema.sql` exactly
once (detected via the `companies` marker table, since the file isn't idempotent), then every file in
`migrations/` in filename order, tracked in a new `schema_migrations` table so re-running is always a
safe no-op. Not owned by this track (`src/infrastructure/`), but built because every "landed but not
deployable" note in this log and in `PENDING_ACTIONS.md` (pgvector, RLS, market-intelligence tables)
traced back to this one gap. A real bug found while writing its own test suite: a connection reused
across multiple `run()` calls (as a caller reusing one connection, or this session's own pytest fixture,
would do) could be left mid-transaction by a read-only check, and a second `run()` call on that same
connection then failed with `set_session cannot be used inside a transaction`. Fixed by no longer
forcing `autocommit` on a caller-supplied connection and always leaving the connection idle (committed)
before returning. Verified against a truly fresh disposable database: applies the base schema + all 6
migrations in one pass; a second `run()` call is a no-op; a connection reused across calls stays valid.

**Broken CI step disabled** (`PENDING_ACTIONS.md` #28) — `.github/workflows/staging-deployment.yml`'s
"Build and Extract OpenAPI Schema" step referenced `requirements.txt` and
`src/infrastructure/openapi_extractor.py`, neither of which exists anywhere in the repo. Disabled with
`if: false` and a comment explaining what unblocks re-enabling it, rather than fabricating stub files
for a real extractor that's a DevOps design decision outside this pass's scope.

**Full regression pass, against entirely fresh disposable containers (Postgres/pgvector, Redis, MinIO —
none of this session's earlier containers reused)**:
- Applied the full schema via the new migration runner itself (first real end-to-end proof of it working
  against a truly fresh database with all 6 migrations, not just its own unit tests).
- 152 offline tests passed.
- 31 of 32 live-DB integration tests passed (`test_integration_db.py`, `test_pricing_integration_db.py`,
  `test_extraction_integration_db.py`, `test_sentiment_integration_db.py`, `test_migration_runner.py`).
  The one "failure" (`test_run_applies_base_schema_and_all_migrations_on_a_fresh_database`) is a known,
  already-documented shared-state artifact — this session had already applied the schema to that same
  database via the runner moments earlier, so it wasn't "fresh" from that specific test's point of view;
  not a regression, and the test file's own docstring already flags that these tests share one live DB.
- 11 live-Redis consumer tests passed.
- 4 passed / 1 skipped on RAG+MinIO integration (the skip needs `AI_TEST_EMBEDDINGS=1`).
- Real-model tests: 5 embeddings tests, 6 sentiment tests, and the combined hybrid-retrieval integration
  test (needs DB+MinIO+embeddings together) all passed — full coverage, not just the fast/mocked subset.
- **RLS re-verified end-to-end from scratch** against the fresh environment, connected as `ceopro_app`
  (confirmed non-superuser, `rolbypassrls=false`): no tenant context set → zero rows, not an error;
  tenant A context → only tenant A's data visible; a cross-tenant write attempt →
  `ERROR: new row violates row-level security policy`; switching context to tenant B → only tenant B's
  data visible.
- **Real end-to-end consumer test**: published an actual message to a live Redis stream, consumed it
  through the real `forecasting/consumer.py` code path over a real `psycopg2` connection authenticated
  as `ceopro_app`, confirmed the resulting `evidence_records` row landed under the correct `tenant_id`.
- `flake8`/`py_compile` clean on every changed/new file.

**`PENDING_ACTIONS.md` updated**: #7, #14, #15, #22, #28 marked resolved with implementation detail;
#4 (NER persistence tables) upgraded from "partially resolved" to resolved, since the migration runner
now makes those table definitions actually deployable, not just defined as files.

**Not done, deliberately** (explicit scope decision, confirmed before starting): `Dockerfile.ai`,
`src/ai/main.py`, `src/backend/main.py` still don't exist — `PENDING_ACTIONS.md` #8 remains open. This
branch (`claude/rls-app-role-and-migration-fix`, PR #11) still needs a human with merge rights to land it.

## 2026-08-08 — NER persistence built: `extracted_entity` is now written to, closing the last piece of `PENDING_ACTIONS.md` #4

Branched from `claude/rls-app-role-and-migration-fix` (PR #11, not yet merged) rather than `main`,
since this work needs that branch's migration runner to actually apply its own new migration and get
tested against a real database. Continuing straight off the previous entry: with the migration runner
built, `extracted_entity`/`news_record`/`social_mention` stopped being "landed but not deployable" —
this closes the remaining gap, actually writing extraction results somewhere.

**New migration** `20260808040000_add_extraction_status.sql`: adds `extraction_status VARCHAR(50)
DEFAULT 'Pending'` to `news_record` and `social_mention`, mirroring `rag_documents_metadata.processed_status`'s
existing convention. Needed because a plain `LEFT JOIN extracted_entity` can't tell "not yet
processed" apart from "processed, genuinely zero entities found" for a given row.

**`ExtractedEntity` gained a `confidence` field** — `None` for regex/rule matches (deterministic, not
probabilistic), populated with the fuzzy-match similarity score for `catalog_matching.py`'s
PRODUCT/COMPETITOR matches. `extracted_entity.confidence_score` is nullable specifically for this
reason.

**`extraction/data_access.py`** gained `load_pending_news_records()`/`load_pending_social_mentions()`
(same "join against the result table, filter unprocessed" shape `sentiment/data_access.py` already
established, but via an explicit status column instead of a join, for the reason above) and
`mark_news_record_status()`/`mark_social_mention_status()`.

**`extraction/evidence.py`** (new): `insert_extracted_entities()` writes to `extracted_entity`, this
track's own table — `entity_value` is the catalog-normalized name when one exists, otherwise the raw
matched text.

**`extraction/pipeline.py`** (new): `extract_and_store_news_records()`/`extract_and_store_social_mentions()`
orchestrate load → extract → persist → mark Processed/Failed, mirroring `rag/pipeline.py`'s
`ingest_pending_documents()` convention (spec §12: never silently discard invalid data). Deliberately
writes no `evidence_records` — bulk entity extraction is an annotation step over raw text, not itself
a user-facing conclusion, same reasoning `sentiment/pipeline.py`'s `classify_and_store_reviews()`
already documents for bulk sentiment labeling. No event contract exists yet for triggering this (same
situation as `sentiment/`), so it's called directly rather than via a Redis consumer.

**Testing**: 5 new offline tests (mocked connection, covering both entry points' persist-and-mark and
mark-Failed-on-error paths) plus 6 new live-DB integration tests, run against a genuinely fresh
disposable Postgres with the full schema applied via the migration runner (first real proof this new
migration composes correctly with the other 6). The end-to-end tests seed a real `news_record`/
`social_mention` row referencing the seeded tenant's own product/competitor names, run the real
pipeline function against the real database, and confirm: the right entity types land in
`extracted_entity` (including `PRODUCT`/`COMPETITOR` catalog matches actually resolving, not just the
regex-shaped ones), the source row's `extraction_status` flips to `Processed`, and a second run
doesn't reprocess it. One test-writing bug caught and fixed along the way: a literal `%` character in
a hardcoded test SQL string (`"20% off"`) collided with psycopg2's `%s` placeholder syntax
(`IndexError: tuple index out of range`) — fixed by parameterizing the text instead of inlining it.
Full offline suite re-run afterward: 157 passed (up from 152), 0 failed. `flake8`/`py_compile` clean.

**Not done, deliberately**: no event contract/consumer for triggering extraction (mirrors `sentiment/`'s
same open state); ORG/PERSON/GPE/ADDRESS entity types remain out of scope (need world knowledge or a
trained model). `PENDING_ACTIONS.md` #4 updated to reflect persistence, not just deployability.

## How to add an entry

1. New date-stamped `##` section at the bottom (never edit history).
2. State what was built/changed, what testing was done, and what it found.
3. Update the Module status table above to match.
4. If it closes or reopens an item in `AI_PLAN_AND_CONTRACT_UPDATES.md`, say so there too, in that
   file's own dated-entry convention.
