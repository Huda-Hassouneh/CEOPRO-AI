# CEOPRO AI — AI/ML Service (`src/ai/`)

Owned by the AI/ML engineering track. Scope is limited to what this team owns per
[`src/infrastructure/DATA_OWNERSHIP_AND_CONTRACTS.md`](../infrastructure/DATA_OWNERSHIP_AND_CONTRACTS.md):
reading business data written by other services, producing ML model outputs, and writing to the
tables this track owns (`demand_forecasts`, `evidence_records`, `model_versions`,
`recommendation_outcomes`, `sentiment_results`).

This directory intentionally does **not** touch:
- `docker-compose.yml` / any `Dockerfile.*` — infra owns container/deployment wiring.
- `src/infrastructure/database/init_schema.sql` — schema changes are infra/DB's call.
- Frontend/dashboard code — UI team's responsibility.

Dependencies for this module are isolated in [`requirements.txt`](requirements.txt) so they don't
get bundled into the backend's dependency set.

## Modules

### `forecasting/` — Phase 2, Demand Intelligence (spec §18, §23, §25)

Implements per-product daily demand forecasting against the existing `transactions` /
`products` / `demand_forecasts` / `evidence_records` / `model_versions` tables — no schema
changes required.

- `data_access.py` — reads daily aggregated demand history and product/inventory context from Postgres.
- `features.py` — builds lag/rolling/calendar features from the daily series.
- `baselines.py` — naive, seasonal-naive, and moving-average forecasts (spec §18: the model must beat these).
- `model.py` — XGBoost forecaster + expanding-window walk-forward validation.
- `evaluation.py` — MAE / RMSE / MASE, and baseline-comparison logic.
- `cold_start.py` — data-sufficiency check (spec §23 unified cold-start policy). Below the
  configured history threshold, the pipeline stays on baseline forecasts and reports low confidence
  instead of training/serving an XGBoost model.
- `evidence.py` — writes `demand_forecasts` + `evidence_records` (category `PREDICTION`) rows, and a
  `model_versions` row whenever a model is actually trained.
- `pipeline.py` — orchestrates the above: load → cold-start check → baseline (+ XGBoost if enough
  data) → pick whichever beats the baseline → persist.
- `consumer.py` — Redis Streams consumer for the `demand_forecast_requested` event contract
  (topic key `ceopro:stream:demand_forecast_requested`, provisioned by
  `src/infrastructure/init_broker.py`). This is the "AI / ML Forecast Engine" consumer named in the
  event contract in `DATA_OWNERSHIP_AND_CONTRACTS.md` — it does not touch or replace
  `src/infrastructure/messaging/ai_consumer.py`, which is a separate, still-unresolved ownership
  question (market-intelligence stream, not demand forecasting).

Runs CPU-only by design — no GPU dependency anywhere in this module.

### `pricing/` — Phase 5, Price Intelligence (spec §9, §19, §23, §24)

Implements competitor price comparison against the existing `products` / `competitors` /
`competitor_prices` / `currency_rates` / `evidence_records` / `recommendation_outcomes` tables — no
schema changes required.

- `matching.py` — name-similarity matching (`difflib`) between our `products.product_name` and
  `competitor_prices.product_name_captured` (free text, no FK between them).
- `data_access.py` — reads own product price/currency, same-currency competitor prices (the
  recommendation-driving set), and separately, cross-currency competitor prices (reference only —
  see `pipeline.py` below). All filtered to `ALLOWED`-source, exact, fresh (default 30-day window),
  and the competitor being currently active.
- `currency.py` — spec §9's traceability requirements: every conversion carries its original
  amount/currency alongside the converted figure, plus the rate, its date, and its source. Returns
  `None` rather than guessing when no rate is available ("the system must explicitly indicate that
  conversion cannot be verified") — doesn't invert rates (e.g. use a stored JOD→SAR rate to serve a
  SAR→JOD request), since that's an inference about `currency_rates`' data this module isn't in a
  position to make.
