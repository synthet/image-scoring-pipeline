# Image embeddings (MobileNetV2, Postgres, backfill)

## What is stored

- **Primary (PostgreSQL):** Registry table **`embedding_spaces`** plus **`image_embeddings`** — one row per `(image_id, embedding_space_id)` with `embedding vector(1280)`, optional `model_version`, and an HNSW index for cosine search. The default space code is **`mobilenet_v2_imagenet_gap`** (see [`modules/embedding_spaces.py`](../../modules/embedding_spaces.py)).
- **Legacy / dual-write column:** **`images.image_embedding`** — still updated on every write so older code paths keep working. Reads on Postgres typically use **`COALESCE(image_embeddings.embedding, images.image_embedding)`** for the default space (see [`modules/db.py`](../../modules/db.py)).
- **Firebird (Electron gallery):** Single BLOB on **`images.image_embedding`** only; multi-space storage is **PostgreSQL-first** until the gallery migrates off Firebird (see [DB_VECTORS_REFACTOR.md](../plans/database/DB_VECTORS_REFACTOR.md)).
- **Model:** TensorFlow Keras **MobileNetV2**, ImageNet weights, `include_top=False`, global average pooling → **1280** floats.
- **Semantics:** Coarse **visual similarity** features for clustering, near-duplicate-style retrieval, tag propagation neighbors, and similar-image search. They are **not** CLIP text–image aligned embeddings.

## When embeddings are written

1. **Culling phase (clustering)** — [`modules/clustering.py`](../../modules/clustering.py) `ClusteringEngine.extract_features()` persists batches with `db.update_image_embeddings_batch()` (PostgreSQL also upserts **`image_embeddings`** for the default space when the registry row exists). Algorithm/model identity is tracked in code as `CLUSTER_VERSION` in that module; callers may pass `model_version=` into the batch API to persist it on `image_embeddings`.
2. **On demand** — [`modules/similar_search.py`](../../modules/similar_search.py) may compute and persist a single embedding via `ClusteringEngine` if an image is queried and `image_embedding` is null.

## Backfill images missing embeddings

Run in **WSL** with **`~/.venvs/tf`** (same as the web UI), with paths to thumbnails or originals resolvable from WSL.

**Canonical Windows one-launcher:**

```text
scripts\maintenance\run_populate_embeddings.bat
```

Optional arguments are passed through to Python, for example:

```text
run_populate_embeddings.bat --dry-run
run_populate_embeddings.bat --limit 500
run_populate_embeddings.bat --folder "D:\Photos\Trip"
run_populate_embeddings.bat --resume-after-id 12345
```

**Direct Python (WSL):**

```bash
python scripts/maintenance/populate_missing_embeddings.py [--dry-run] [--limit N] [--folder PATH] [--batch-size N] [--resume-after-id ID]
```

**Legacy launcher name:** `run_populate_missing_embeddings.bat` calls the same script (backward-compatible).

## Schema: column on `images` vs registry + `image_embeddings`

On **PostgreSQL**, the app now uses:

- **`embedding_spaces`** — canonical codes and dimensions (`dim` documents intent; the physical `vector(N)` column is still fixed per table).
- **`image_embeddings`** — stores vectors for each `(image_id, embedding_space_id)` with **`UNIQUE(image_id, embedding_space_id)`** and HNSW on **`image_embeddings.embedding`**.
- **`images.image_embedding`** — retained for **dual-write** and **dual-read** fallback during migration; new work should assume the keyed table is the long-term home for additional spaces.

For a **single** embedding type, a column on `images` alone is enough; the project is in an **expand-contract** phase: both the column and `image_embeddings` are populated for the default MobileNet space.

**pgvector rule (unchanged):** each `vector(N)` has a **fixed N**. A **512-d** CLIP space needs a **different** column or table — not another row in the current `image_embeddings.embedding` column (1280). See [DB_VECTORS_REFACTOR.md](../plans/database/DB_VECTORS_REFACTOR.md) worklog and follow-ups.

**Upgrade:** run Alembic revision **`0004`** (`migrations/versions/0004_embedding_spaces_image_embeddings.py`) on existing databases; `init_db()` on greenfield Postgres creates the same objects.

## Checklist for additional models (e.g. CLIP)

If you add another stored vector, define up front:

| Field | Example |
|-------|---------|
| Model identity | `mobilenet_v2_imagenet_gap`, `clip_vit_b32_image` |
| Dimension `N` for `vector(N)` | 1280 vs 512, etc. |
| Semantic use | CNN visual vs CLIP image tower vs text |
| Version | Tie to `CLUSTER_VERSION`, HF revision, or weights hash |
| Indexes | Separate HNSW (or IVFFlat) per query pattern |
| API / callers | Which endpoints and MCP tools read which space |

Treat a new space as **not interchangeable** with MobileNet embeddings without migration, reindex, and caller updates.

## Related code

- [`modules/embedding_spaces.py`](../../modules/embedding_spaces.py) — default space code, `get_default_embedding_space_id()`
- [`modules/clustering.py`](../../modules/clustering.py) — feature extraction and culling persistence
- [`modules/similar_search.py`](../../modules/similar_search.py) — similarity search, `EMBEDDING_DIM`; Postgres queries join `image_embeddings`
- [`modules/db.py`](../../modules/db.py) — `update_image_embedding(s)`, `get_images_missing_embeddings`, `_postgres_has_default_embedding_sql`, etc.
- [`modules/db_postgres.py`](../../modules/db_postgres.py) — DDL for `images`, `embedding_spaces`, `image_embeddings`, HNSW indexes
- [`migrations/versions/0004_embedding_spaces_image_embeddings.py`](../../migrations/versions/0004_embedding_spaces_image_embeddings.py) — Alembic upgrade for registry + backfill
- [`scripts/maintenance/populate_missing_embeddings.py`](../../scripts/maintenance/populate_missing_embeddings.py) — backfill CLI
- [`docs/plans/database/DB_VECTORS_REFACTOR.md`](../plans/database/DB_VECTORS_REFACTOR.md) — plan, worklog, follow-ups
