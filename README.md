## Doctor signature and stamp extraction

This version integrates the `3aryan8/pme_database` main branch with persistent
doctor recognition, per-page signature/stamp crops, combined-region crops and
full-page bounding-box annotations. The current dashboard and normalized
`src/database` package display/store this evidence.

```bash
uv sync --extra vlm --group dev
# On the GPU machine, after configuring PDF sources and split boundaries:
uv run --extra vlm python -m pipelines.run_all
# Re-extract previously processed reports to add bounding boxes:
uv run --extra vlm python -m src.extraction.run_extraction --overwrite
uv run python -m src.database.run_database
uv run streamlit run frontend/app.py
```

See [doctor recognition setup, database upgrades and validation](docs/doctor-recognition.md).

# Offline Medical Report Digitization & Query System

A local, modular, and reproducible Document-AI pipeline for converting scanned multi-page medical examination reports into structured, queryable, and traceable records.

This system handles complex scanned medical documents containing a mixture of typed text, handwriting, numerical measurements, tables, signatures, stamps/seals, thumbprints, photographs, and overlapping visual regions.

---

## Key Features

* **Strict Local Privacy**: 100% offline. Zero cloud services, remote API calls, or internet dependencies at runtime.
* **Modular Architecture**: AI models, OCR engines, preprocessing algorithms, databases, and storage layers are completely decoupled and independently replaceable.
* **Full Traceability & Provenance**: Every extracted field links directly back to its source PDF, page index, bounding box (`[x1, y1, x2, y2]`), and extraction run metadata.
* **Schema-Driven Extraction**: Medical fields are defined in declarative YAML configurations (`configs/schema.yaml`) rather than hardcoded logic.
* **Human-in-the-Loop Feedback**: Corrections made during review automatically feed back into ground-truth datasets for model evaluation, detector retraining, and fine-tuning.
* **Dual-GPU Optimization**: Configured out-of-the-box for multi-GPU worker parallel inference on hardware setups like 2 × NVIDIA RTX 4500 Ada.

---

## Document Model

The system processes multi-person batch PDFs where every individual candidate report consists of exactly **four pages**:

```text
Person Report Unit (4 Pages)
├── Page 1 — Basic Information, Identification, & Medical Memo
├── Page 2 — Medical Metrics, Lab Results, & Handwritten Remarks
├── Page 3 — Fitness Classification, Vision Measurements, & Clinical Notes
└── Page 4 — Candidate & Examiner Declarations / Consent
```

---

## Pipeline Flow

```text
configs/pdf_sources.yaml          YAML list of PDF filenames
        ↓
PDF merge (src/pdf_merge)         locate + validate + merge in YAML order
        ↓
data/merged/merged_source.pdf     single batched source PDF (separate folder — never re-merged)
        ↓
Assembly (src/assembly)           split per configs/splits.yaml (pages_per_person — count derived from the merged page count) → render N pages/person
        ↓
Preprocessing (src/preprocessing) clean + VLM-sized copies → manifest
        ↓
Detection / Extraction            (VLM stages, separate entrypoints)
        ↓
src/database (validate+import)  validate → SQLite (data/pme.db) → report generation
```

### Run the whole thing, start to finish

```bash
uv run python -m pipelines.run_all              # all module stages (GPU needed for detect/extract)
uv run python -m pipelines.run_all --skip-gpu   # CPU stages plus database import
uv run python -m pipelines.run_all --dry-run    # print the central plan, run nothing
```

## Getting Started

### Prerequisites