- `recommendation.py` — transparent rule-based raise/lower/hold recommendation vs. the matched
  **same-currency** competitors' market average only. Not a learned model — spec §19 requires enough
  price-change history to exist first, and there isn't any yet.
- `guardrails.py` — bounds how far a suggested price can move from the current price (default 15%).
  **Not** a margin guardrail — `products` has no cost column (see blockers below).
- `evidence.py` — reuses `forecasting.evidence.insert_evidence_record` (spec §22: one shared evidence
  architecture, not reimplemented per module) and adds `insert_recommendation_outcome`.
- `pipeline.py` — orchestrates: load own product → load same-currency competitor prices → match by
  name → no matches: `UNKNOWN` evidence (cold-start) → matches: recommendation → guardrail → persist.
  Cross-currency matches, when any exist and convert successfully, get appended to the evidence
  explanation as a clearly-labeled **reference-only** note — spec §19: "The system must NOT use a
  simple currency conversion as the only basis for a cross-country pricing recommendation," so
  cross-currency data is never blended into `recommendation.py`'s market-average math, only surfaced
  as context.

Same-currency comparison is spec §19's "LOCAL MARKET COMPARISON." Cross-currency reference is a
first step toward "CROSS-COUNTRY COMPARISON," but not the full thing — spec §19 also asks for
purchasing power, local taxes, import costs, and shipping to be accounted for, none of which is
modeled here; a converted price is shown as context, not treated as an equivalent competitor. CPU-only,
no ML model at all — purely rule-based per spec's explicit cold-start requirement for pricing.

### `rag/` — Phase 3 groundwork, retrieval only (spec §4, §6, §21)

Implements document ingestion and hybrid (lexical + semantic) retrieval against the existing
`rag_documents_metadata` table and the `ceopro-rag-knowledge` MinIO bucket — no schema changes.
**Not** the full RAG chatbot: no LLM reasoning step, no chat history persistence (would need a new
table). CPU-only throughout — the embedding model is small (~470MB, "light-medium" tier), nothing
here approaches LLM-scale compute.

