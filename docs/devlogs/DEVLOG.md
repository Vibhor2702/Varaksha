# Varaksha — Development Log

> Written March 10–11, 2026. Records every architectural decision, rebuild rationale,
> layer-by-layer implementation note, and current open items for the test branch.

---

## Table of Contents

- [Why V2 Exists](#why-v2-exists)
- [Timeline](#timeline)
  - [Phase 0 — V1 Audit & Decision to Rebuild](#phase-0--v1-audit--decision-to-rebuild)
  - [Phase 1 — Layer 1: Local Fraud Engine](#phase-1--layer-1-local-fraud-engine)
  - [Phase 2 — Layer 2: Rust Gateway Stub](#phase-2--layer-2-rust-gateway-stub)
  - [Phase 3 — Layer 3: Graph Agent](#phase-3--layer-3-graph-agent)
  - [Phase 4 — Layer 4: Accessible Alert Agent](#phase-4--layer-4-accessible-alert-agent)
  - [Phase 5 — Layer 5: Streamlit Demo Dashboard](#phase-5--layer-5-streamlit-demo-dashboard)
  - [Phase 6 — ML Pipeline Overhaul: RF-Only + 5 Datasets](#phase-6--ml-pipeline-overhaul-rf-only--5-datasets)
  - [Phase 7 — Frontend Dashboard: Next.js 15](#phase-7--frontend-dashboard-nextjs-15)
  - [Phase 8 — Dataset Audit + Retrain on 111K Rows](#phase-8--dataset-audit--retrain-on-111k-rows)
  - [Phase 9 — UI Polish: Textures, Colour Tokens, Live Page](#phase-9--ui-polish-textures-colour-tokens-live-page)
- [Directory Map](#directory-map)
- [Architecture Deep-Dive](#architecture-deep-dive)
  - [Why Five Separate Layers?](#why-five-separate-layers)
  - [Why Rust for the Gateway?](#why-rust-for-the-gateway)
  - [Risk Cache Design](#risk-cache-design)
  - [Graph Typologies](#graph-typologies)
  - [Accessible Alert Design](#accessible-alert-design)
  - [ML Stack Rationale](#ml-stack-rationale)
- [Open Items — Rust Teammate Checklist](#open-items--rust-teammate-checklist)
- [Datasets Used](#datasets-used)
- [Honest Caveats](#honest-caveats)

---

## Why V2 Exists

V1 (committed on `main`) was a full working system: PyO3 Rust-Python bridge,
GATE-M OS-level security monitor, SLSA supply-chain verification, Ed25519 message
signing between agents. It compiled and passed tests.

The problem: **V1 was too deep into security research and too far from a legible
demo**. A judge running `demo.py` for the first time would hit PyO3 build
dependencies, a GATE-M kernel module, and a six-agent LangGraph pipeline before
seeing a single scored transaction. The barrier was too high.

V2 takes the opposite stance:

- **Three Python scripts runnable with `pip install -r requirements.txt`** — no
  native build, no kernel module, no API keys.
- **Rust gateway kept as a clearly-labelled stub** with a teammate implementation
  checklist, so the Rust layer can be filled in independently without blocking
  the Python demo.
- **One `streamlit run` command shows a live risk feed** with coloured verdict
  badges, a Plotly network graph, and a text narration.

The V1 codebase is preserved on `main` and documented in its own devlog
(`docs/devlogs/DEVLOG.md` on `main`).

---

## Timeline

### Phase 0 — V1 Audit & Decision to Rebuild

Reviewed V1 test results:

- Rust gateway: 3/3 arena tests PASS (rate-limit, ML evasion, graph ring)
- Python pipeline: full end-to-end scoring functional
- Demo friction: 12-step setup, PyO3 compilation required, GATE-M Linux-only

Decision: branch `test`, clean slate, five focused layers with clear interfaces
between them. V1 artefacts removed from `test` branch to avoid confusion.

Removed from `test`:
- `gateway/rust-core/` (full PyO3 gateway)
- `security/gate-m/` (kernel monitor)
- `scripts/` (adversarial scan, legal report)
- All V1 HTML pitch/flow files from `docs/`

---

### Phase 1 — Layer 1: Local Fraud Engine

**File:** `services/local_engine/train_ensemble.py`

The ML training script satisfies every hackathon evaluation criterion:

| Criterion | Implementation |
|-----------|---------------|
| Anomaly detection | `IsolationForest` (contamination=0.02) |
| Ensemble methods | `VotingClassifier` wrapping RF + XGBoost (soft vote) |
| Imbalanced dataset | `SMOTE` (imblearn) before train split |
| Feature engineering | 8 derived features: velocity, round-amount flag, out-degree, hour-of-day |
| Model persistence | `joblib.dump` → `data/models/` |

**Training path resolution:** The script auto-detects which dataset is available
and falls back through three sources in order:
1. `data/datasets/Untitled spreadsheet - upi_transactions.csv` (local synthetic)
2. `data/datasets/PS_20174392719_1491204439457_log.csv` (PaySim 6.36 M rows)
3. Synthetic generation via `numpy` if neither is present (hackathon offline mode)

**Why VotingClassifier instead of stacking?** Stacking requires a meta-learner
trained on out-of-fold predictions — that's an extra training pass and doubles
memory pressure on a free-tier machine. Soft voting with equal weights is
simpler, interpretable, and generalises comparably on tabular fraud data per the
PaySim benchmark paper (López-Rojas et al., 2016).

---

### Phase 2 — Layer 2: Rust Gateway Stub

**Files:** `gateway/src/main.rs`, `gateway/src/cache.rs`, `gateway/src/models.rs`

The gateway is an **Actix-Web 4** server on port `8082`. The structure is fully
scaffolded:

- All types defined in `models.rs` (`TxRequest`, `TxResponse`, `CacheUpdateRequest`, `Verdict`)
- `RiskCache` struct skeleton in `cache.rs` with `DashMap` field declared
- Three endpoints wired in `main.rs`: `GET /health`, `POST /v1/tx`, `POST /v1/webhook/update_cache`
- `hash_vpa()` helper (SHA-256 of raw VPA) implemented and used in the handler
- `score_to_verdict()` threshold logic implemented

**What is stubbed (TODO for Rust teammate):**
- `RiskCache::get()` — always returns `(0.0, "no cache entry")`
- `RiskCache::upsert()` — no-op
- HMAC-SHA256 verification on `update_cache` — skipped, always 200

All TODO items are inline-commented in the source with exact steps. The server
compiles and responds to all three endpoints — the stub behaviour is safe for
demo use (all transactions return `ALLOW` until the cache is populated).

**Why DashMap?** Lock-free concurrent hashmap with `Arc<DashMap>` shared across
Actix worker threads. At the expected demo load (< 100 RPS) a `Mutex<HashMap>`
would be fine, but DashMap is the idiomatic choice for a production gateway and
signals intent to reviewers.

---

### Phase 3 — Layer 3: Graph Agent

**File:** `services/graph/graph_agent.py`

Runs **out of the payment hot path** — it builds a transaction graph in memory
and pushes risk scores to the Rust cache via the webhook. This means a
slow graph computation never blocks a `/v1/tx` response.

**Typologies detected** (following BIS Project Hertha taxonomy):

| Typology | Detection method | Risk delta |
|----------|-----------------|------------|
| Fan-out | out-degree > threshold from single source | +0.35 |
| Fan-in | in-degree > threshold on single destination | +0.30 |
| Cycle | `nx.simple_cycles` on directed subgraph | +0.50 |
| Scatter | out-degree > 2× in-degree, high total degree | +0.20 |

Scores are clipped to `[0.0, 1.0]` after accumulation. The score pushed to
the Rust cache is the **max** across all detected typologies for a given VPA
hash, not a sum — summing caused false-flagging on high-volume but legitimate
merchants in testing.

**Webhook auth:** The graph agent signs each update with HMAC-SHA256 using
`WEBHOOK_SECRET`. The Rust gateway stub currently skips verification (TODO), but
the Python side always sends a valid signature so integration is drop-in once
the Rust side implements `verify_slice`.

---

### Phase 4 — Layer 4: Accessible Alert Agent

**File:** `services/agents/agent03_accessible_alert.py`

Handles the **last-mile communication** requirement: a flagged transaction
should reach the account holder in their language, not just log a JSON verdict.

**What it does:**

1. Takes a `TxResponse` JSON from the gateway
2. Generates a Hindi narration template via string interpolation (no LLM
   dependency — narration quality is deterministic and auditable)
3. Optionally translates to the user's preferred language via `googletrans` if
   available
4. Optionally synthesises speech via `edge-tts` (Microsoft TTS, free tier) if
   available
5. Cites the relevant Indian legal statute (IT Act 2000 §66D for cheating by
   personation using a computer resource, BNS §318(4) for cheating offences)

**Graceful degradation:** Every optional dependency (`googletrans`, `edge-tts`,
`lime`) is wrapped in a try/except import. The agent works on base Python +
`requests` alone — it falls back to a printed narration string.

**Why not a real NMT model?** A full Bhashini API integration requires a
government API key and 200–500 ms per translation call. The hackathon judges
need a working demo in < 30 s. googletrans covers the same 22 Indian scheduled
languages synchronously with zero credentials.

---

### Phase 5 — Layer 5: Streamlit Demo Dashboard

**File:** `services/demo/app.py`

Single-file Streamlit dashboard. Run with:

```bash
streamlit run services/demo/app.py
```

**Panels:**

| Panel | Contents |
|-------|----------|
| Risk Feed | Live auto-refreshing table of synthetic transactions with verdict badges (ALLOW / FLAG / BLOCK) |
| Transaction Network | Plotly Scattergl force-directed graph, edges coloured by risk tier |
| Accessible Alert | Hindi narration + English translation for the most recent flagged transaction |
| Audit Log | Expandable JSON of last 50 scored transactions |

**No real PII is used.** All transactions are generated from a seeded RNG.
VPA strings are synthetic (`user_XXXX@okicici`, `merchant_XXXX@paytm`).

### Phase 6 — ML Pipeline Overhaul: RF-Only + 5 Datasets

**Files:** `services/local_engine/train_ensemble.py`, `services/local_engine/infer.py`

The original Phase 1 ML stack was rebuilt to address two constraints that appeared
after the initial commit:

1. **Memory budget**: The free-tier deployment target (512 MB RAM) cannot host
   both RandomForest and XGBoost simultaneously at inference time. XGBoost was
   dropped; RF-300 alone provides the same recall with a smaller ONNX footprint.
2. **Data quality**: The previous fallback chain (UPI CSV → PaySim → synthetic)
   used at most ~5 K rows. Five real datasets were integrated to reach 75 K rows
   and reduce reliance on synthetic oversampling.

#### Changes to `train_ensemble.py`

| Item | Before | After |
|---|---|---|
| Classifiers | `VotingClassifier(RF + XGB)` | `RandomForestClassifier(n_estimators=300)` |
| Feature count | 8 | **16** |
| Dataset loaders | 2 (PaySim, UPI CSV) | **7 loaders** (PaySim, UPI CSV, MomTSim, Digital Payment, USA Banking, Customer_DF joined, CDR Realtime Fraud) |
| ONNX output | `voting_ensemble.onnx` | `varaksha_rf_model.onnx` |
| Training rows | ~5,000 | **75,358** |

**4 new engineered features** added on top of the original 8:
- `balance_drain_ratio` — (oldbalanceOrg - newbalanceOrig) / (oldbalanceOrg + 1)
- `account_age_days` — days since first transaction for the sender VPA
- `previous_failed_attempts` — count of prior FLAG/BLOCK verdicts for the same sender
- `transfer_cashout_flag` — 1 if transaction type is TRANSFER or CASH_OUT

#### Training results

| Dataset | Rows | Fraud % |
|---|---|---|
| PaySim (stratified 50 K) | 50,000 | 16.4% |
| UPI Transactions | 647 | 24.0% |
| Customer_DF + cust_transaction_details (joined) | 168 | 36.3% |
| CDR Realtime Fraud | 24,543 | 50.2% |
| **Merged total** | **75,358** | **27.5%** |

| Metric | Value |
|---|---|
| RF Accuracy | **94.4%** |
| RF ROC-AUC | **0.9869** |
| Fraud Precision | 0.8996 |
| Fraud Recall | 0.8983 |
| Fraud F1 | **0.899** |

> ⚠ These results reflect the Phase 6 training run. See Phase 8 for the updated results after the full dataset audit.

#### Changes to `infer.py`

- `_xgb_sess` and `_XGB_ONNX` removed — inference now loads only `varaksha_rf_model.onnx`
- `_NUMERICAL` list expanded from 8 to **16 features** to match training schema
- Fallback synthetic-input generator updated to produce 16-element vectors
- Log line updated: `features=16 | iso=yes`

#### Why RF-only?

At the 75 K training scale, RF-300 achieves ROC-AUC 0.9869 — the marginal gain
from adding XGBoost in a voting ensemble is < 0.005 AUC on this dataset family.
Dropping XGBoost reduces the cold-start memory footprint from ~450 MB (RF + XGB
loaded simultaneously in onnxruntime) to ~130 MB, fitting comfortably in the
512 MB Render free tier.

---

### Phase 7 — Frontend Dashboard: Next.js 15

**Directory:** `frontend/`

A React/Next.js 15 web app was added as the public-facing interface for the
hackathon demo. It replaces the Streamlit dashboard for the web deployment tier
(Streamlit is retained for local introspection).

**Three pages:**

| Route | Contents |
|---|---|
| `/` | Landing — product pitch, risk tier badges, key stats |
| `/flow` | How-it-works — animated data-flow diagram through all 5 layers |
| `/live` | Live demo — synthetic transaction feed with real-time gateway scoring |

**Key technical decisions:**

- **All components are `"use client"`** — no server-side rendering, no API routes.
  Every page fetches data from the gateway directly from the browser.
- **`output: "export"` in `next.config.ts`** — produces a fully static `out/`
  directory. This is what enables deployment on Cloudflare Pages (no Node.js
  server required, no cold starts, free edge caching globally).
- **`images: { unoptimized: true }`** — required when `output: "export"` is set;
  Next.js image optimisation needs a server, which we don't have.

**Deployment target: Cloudflare Pages**

| Setting | Value |
|---|---|
| Build command | `npm run build` |
| Output directory | `out` |
| Root directory | `frontend` |
| Framework preset | Next.js (Static) |

Reason for preferring Cloudflare Pages over Vercel: Vercel free tier spins down
static projects after inactivity (cold start visible to demo judges). Cloudflare
Pages serves from edge PoPs with zero cold start, unlimited free requests, and
no sleep behaviour.

```
varaksha/
├── frontend/
│   ├── app/
│   │   ├── page.tsx               Landing page
│   │   ├── flow/page.tsx          How-it-works flow
│   │   └── live/page.tsx          Live transaction demo
│   └── next.config.ts             Static export for Cloudflare Pages
│
├── gateway/
│   ├── Cargo.toml                     Actix-Web 4 + DashMap + sha2 + uuid
│   └── src/
│       ├── main.rs                    HTTP server, endpoint handlers (stubs marked)
│       ├── cache.rs                   RiskCache (DashMap wrapper — stubs marked)
│       └── models.rs                  Serde types: TxRequest, TxResponse, Verdict
│
├── services/
│   ├── local_engine/
│   │   ├── train_ensemble.py          Layer 1 — ML training (RF-300 + IF + SMOTE, 16 features)
│   │   └── infer.py                   ONNX scoring engine
│   ├── graph/
│   │   └── graph_agent.py             Layer 3 — NetworkX mule-ring detection
│   ├── agents/
│   │   └── agent03_accessible_alert.py  Layer 4 — multilingual alert + law cite
│   └── demo/
│       └── app.py                     Layer 5 — Streamlit dashboard (local)
│
├── data/
│   ├── datasets/                      Training data (CSV, Parquet, JSON) — gitignored
│   └── models/                        ONNX model artefacts (.onnx) — committed
│
├── Cargo.toml                         Root Rust workspace (gateway + risk-cache)
├── docs/
│   └── devlogs/
│       └── DEVLOG.md                  ← this file
│
├── requirements.txt                   All Python dependencies
└── README.md                          Setup & run instructions
```

---

## Architecture Deep-Dive

### Why Five Separate Layers?

Each layer can be developed, tested, and replaced independently:

- Layer 1 (ML) can be retrained on new data without touching the gateway
- Layer 2 (Rust) can be filled in by a Rust developer without any Python knowledge
- Layer 3 (Graph) can upgrade typology logic without changing the webhook interface
- Layer 4 (Alert) can swap translation backends without touching the score pipeline
- Layer 5 (Demo) is purely a view layer — it reads output, never writes

The interfaces between layers are **plain JSON over HTTP**. No shared memory,
no message brokers, no compiled protocol buffers. This keeps the demo runnable
on a single laptop with no infrastructure.

---

### Why Rust for the Gateway?

The gateway is the single process that sees raw VPA strings (UPI IDs). It hashes
them immediately and nothing downstream ever sees the original. This is a
**privacy chokepoint** — it must:

1. Be fast enough to not add latency to the payment path (< 5 ms P99)
2. Be memory-safe to rule out buffer-overflow attacks on VPA inputs
3. Be the single source of truth for the risk cache (thread-safe concurrent reads)

Rust satisfies all three. A Python process behind `asyncio` could achieve the
latency target at demo load, but would require `multiprocessing.Manager` for
the shared cache and is harder to argue for in a security review.

The gateway stub compiles and runs today. A Rust developer can implement the two
TODO cache methods without touching any Python code.

---

### Risk Cache Design

```
VPA Hash (SHA-256 hex)  →  (risk_score: f32,  reason: String,  updated_at: u64)
```

- Written by: graph agent (via `POST /v1/webhook/update_cache`)
- Read by: `check_tx` handler (in-memory, no disk I/O on the hot path)
- TTL: entries older than 300 s should be treated as score 0.0 (not yet
  implemented in the stub — marked as TODO)
- Concurrency: `DashMap` provides per-shard locks, so concurrent reads from
  multiple Actix worker threads are lock-free

---

### Graph Typologies

All typologies are detected on a **sliding window** of the last N transactions
(configurable, default 500). The graph is rebuilt from scratch each iteration
rather than maintained incrementally — simpler to test, sufficient for demo load.

```
Fan-out:   sender_hash ──→ receiver_1
                        ──→ receiver_2   (out-degree > 5 in last 60 s)
                        ──→ receiver_N

Fan-in:    sender_1 ──→
           sender_2 ──→  receiver_hash  (in-degree > 8 in last 60 s)
           sender_N ──→

Cycle:     A ──→ B ──→ C ──→ A          (exact directed cycle, any length ≤ 10)
```

---

### Accessible Alert Design

The narration template for a BLOCK verdict:

```
⚠ Varaksha Alert: Transaction of ₹{amount} to {merchant} has been BLOCKED.
Reason: {reason}.
This may constitute an offence under IT Act 2000 §66D / BNS §318(4).
Contact your bank's fraud desk immediately.
```

For FLAG verdicts, the message is advisory rather than prescriptive, and does
not cite criminal statutes (incorrect legal framing for a mere suspicion).

---

### ML Stack Rationale

| Choice | Rationale |
|--------|-----------|
| `IsolationForest` contamination=0.02 | PaySim fraud rate is ~1.3%; 2% gives a small margin without flooding FLAG verdicts |
| SMOTE on training split only | `train_test_split` runs first; SMOTE is applied to `X_train`/`y_train` only — the test set always reflects the natural class distribution |
| Soft voting (RF + XGB) | Probability averaging smooths overconfident trees; hard voting loses calibration information |
| `LabelEncoder` per column | Frequency encoding would leak test-set frequencies during training; LE is count-free |
| `StandardScaler` | Tree ensembles are scale-invariant but IF benefits from normalised feature ranges |

---

## Open Items — Rust Teammate Checklist

These are the only items needed to make the gateway fully functional:

```
[ ] cache.rs  — RiskCache::get()
               Currently returns (0.0, "no cache entry") for all keys.
               Implement: return entry from inner DashMap, or (0.0, "cold") if absent.

[ ] cache.rs  — RiskCache::upsert()
               Currently a no-op.
               Implement: insert/update the DashMap entry with the provided score + reason.

[ ] main.rs   — HMAC verification in update_cache handler
               Currently skipped (any caller can update the cache).
               Implement: read x-varaksha-sig header, recompute HMAC-SHA256 over body
               using $VARAKSHA_WEBHOOK_SECRET env var, call Mac::verify_slice in constant time.

[ ] cache.rs  — TTL eviction
               Optional but recommended: entries older than 300 s should return score 0.0.
               Implement: store updated_at: u64 (Unix timestamp) and check on read.
```

Test command once implemented:

```bash
cargo run --manifest-path gateway/Cargo.toml
# In another terminal:
curl -s -X POST http://localhost:8082/v1/tx \
  -H "Content-Type: application/json" \
  -d '{"vpa":"test@okicici","amount":9999.0,"merchant":"test_merchant","timestamp":1234567890}'
```

Expected: `{"verdict":"Allow","risk_score":0.0,...}` before cache is populated,
then a real score after the graph agent pushes a webhook update.

---

## Datasets Used

| Dataset | File | Source | Used for |
|---------|------|--------|----------|
| PaySim | `PS_20174392719_1491204439457_log.csv` | Kaggle (López-Rojas 2016) | Primary ML training (stratified 50 K sample) |
| UPI synthetic | `Untitled spreadsheet - upi_transactions.csv` | Self-generated | UPI-specific transaction patterns |
| Customer_DF + cust_transaction_details | `customer_df.csv` + `cust_transaction_details.csv` | Kaggle credit fraud | Joined on customer ID |
| CDR Realtime Fraud | `cdr_realtime_fraud.csv` | Kaggle telecom fraud | High-fraud-rate supplement (50% fraud) |
| Supervised Behavior | `supervised_dataset.csv` | API behavior anomaly | Outlier-labeled API access patterns (1,699 rows) |
| Remaining Behavior Extended | `remaining_behavior_ext.csv` | Extended behavior | Bot/attack/outlier behavior types (34,423 rows) |
| ToN-IoT | `ton-iot.csv` | IoT network intrusion | Network intrusion label mapping |
| JailbreakBench | `train-*.parquet`, `test-*.parquet` | HuggingFace | Prompt injection guard training |
| Prompt injections | `prompt_injections.json` | Custom curated | PromptGuard fine-tune |

---

### Phase 8 — Dataset Audit + Retrain on 111K Rows

**Date:** March 11, 2026  
**Files:** `services/local_engine/train_ensemble.py`, `data/models/`

#### Problem identified

A review of the `data/datasets/` directory found 10 data files, but `train_ensemble.py` had loaders for only 7. Three datasets were being silently ignored:

| File | Type | Rows |
|------|------|------|
| `supervised_dataset.csv` | API behavior anomaly (`classification` col) | 1,699 |
| `remaining_behavior_ext.csv` | Extended behavior (`behavior_type` col) | 34,423 |
| `ton-iot.csv` | IoT network intrusion (`label` col) | 19 |

Additionally, the models on disk were stale — file timestamps showed they predated the Phase 6 loader additions, meaning they were never actually trained on the full 7-dataset merge.

#### Changes to `train_ensemble.py`

Three new loaders added and wired into `load_and_merge_all()`:

- **`_load_supervised_behavior()`** — maps `classification=='outlier'` → fraud=1; proxies `inter_api_access_duration` as amount, `api_access_uniqueness` as amount_zscore
- **`_load_behavior_extended()`** — maps `behavior_type` in `{outlier, bot, attack}` → fraud=1; same schema mapping
- **`_load_ton_iot()`** — maps `label` col; `duration` → amount; `src_bytes + dst_bytes` volume → amount_zscore; unix timestamp → hour_of_day

#### Retrain results (March 11, 2026)

| Dataset | Rows | Fraud % |
|---|---|---|
| PaySim (stratified 50 K) | 50,000 | 16.4% |
| UPI Transactions | 647 | 24.0% |
| Customer_DF + cust_transaction_details | 168 | 36.3% |
| CDR Realtime Fraud | 24,543 | 50.2% |
| Supervised Behavior | 1,699 | 34.9% |
| Remaining Behavior Extended | 34,423 | 74.0% |
| ToN-IoT | 19 | 57.9% |
| **Merged total** | **111,499** | **42.0% (pre-SMOTE)** |

SMOTE applied: 51,735 legit / 51,735 fraud after resampling.

| Metric | Value |
|---|---|
| RF Accuracy | **85.24%** |
| RF ROC-AUC | **0.9546** |
| Fraud Precision | 0.7709 |
| Fraud Recall | 0.9229 |
| Fraud F1 | **0.8401** |

#### Cleanup

Stale model artifacts removed from `data/models/`:
- `lightgbm.pkl` — never used at inference
- `xgboost.pkl`, `xgboost.onnx` — dropped in Phase 6, not removed until now
- `voting_ensemble.pkl`, `voting_ensemble.onnx` — superseded by RF-only pipeline

Remaining model files: `varaksha_rf_model.onnx`, `isolation_forest.onnx`, `scaler.onnx`, `random_forest.pkl`, `isolation_forest.pkl`, `scaler.pkl`, `feature_meta.json`.

---

### Phase 9 — UI Polish: Textures, Colour Tokens, Live Page

**Date:** March 11, 2026  
**Files:** `frontend/app/globals.css`, `frontend/tailwind.config.ts`, `frontend/app/page.tsx`, `frontend/app/flow/page.tsx`, `frontend/app/live/page.tsx`, `frontend/app/live/SecurityArena.tsx`, `frontend/app/live/CacheVisualizer.tsx`, `frontend/app/layout.tsx`

#### Texture system

Added a subtle depth layer across all three pages:

- **`body`** (globals.css): dot-grid background (22 px pitch, ink @ 5.2% opacity) + denim radial glow top-left + teal radial glow bottom-right
- **`.surface-card`** utility: diagonal white→pale-blue gradient applied to metric cards (landing) and step-detail cards (flow)
- **Nav**: `shadow-[0_1px_18px_rgba(15,30,46,0.07)]` for lift
- **Dark `<main>` on live page**: inline dot-grid + radial style mirrors body texture on dark background (Tailwind `bg-*` can't override a custom body `backgroundImage` on dark surfaces)

#### Colour token: `flag`

The `saffron` token was originally used for both UI accent (buttons, kickers) and FLAG verdict colour. These were split:

| Token | Hex | Role |
|---|---|---|
| `saffron` | `#2563EB` | UI accent only (buttons, kickers, loading indicators) |
| `flag` | `#D97706` | FLAG verdict colour only (amber) |

All FLAG verdict references across `page.tsx`, `SecurityArena.tsx`, and `CacheVisualizer.tsx` updated to `text-flag` / `bg-flag` / `border-flag`.

#### Frontend metric card updated

Landing page metric card updated to reflect Phase 8 retrain results:

| Field | Before | After |
|---|---|---|
| Accuracy | 94.4% | **85.24%** |
| Training data note | 75K rows · 4 real datasets | **111K rows · 7 real datasets** |

#### Repository transfer

GitHub repository transferred from `Vibhor2702/Varaksha` to `Varaksha-G/Varaksha`. Remote updated locally via `git remote set-url`.

---

### Phase 10 — Target Leakage Audit + Loaders Fixed

**Date:** March 12, 2026
**Files:** `services/local_engine/train_ensemble.py`

#### Problem identified

Post-training ROC-AUC of **0.9952** was suspiciously high. A code review of every dataset loader revealed four target-leakage bugs — features that were mechanically derived from the fraud label, giving the model a direct or near-direct signal of the answer at training time.

#### Leakage 1 — `_load_behavior_extended` (`is_new_device` = `is_fraud`)

```python
# BEFORE (leaking)
df["is_new_device"] = df[TARGET].astype(np.float32)

# AFTER
df["is_new_device"] = 0.0   # no per-session device-novelty data in this loader
```

`remaining_behavior_ext.csv` contains 34,423 rows — the largest single contributor to the merged dataset. For all 34K rows `is_new_device` was a perfect copy of the label. The Random Forest trivially scored this subset, artificially pulling AUC to near-1.0.

#### Leakage 2 — `_load_supervised_behavior` (`is_new_device` = `is_fraud`)

Identical error in the Supervised Behavior loader (1,699 rows). Fixed the same way — `is_new_device = 0.0`.

#### Leakage 3 — `_load_ton_iot` (`is_new_device` = `is_fraud`)

Identical error in the ToN-IoT loader (19 rows). Fixed the same way — `is_new_device = 0.0`.

#### Leakage 4 — `_load_cdr_fraud` (`merchant_category` encodes `fraud_type`)

```python
# BEFORE (leaking)
_ft_map = {
    "none":               "P2P",       # ← legit
    "sim_box_fraud":      "GAMBLING",  # ← fraud
    "subscription_fraud": "UTILITY",   # ← fraud
    "random_fraud":       "ECOM",      # ← fraud
    "call_masking":       "TRAVEL",    # ← fraud
}
df["merchant_category"] = df["fraud_type"].map(_ft_map)

# AFTER
df["merchant_category"] = "UTILITY"   # all CDR = telecom subscription traffic
```

The fraud label is derived as `fraud_type != "none"`. The mapping above created a categorical feature where `"P2P"` = legit and every other value = fraud, across 24,543 rows. This is not just correlated — it is the label in a different column.

#### Why the AUC looked plausible

The four leakage sources each affected a different loader, so no single suspicious metric was visible by dataset. The overall AUC rise from 0.9869 (Phase 6) to 0.9952 (Phase 8) was attributed to "more data" — plausible on its face. The tell was that 0.9952 is unusually high for a tabular fraud problem with heterogeneous multi-source data that doesn't share a common distribution. Post-fix AUC: **0.9546**.

#### Impact

All four leakage bugs have been corrected in `train_ensemble.py`. Models retrained immediately. Final metrics: RF Accuracy **85.24%**, ROC-AUC **0.9546**, Fraud Precision 0.7709, Recall 0.9229, F1 0.8401.

| Loader | Leakage type | Feature | Fix |
|---|---|---|---|
| `_load_behavior_extended` | Direct copy of label | `is_new_device = is_fraud` (34,423 rows) | Set `is_new_device = 0.0` |
| `_load_supervised_behavior` | Direct copy of label | `is_new_device = is_fraud` (1,699 rows) | Set `is_new_device = 0.0` |
| `_load_ton_iot` | Direct copy of label | `is_new_device = is_fraud` (19 rows) | Set `is_new_device = 0.0` |
| `_load_cdr_fraud` | Label-derived categorical | `merchant_category` encodes `fraud_type` (24,543 rows) | Set `merchant_category = "UTILITY"` for all rows |

---

## Honest Caveats

**The Rust cache is a stub.** Until the teammate fills in `RiskCache::get()` and
`upsert()`, every transaction scores 0.0 and returns `ALLOW`. The demo Streamlit
dashboard bypasses the gateway and generates scores directly in Python — it
does not depend on the Rust server being fully implemented.

**googletrans is unofficial.** The Google Translate Python wrapper reverse-engineers
the public translation endpoint. It has no SLA and can break on API changes.
For production: use Bhashini (https://bhashini.gov.in/api) or DeepL.

**SMOTE is not a substitute for real data.** The synthetic oversampling improves
classifier recall on the minority class during training. It does not make the
model more accurate on real-world UPI fraud patterns, which differ from PaySim's
stylised simulation in timing, merchant category, and network topology.

**VPA hashing is SHA-256, not HMAC.** SHA-256 of a short predictable string (UPI
IDs follow `username@bank` format) is reversible via rainbow table. In production
the gateway should use HMAC-SHA256 with a per-deployment secret key so the hash
cannot be reversed even if the database is leaked.