- Python 3.11 or newer
- [`uv`](https://docs.astral.sh/uv/) for dependency and environment management
- A local OpenAI-compatible LLM server for the generic extraction workflow
- NVIDIA drivers and the NVIDIA Container Toolkit for VLM detection/extraction

Install the project and development dependencies:

```bash
uv sync --dev
```

The pipeline expects input PDFs in `data/raw/`. Add their filenames to
`configs/pdf_sources.yaml`, review `configs/splits.yaml`, and then run the
appropriate pipeline command from the project root.

### Useful Commands

```bash
# Run the complete workflow
uv run python -m pipelines.run_all

# Run only merge, assembly, and preprocessing
uv run python -m src.run_pipeline --phase all

# Run the test suite
uv run pytest tests/ -v

# Validate extraction files without importing them
uv run python scripts/validate_extractions.py \
        --directory data/processed/extractions

# Import validated extractions into the database
uv run python scripts/import_extractions.py \
        --directory data/processed/extractions

# Run the canonical database module directly
uv run python -m src.database.run_database \
        --directory data/processed/extractions

```

### Canonical Module Runners

Each processing module has one `run_<module>.py` entrypoint. The central
cross-module orchestrator is `pipelines/run_all.py`.

| Module | Runner | Input | Output |
| --- | --- | --- | --- |
| PDF merge | `python -m src.pdf_merge.run_pdf_merge` | configured raw PDFs | merged source PDF |
| Assembly | `python -m src.assembly.run_assembly` | merged PDF and split map | rendered pages and manifest |
| Preprocessing | `python -m src.preprocessing.run_preprocessing` | manifest and rendered pages | cleaned/VLM images and manifest |
| Detection | `python -m src.detection.run_detection` | processed pages and region config | region JSON and overlays |
| Extraction | `python -m src.extraction.run_extraction` | processed pages and schema | extraction records |
| Database | `python -m src.database.run_database` | canonical `record.json` files | normalized database rows |
| Ground truth | `python -m src.ground_truth.run_ground_truth` | GT JSON and extraction records | Gate 1 report |

Run the complete sequence with:

```bash
uv run python -m pipelines.run_all --help
uv run python -m pipelines.run_all --dry-run
uv run python -m pipelines.run_all --with-ground-truth
```

Every Python source and test file begins with a phase, input, output, and
individual command header. Run one test file with `uv run pytest
tests/test_<name>.py -q`, or run the complete suite with:

```bash
uv run pytest tests/ -q
```

## Streamlit Dashboard

Start the dashboard from the project root:

```bash
uv run streamlit run frontend/app.py
```

The dashboard synchronizes extraction records at startup and every 60 seconds.
Use **Sync extraction files** in the sidebar to request an immediate sync.
Candidate and examination summary counts are scoped to the document IDs in the
current extraction directory, rather than every historical row in the database.

The **Unique medical examinations** count deduplicates records by candidate and
medical-examination date. Multiple extraction documents for the same candidate
and date count as one examination; examinations on different dates count
separately. The dashboard's candidate search and record details are served from
the normalized database.

Default data locations and environment overrides:

| Setting | Default | Purpose |
| --- | --- | --- |
| `EXTRACTION_DIR` | `data/processed/extractions` | Canonical `record.json` files synced into the database |
| `REPORT_IMAGES_DIR` | `data/interim/high_res` | Rendered report pages, organized by document ID |
| `DATABASE_URL` | `sqlite:///data/pme.db` | Database used for candidate search and record details |

Images are resolved from the current report-image directory when a candidate
is viewed. Extractions without a roll number cannot be linked to a candidate;
sync failures are reported in the sidebar.

## Configuration

Pipeline configuration is kept in `configs/`:

| file | purpose |
| --- | --- |
| `pdf_sources.yaml` | ordered raw PDF inputs |
| `splits.yaml` | pages per person and manual page ranges |
| `pipeline.yaml` | stage and processing settings |
| `regions.yaml` | detection region definitions |
| `models.yaml` | model and inference settings |
| `schema.yaml` | fields extracted by the VLM pipeline |
| `schema.baseline.yaml` | baseline schema for comparison |
| `holdout_ids.txt` | IDs reserved for evaluation |

Database connection settings are read from environment variables by the
database configuration module. The default local workflow uses SQLite; keep
credentials and machine-specific settings in a local `.env` file rather than
committing them.

## Docker

Build the development image and open a shell:

```bash
make build
make shell
```

Run the test suite in the container:

```bash
make test
```

Verify NVIDIA GPU passthrough and run GPU-enabled commands with:

```bash
make verify-gpu
make gpu CMD="python -m src.detection.run_detection"
```

The GPU compose override requires a native Docker daemon with the NVIDIA
Container Toolkit. Label Studio is available at `http://localhost:8080` when
the compose services are started.

## Repository Layout

```text
configs/       versioned pipeline, model, split, and schema configuration
data/          raw inputs, intermediate artifacts, ground truth, and reports
frontend/      Streamlit candidate database dashboard
scripts/       validation, import, reporting, and inspection utilities
src/           pipeline stages and database implementation
tests/         unit and integration tests
docker/        CPU and GPU Docker Compose definitions
```

Generated files under `data/` can be removed with `make clean`. Raw PDFs,
ground-truth annotations, configuration files, and other source material are
not removed by that command.

Stages: `core` (merge → assembly → preprocess) → `detect` (GPU) → `extract` (GPU) → `validate` → `import` (extractions + rendered report images into the DB). Fail-fast: stops at the first failing stage.

### CPU-only core pipeline

`uv run python -m src.run_pipeline` (or `--phase assembly|preprocess|all`) — merge → assembly → preprocess without the GPU/DB stages.

## PDF Merging (first pipeline step)

Before assembly, the pipeline merges the configured raw PDFs into one batched source PDF.

1. **Where the config lives:** `configs/pdf_sources.yaml`
   ```yaml
   pdfs:
     - report_001.pdf
     - report_002.pdf
   ```
   Order matters — the merged PDF's page order is exactly this list's order. All listed PDFs must exist or the pipeline fails with a clear error naming the missing files.
2. **Where input PDFs go:** `data/raw/` (filenames in the YAML resolve against this directory).
3. **Where the merged PDF lands:** `data/merged/merged_source.pdf` — a **separate folder** from the raw inputs, so the merged file can never be picked up as an input on a later run (no recursive re-merging). Input PDFs are never modified or deleted. A **single** configured PDF is **copied byte-for-byte** into this folder (SHA preserved → document IDs stay stable, no re-encoding); several are merged in YAML order (new SHA → new document IDs). The merged file is the **only input the rest of the pipeline consumes** — `data/raw` is never read downstream.
4. **How the pipeline uses it:** `src/run_pipeline.py` calls `merge_configured_pdfs()` and passes the result to assembly. `configs/splits.yaml` splits it **dynamically**: `pages_per_person` consecutive pages per person, person count = merged page count / `pages_per_person` — so the map stays correct when the merged PDF grows. Assembly refuses unconfirmed maps and page counts that are not a multiple of `pages_per_person` (no partial-person guessing).
5. **Standalone:** `uv run python -m src.pdf_merge.run_pdf_merge`

## Report Images (verification)

Every imported report stores its **rendered page images** in the database so extracted values can be visually checked against the original scan.

- **N pages per person is set by `configs/splits.yaml`** (`pages_per_person`, or that person's manual page range), not a fixed 4 — a person with 3 or 6 report pages works the same way. The import cross-checks the rendered count against the record's declared coverage (`pages_covered`) and fails atomically on mismatch.
- Images live in the pipeline's standard render output: `data/interim/high_res/<document_id>/page_0000.png .. page_NNNN.png` (assembly output). They are **not** copied — the database stores a path reference (project-relative when possible).
- Stored per examination (the report record) in the `report_images` table: `examination_id`, `page_number` (1-based, 1–N), `image_path`, `document_id` (provenance). Unique on `(examination_id, page_number)` — exactly one image per page per report.
- Inserted in the **same transaction** as the candidate/examination: a missing page rolls back the whole import, so no orphan image rows and no partial records are ever left behind.
- **Retrieving the report images for a candidate** (from the project root):
  ```python
  from src.database.database import get_session, init_db
  from src.database.repository import get_candidate_report_images

  init_db()
  session = get_session()
  for image in get_candidate_report_images(session, candidate_id):
      print(image.page_number, image.image_path)   # 1..N, in order
  ```
  Or by examination: `get_report_images(session, examination_id)`.

## Generic LLM Extraction Pipeline (zero-touch)

A schema-driven, decoupled text → LLM → schema → DB path in `src/database`:
the Pydantic schema class is the **single source of truth** — add/remove/rename
fields there and the LLM prompt, validation, storage, and retrieval all adapt
without touching extractor, store, or pipeline code (generic over *any*
Pydantic class).

| file | role |
|---|---|
| `src/database/extraction_schema.py` | **the schema** — `MedicalExaminationRecord` (+ `ReportTableRow`). Edit fields here only. |
| `src/database/extractor.py` | generic LLM extractor: prompt from JSON schema, tolerant JSON recovery, `model_validate` at the trust boundary. Client-agnostic (`complete(prompt) -> str`), default: OpenAI-compatible server via stdlib `urllib`. |
| `src/database/store.py` | generic store: any validated Pydantic instance → one row in `extraction_records(id, schema_name, payload JSON, created_at)`; `get()`/`all_rows()` validate the payload back into the class. |
| `scripts/run_pipeline.py` | runner: `text → extract → save`, with `--dry-run` (print the prompt) and `--schema` (any Pydantic class). |

```bash
uv run python scripts/run_pipeline.py --text samples/sample_report.txt   # text → LLM → validated schema → DB
uv run python scripts/run_pipeline.py --dry-run                          # print the generated LLM prompt

# retrieve
uv run python -c "from src.database.extraction_schema import MedicalExaminationRecord as M; \
                  from src.database.store import all_rows; print(all_rows(M))"
```

LLM endpoint (any OpenAI-compatible server — LM Studio, OpenAI, vLLM, Ollama):

| env | default |
|---|---|
| `PME_LLM_BASE_URL` | `http://localhost:1234/v1` |
| `PME_LLM_MODEL` | `qwen/qwen3.8-27b` |
| `PME_LLM_API_KEY` | *(unset)* |
| `PME_LLM_MAX_TOKENS` | `8192` |
| `PME_LLM_TIMEOUT` | `300` |

Notes:

- The generic `extraction_records` table is separate from the normalized
  relational tables (`candidates`, `medical_examinations`, ...) — those stay
  the curated store for the VLM pipeline; this is the schema-driven path.
- `payload` stores the validated instance as JSON, so schema evolution needs
  no table migration and never breaks old rows' reads (they validate against
  the current class or raise clearly).
- Tests: `uv run pytest tests/test_generic_pipeline.py -q` (fake LLM client,
  in-memory SQLite — no network, no GPU).