- `chunking.py` — word-boundary overlapping-window text chunking. Works for Arabic and English alike
  (no language-specific tokenizer, spec §8's Arabic-English code-switching requirement).
- `bm25_index.py` — in-memory lexical index (`rank_bm25`, pure Python, no ML model). Uses **BM25Plus**,
  not the more common BM25Okapi — see the note in the file: Okapi's IDF formula is exactly zero for
  any term appearing in precisely half a small corpus, which silently zeroed out obvious matches for
  tenants with only 2-3 documents (a realistic cold-start state). Found via the live-MinIO
  integration test, not by code review.
- `embeddings.py` — multilingual sentence embeddings (`sentence-transformers/paraphrase-multilingual-MiniLM-L12-v2`,
  configurable via `RAG_EMBEDDING_MODEL`). CPU inference, ~470MB one-time download (cached locally
  after). Confirmed manually: ~140s first download, ~20-30s to load a fresh process even once cached
  (still checks the HF Hub), fast for repeat calls within one process (module-level model cache).
- `faiss_index.py` — semantic retrieval index (`faiss-cpu`, exact flat search — corpus sizes here
  don't warrant an approximate index). Embeddings are L2-normalized, so inner product = cosine
  similarity.
- `hybrid_retrieval.py` — Reciprocal Rank Fusion combining BM25 + FAISS rankings, unweighted (no
  training/tuning, matching this module's rule-based approach elsewhere). **A real limitation found
  during testing, not fixed**: with very short chunks (single sentences, 10-13 tokens) and a query
  with only one genuine keyword match, BM25's document-length normalization can outrank a document
  with zero real matches over one with a real match — and unweighted RRF doesn't reliably correct for
  it when BM25 and FAISS disagree on which of only 2-3 candidates is "best" (see the note in
  `test_rag_integration.py` for the specific case this showed up in). Works correctly and reliably
  when either retriever alone would already find the right answer, or when BM25 finds literally no
  matches for anything (letting FAISS's ranking pass through unweighted) — the fragile case is
  specifically "BM25 and FAISS disagree between few very short candidates."
- `data_access.py` — reads/updates `rag_documents_metadata`, fetches raw MinIO object bytes. Handles
  plain-text (`.txt`) content only — PDF/DOCX extraction isn't implemented (flagged in
  `PENDING_ACTIONS.md`).
- `pipeline.py` — `ingest_pending_documents()` (fetch → chunk-check → mark Processed/Failed, never
  silently drops a document per spec §12); `build_tenant_index()`/`retrieve()` for BM25-only (no
  embedding model needed); `build_hybrid_index()`/`retrieve_hybrid()` for the full lexical+semantic
  pipeline. Since there's no `knowledge_chunks` table, nothing is persisted between calls — chunks
  and embeddings are recomputed from MinIO on every call. That's correct but doesn't scale, which is
  itself a concrete argument for the pgvector ask in `PENDING_ACTIONS.md` #1, not just a workaround
  for its absence.

### `sentiment/` — Phase 4 groundwork, multilingual sentiment analysis (spec §16, §23)

Implements per-review sentiment classification and per-subject aggregation against the existing
`reviews` / `sentiment_results` / `evidence_records` tables — no schema changes required.

- `model.py` — wraps `cardiffnlp/twitter-xlm-roberta-base-sentiment`, a pretrained XLM-RoBERTa-based
  3-class (positive/neutral/negative) classifier — spec §16's stated model choice, covering Arabic,
  English, and mixed content with no per-language routing. Deliberately reads the label vocabulary
  from the model's own `config.id2label` instead of assuming a fixed index order — confirmed by
  testing that this specific model's actual order (`{0: 'negative', 1: 'neutral', 2: 'positive'}`)
  isn't the naive alphabetical guess, and the project has already been bitten once this track by an
  ordering assumption (the NER regex alternation-order bug). CPU-only, batched (`SENTIMENT_BATCH_SIZE`,
  default 16). Confirmed manually on real Arabic and English reviews (see `test_sentiment_model_real.py`):
  correctly classifies clear positive/negative/neutral cases in both languages.
- `data_access.py` — reads unanalyzed `reviews` (ALLOWED-source, non-empty text only — spec §13's
  Collection Policy Engine), and aggregates already-analyzed `sentiment_results` per subject
  (product/competitor/business-overall), including the continuous sentiment score spec §16 allows
  (`avg(positive_probability) − avg(negative_probability)`, count-weighted across labels).
- `cold_start.py` — spec §16's sample-size policy: "If a country has insufficient review data, the
  system must display LOW SAMPLE SIZE" / "must not present a statistically weak result as a reliable
  market conclusion." Applied per-subject (`SENTIMENT_MIN_SAMPLE_SIZE`, default 10) rather than
  strictly per-country, since `reviews` has no country column — see the note in the file.
- `evidence.py` — writes `sentiment_results` rows and `evidence_records` (category `FACT`, or
  `UNKNOWN` when a subject has zero analyzed reviews yet).
- `pipeline.py` — two entry points, deliberately not one: `classify_and_store_reviews()` runs the
  classifier over a tenant's unanalyzed reviews and writes raw `sentiment_results` rows (bulk
  labeling, not itself a user-facing conclusion, so it writes no evidence — mirrors how
  `rag/embeddings.py`'s embedding step is infrastructure, not evidence-bearing); `get_subject_sentiment_summary()`
  aggregates already-analyzed sentiment for one subject, applies the LOW SAMPLE SIZE policy, and is
  the only function here that writes to `evidence_records`.

No event contract exists yet for triggering sentiment analysis (no `ceopro:stream:*` topic
provisioned for it in `src/infrastructure/init_broker.py`), so — like `pricing/` — this is called
directly rather than via a Redis consumer; add a `consumer.py` once such a contract is agreed, the
same way `forecasting/consumer.py` was added for `demand_forecast_requested`.

### `mpi/` — Phase 4, Market Perception Index (spec §17, §22, §23)

Implements the MPI directly on top of `sentiment/`'s output — no schema changes, no dedicated MPI
table (checked: there isn't one in `init_schema.sql`), results are written purely to
`evidence_records` per spec §22's shared evidence architecture.

- `scoring.py` — pure functions, no DB access, fully unit-testable in isolation. Combines spec §17's
  five required components (sentiment, source reliability, recency, volume, entity relevance) into a
  single 0-100 index: each already-analyzed review contributes `sentiment_score × recency_weight ×
  reliability_weight × relevance_weight`, averaged across all contributing reviews, then dampened
  toward the neutral midpoint (50) by a volume-confidence factor that saturates at
  `MPI_MIN_VOLUME_FOR_FULL_CONFIDENCE` (default 20) — a single strongly-worded review can't swing the
  index to 100 the way it could a raw average. Recency uses exponential decay (`MPI_RECENCY_HALF_LIFE_DAYS`,
  default 90); source reliability ranks `PUBLIC_API` > `PUBLIC_FEED` > `MANUAL`, reflecting spec §13's
  stated preference for official/structured sources over scraping/manual entry, quantified rather than
  left as an unweighted principle. Entity relevance defaults to 1.0 for every review (already explicitly
  linked to its subject via `reviews.subject_type`/`product_id`/`competitor_id`, not fuzzy-matched) —
  a continuous relevance score is a natural future refinement once `extraction/`'s NER output has
  somewhere to persist to (`PENDING_ACTIONS.md` #4).
- `compare_mpi_results()` (in `scoring.py`) — spec §17: "must support cross-country analysis only when
  the comparison is statistically and economically meaningful" and "must not blindly compare raw
  sentiment volume between countries with radically different market sizes." Refuses to return a
  numeric difference at all — not a low-confidence one, none — when either side is under a volume
  floor, rather than diluting a well-sampled subject's real signal with a near-noise comparison.
- `cold_start.py` — the discrete LOW SAMPLE SIZE status label (spec §16/§23's pattern, reused here)
  layered on top of `scoring.py`'s continuous volume dampening — the dashboard needs both: a score
  that degrades gracefully *and* an explicit flag for "don't trust this yet."
- `data_access.py` — row-level reads (unlike `sentiment/data_access.py`'s pre-aggregated view), since
  the MPI needs each review's own date/collection_method to compute per-review weights. Supports
  BUSINESS/PRODUCT/COMPETITOR levels, matching `reviews.subject_type`'s own three-way taxonomy exactly.
  CATEGORY/COUNTRY/REGION-level aggregation (also named in spec §17) would need grouping through
  `products.category`/`competitors.country_code` — a natural extension, not built this round.
- `pipeline.py` — `get_subject_mpi()` computes and persists one subject's MPI as an `evidence_records`
  `FACT` (or `UNKNOWN` if no analyzed reviews exist yet), preserving every component's individual
  contribution in `source_record_ids` (spec §17: "the system must preserve the underlying
  contributions" so a dashboard can answer "why did the MPI change"), not just the final number.
  `compare_subjects()` computes two subjects' MPIs in-memory and applies the cross-country guard above.

### `extraction/` — Phase 4 groundwork, rule-based NER (spec §15)

Implements the regex/rule tier of information extraction — spec §15's own explicitly-sanctioned
low-resource option ("NER may use: ... EntityRuler. Regex patterns. Fuzzy matching. Domain-specific
rules."), not a pretrained transformer. No trained model, no GPU, the lightest possible NER tier.

- `regex_patterns.py` — MONEY, CURRENCY, PERCENT, DISCOUNT, EMAIL, PHONE, INVOICE_ID, ORDER_ID, DATE.
  Currency codes are configuration-driven (spec §9), defaulting to spec's own list (JOD, EGP, SAR,
  AED, QAR, KWD, BHD, OMR, MAD, TND, DZD, USD, EUR, ZAR).
- `catalog_matching.py` — PRODUCT/COMPETITOR entity types, matched against a tenant's own known
  names rather than pattern-extracted (there's no regular pattern for a product name). Reuses
  `pricing.matching.similarity()` directly rather than a second fuzzy-matching implementation.
- `data_access.py` — reads known product/competitor names from the existing `products`/`competitors`
  tables. Nothing is written — there's no `extracted_entity` table yet (`PENDING_ACTIONS.md` #4), so
  this produces a result list with nowhere to persist to until that table exists.
- `extractor.py` — combines both into one call.

Out of scope here: ORG, PERSON, GPE, ADDRESS (spec §15's other target types) — these need world
knowledge or a trained model to extract reliably; regex/catalog-matching can't do them justice.

### Known upstream blockers (not fixed here — flagged in [`PENDING_ACTIONS.md`](../../PENDING_ACTIONS.md))

- No real transaction volume yet (`mocks/sales_transactions_mock.csv` has 3 rows) — `forecasting/`'s
  cold-start path is exercised by default until real data lands.
- No real competitor price data or scraper running — `competitor_prices` exists but is empty, so
  `pricing/`'s `UNKNOWN`-evidence path is what actually executes today.
- No real review data yet — `reviews` exists but is empty (same "table landed, no producer feeding it
  yet" situation as `competitor_prices`), so `sentiment/`'s `UNKNOWN`-evidence path is what actually
  executes today until a review-collection service starts writing to it.
- `model_versions` has no `artifact_path` column yet, so trained model binaries aren't persisted to
  MinIO (`ceopro-ai-artifacts`) in this first version — metrics/version metadata are still recorded
  in `model_versions` on every training run. Wiring artifact storage is a follow-up once that column
  exists.
- `products` has no `cost` column, so `pricing/guardrails.py` can only bound price-change magnitude,
  not enforce a real margin floor as spec §19 also asks for.
- `currency_rates` table landed and is now wired into `pricing/currency.py` — no longer blocked.
- pgvector's *schema* (extension + `rag_document_chunks`) landed, but `docker-compose.yml`'s
  `postgres` image tag is invalid (doesn't exist on Docker Hub) — not actually deployable yet
  (`PENDING_ACTIONS.md` #1/#17).
- Row-Level Security policies exist and are enabled, but currently provide no real protection — the
  app connects as the table-owner role, which Postgres exempts from RLS by default; confirmed with a
  direct test (`PENDING_ACTIONS.md` #2).
- `rag/data_access.py` decodes MinIO objects as plain UTF-8 text only — PDF/DOCX documents (which
  `MINIO_STORAGE_ARCHITECTURE.md` explicitly expects in `ceopro-rag-knowledge`) aren't extracted.
- No chat-history table exists, so RAG conversation persistence isn't implemented.
- No `extracted_entity` table exists, so `extraction/`'s output has nowhere to persist to yet —
  `extractor.py` is called directly and its result used in-memory, not written anywhere.

## Running tests

Tested against Python 3.11 (matching `Dockerfile.backend`'s target) in a clean venv — not just the
system interpreter, since dependency pins here (numpy/xgboost) don't have wheels for every Python
version. `pip install -r src/ai/requirements.txt` on anything newer than 3.11/3.12 may fail to build
numpy from source; use a 3.11 interpreter if that happens.

Pure-function modules (`baselines`, `evaluation`, `features`, `cold_start`) plus `model.py` and
`pipeline.py` (DB calls mocked out) run without a live database:

```bash
pip install -r src/ai/requirements.txt
pytest src/ai/tests
```

`test_integration_db.py` (forecasting), `test_pricing_integration_db.py` (pricing),
`test_extraction_integration_db.py` (extraction), `test_sentiment_integration_db.py` (sentiment), and
`test_mpi_integration_db.py` (MPI) additionally validate the raw SQL in each module's
`data_access.py`/`evidence.py` against a real PostgreSQL instance running the actual
`init_schema.sql` — column types, JSONB casts, FK constraints, and INT rounding on
`demand_forecasts.expected_demand` are things a mocked connection can't catch. All are
skipped unless `AI_TEST_DATABASE_URL` is set, so none ever run in CI or block anyone without
Docker available. Point it at a disposable database — the tests insert and roll back rows, but don't
aim it at a shared dev database:

```bash
docker run -d --name ceopro_postgres_aitest -e POSTGRES_USER=ceopro_admin \
  -e POSTGRES_PASSWORD=local_test_password_only -e POSTGRES_DB=ceopro_platform \
  -p 5433:5432 postgres:15-alpine
psql "postgresql://ceopro_admin:local_test_password_only@localhost:5433/ceopro_platform" \
  -f src/infrastructure/database/init_schema.sql
AI_TEST_DATABASE_URL="postgresql://ceopro_admin:local_test_password_only@localhost:5433/ceopro_platform" \
  pytest src/ai/tests
docker rm -f ceopro_postgres_aitest
```

`test_consumer.py` covers `ForecastRequestConsumer` (payload validation, and the same
publish/xreadgroup/handle/xack cycle `listen()` uses) against a real Redis — constructing the
consumer calls `xgroup_create` eagerly, so a mocked client can't stand in for this one. Skipped
unless `AI_TEST_REDIS_HOST` is set:

```bash
docker run -d --name ceopro_redis_aitest -p 6380:6379 redis:7-alpine
AI_TEST_REDIS_HOST=localhost AI_TEST_REDIS_PORT=6380 pytest src/ai/tests/test_consumer.py
docker rm -f ceopro_redis_aitest
```

`test_rag_integration.py` covers `rag/data_access.py` and `rag/pipeline.py` against real Postgres
*and* real MinIO together — skipped unless both `AI_TEST_DATABASE_URL` and `AI_TEST_MINIO_ENDPOINT`
are set:

```bash
docker run -d --name ceopro_minio_aitest -p 9002:9000 \
  -e MINIO_ROOT_USER=minio_admin -e MINIO_ROOT_PASSWORD=local_test_password_only \
  minio/minio server /data
# ... plus the disposable postgres container from above, with its schema loaded ...
AI_TEST_DATABASE_URL="postgresql://ceopro_admin:local_test_password_only@localhost:5433/ceopro_platform" \
AI_TEST_MINIO_ENDPOINT="localhost:9002" \
  pytest src/ai/tests/test_rag_integration.py
docker rm -f ceopro_minio_aitest
```

`test_rag_embeddings.py` and the hybrid-retrieval test in `test_rag_integration.py` additionally
need `AI_TEST_EMBEDDINGS=1` — they download/load the real ~470MB embedding model (network access
required, ~140s first time, ~20-30s per fresh process even cached). Not required for the rest of the
suite, including the BM25-only RAG tests:

```bash
AI_TEST_EMBEDDINGS=1 pytest src/ai/tests/test_rag_embeddings.py
# or combined with the Postgres+MinIO setup above, for the hybrid-retrieval integration test:
AI_TEST_DATABASE_URL="postgresql://ceopro_admin:local_test_password_only@localhost:5433/ceopro_platform" \
AI_TEST_MINIO_ENDPOINT="localhost:9002" \
AI_TEST_EMBEDDINGS=1 \
  pytest src/ai/tests/test_rag_integration.py
```

`test_sentiment_model_real.py` needs `AI_TEST_SENTIMENT=1` — it downloads/loads the real ~1.1GB
sentiment classifier (network access required, ~30s once cached). `test_sentiment_integration_db.py`
only needs `AI_TEST_DATABASE_URL` (it patches `model.classify` with a deterministic fake, since the
real model's own correctness is what `test_sentiment_model_real.py` already covers):

```bash
AI_TEST_SENTIMENT=1 pytest src/ai/tests/test_sentiment_model_real.py
AI_TEST_DATABASE_URL="postgresql://ceopro_admin:local_test_password_only@localhost:5433/ceopro_platform" \
  pytest src/ai/tests/test_sentiment_integration_db.py
```

See [`AI_PROGRESS.md`](../../AI_PROGRESS.md) at the repo root for the dated log of what's been built,
what tests found, and what's still blocked. Items that need action from another team or a human
outside this track are tracked separately in [`PENDING_ACTIONS.md`](../../PENDING_ACTIONS.md).
