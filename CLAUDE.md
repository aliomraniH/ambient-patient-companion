# CLAUDE.md — Ambient Patient Companion
> This file is the primary source of truth for Claude Code working in this repository.
> Read it in full before touching any file. Update it as architecture decisions are made.

---

## 1. Project Identity

**Repository:** `aliomraniH/ambient-patient-companion`
**Framework:** Ambient Action Model — `S = f(R, C, P, T)`
- **R** = Role (PCP, Care Manager, Patient)
- **C** = Context (pre-session, in-encounter, post-encounter, async)
- **T** = Time (urgency window, schedule position, care gap age)
- **P** = Patient State (conditions, medications, labs, SDoH, risk scores)

**Canonical Demo Patient:** Maria Chen, 54F, MRN 4829341 — managed by Dr. Rahul Patel at Patel Family Medicine.

**Core Design Principles (never violate):**
- Zero Activation Cost — surface the right action before the clinician thinks to look
- One Big Thing — one dominant signal per view; never compete for attention
- Progressive Trust Calibration — AI earns authority incrementally, never asserts it upfront
- Hick's Law applied to clinical panels — fewer choices = lower cognitive load

---

## 2. Current State (Baseline Before This Work)

| Artifact | Status | Location |
|---|---|---|
| Pre-session home dashboard | ✅ Complete | `prototypes/pcp-home.html` |
| In-encounter workspace | ✅ Complete | `prototypes/pcp-encounter.html` |
| Population health panel | ✅ Complete | `prototypes/population-health.html` |
| Message triage inbox | ✅ Complete | `prototypes/inbox.html` |
| FastMCP server | ❌ Not started | `server/mcp_server.py` |
| Clinical guidelines layer | ❌ Not started | `server/guidelines/` |
| Guardrail pipeline | ❌ Not started | `server/guardrails/` |
| Vector database | ❌ Not started | `server/vector_db/` |

**Known hard constraints:**
- HealthEx MCP cannot generate synthetic data and is **incompatible with Claude Code** — never use it
- FastMCP is the only approved path for synthetic data and tool serving
- All prototypes are single-file HTML/CSS/JS — no build step, no bundler
- Claude API model: always use `claude-sonnet-4-20250514`

---

## 3. Target Architecture

```
┌─────────────────────────────────────────────────────────┐
│  AMBIENT SURFACE  (HTML Prototypes)                      │
│  S = f(R, C, P, T) rendering engine in ambient-surface.js│
└─────────────────┬───────────────────────────────────────┘
                  │ tool calls via MCP protocol
┌─────────────────▼───────────────────────────────────────┐
│  FASTMCP SERVER  (server/mcp_server.py)                  │
│  Tools: search_guidelines, get_patient_context,          │
│         check_screening_due, flag_drug_interaction        │
└──────┬───────────────┬────────────────┬─────────────────┘
       │               │                │
┌──────▼──────┐ ┌──────▼──────┐ ┌──────▼──────────────────┐
│  GUARDRAILS │ │  CLAUDE API  │ │  VECTOR DB (pgvector)   │
│  Layer 1:   │ │  System      │ │  MedCPT embeddings      │
│  Input      │ │  prompt per  │ │  Hybrid BM25 + dense    │
│  Layer 2:   │ │  role (R)    │ │  Metadata filters:      │
│  Generation │ │  Injected    │ │  source, grade, pop,    │
│  Layer 3:   │ │  guidelines  │ │  contraindications      │
│  Output     │ │  from DB     │ │                         │
└─────────────┘ └─────────────┘ └─────────────────────────┘
                       │
┌──────────────────────▼──────────────────────────────────┐
│  SOURCES OF TRUTH                                        │
│  guidelines/ada_standards.json                           │
│  guidelines/uspstf_recs.json                             │
│  Synthetic patient data (FastMCP generated)              │
└─────────────────────────────────────────────────────────┘
```

---

## 4. Implementation Plan

### PHASE 1 — LLM Guardrails + Hardcoded Guidelines
**Goal:** Working Claude API integration with safety rails and 20-30 structured guidelines embedded in system prompts. No vector DB yet.
**Duration target:** ~4 weeks
**Status:** 🔴 Not started

#### 4.1 Directory scaffold (create these first)
```
server/
├── mcp_server.py
├── guardrails/
│   ├── __init__.py
│   ├── clinical_rules.py        # hard-coded clinical decision rules
│   ├── input_validator.py       # PHI detection + jailbreak screening
│   └── output_validator.py      # citation verification + hallucination check
├── guidelines/
│   ├── ada_standards.json       # ADA Standards of Care (20-30 key recs)
│   ├── uspstf_recs.json         # USPSTF top-10 screening recommendations
│   └── ingestion/
│       └── chunk_guidelines.py  # chunking logic (for Phase 2)
config/
└── system_prompts/
    ├── pcp_encounter.xml
    ├── care_manager.xml
    └── patient_facing.xml
```

#### 4.2 Guidelines JSON schema (use for every entry)
```json
{
  "guideline_source": "ADA",
  "version": "2026",
  "chapter": "9. Pharmacologic Approaches to Glycemic Treatment",
  "section": "9.3",
  "recommendation_id": "9.3a",
  "text": "Metformin is the preferred initial pharmacologic agent for type 2 diabetes",
  "evidence_grade": "A",
  "recommendation_strength": "Strong",
  "patient_population": ["adults", "type_2_diabetes"],
  "contraindications": ["eGFR < 30"],
  "medications_mentioned": ["metformin"],
  "last_reviewed": "2026-01-15",
  "is_current": true
}
```

Populate `ada_standards.json` with at minimum:
- Chapter 9: Pharmacologic treatment (metformin, SGLT2i, GLP-1 RA)
- Chapter 10: Cardiovascular disease + risk management
- Chapter 11: CKD in diabetes
- Chapter 6: Glycemic targets (HbA1c < 7% for most adults, Grade A)

Populate `uspstf_recs.json` with:
- Colorectal cancer screening (Grade A, adults 45-75)
- Hypertension screening (Grade A, adults ≥ 18)
- Diabetes screening (Grade B, adults 35-70, overweight/obese)
- Breast cancer screening (Grade B, women 40+)
- Depression screening (Grade B, adults)
- Cervical cancer screening (Grade A, women 21-65)
- Lung cancer screening (Grade B, adults 50-80, 20 pack-year history)

#### 4.3 System prompt architecture (XML format, one file per role)

**`config/system_prompts/pcp_encounter.xml`** must contain:
```xml
<role>Clinical decision support assistant for licensed primary care providers during
time-bounded 15-minute encounters. NOT a diagnostic authority.</role>

<retrieved_context>
  {{GUIDELINES_PLACEHOLDER}}
</retrieved_context>

<clinical_boundaries>
  - Ground ALL recommendations in retrieved context above
  - Cite: guideline source, version, evidence grade with every recommendation
  - Calibrated language: "Evidence strongly supports..." (Grade A) |
    "Clinical findings suggest..." (Grade B) | "Consider evaluating..." (Grade C)
  - Never provide definitive diagnoses — frame as differential considerations only
  - Medication mentions: always append "Verify dosing with pharmacist"
  - Insufficient evidence: state "Insufficient guideline evidence. Clinician judgment required."
  - Never extrapolate beyond retrieved evidence
</clinical_boundaries>

<escalation_triggers>
  - Life-threatening condition → prepend "⚠️ URGENT: Immediate clinician review required"
  - Controlled substance request → BLOCK, return escalation notice, do not generate recommendation
  - Pediatric dosing → require weight-based verification flag
  - Pregnancy or possible pregnancy → flag teratogenicity review
</escalation_triggers>

<output_format>
  Clinical Finding → Guideline Recommendation → Evidence Grade →
  Action Items → Caveats/Contraindications
  Maximum 3 action items per response. Surface the One Big Thing first.
</output_format>
```

**`config/system_prompts/patient_facing.xml`** must add:
- Reading level target: 6th grade Flesch-Kincaid
- Every response ends: "Please discuss with your healthcare provider before making any changes."
- No drug dosages in patient-facing responses — ever
- Emotional acknowledgment before clinical content

**`config/system_prompts/care_manager.xml`** must add:
- Population-level framing (panel context, not individual encounter)
- Care gap language: "X% of your diabetes panel is overdue for..."
- SDoH flags when present in patient context

#### 4.4 FastMCP server tools (Phase 1 minimum viable set)

```python
# server/mcp_server.py

@mcp.tool()
def clinical_query(query: str, role: str, patient_context: dict) -> dict:
    """Three-layer guardrail pipeline: validate input → generate with role prompt → validate output."""

@mcp.tool()
def get_guideline(recommendation_id: str) -> dict:
    """Fetch a specific guideline by ID from JSON store."""

@mcp.tool()
def check_screening_due(patient_age: int, sex: str, conditions: list[str]) -> list[dict]:
    """Return list of overdue USPSTF screenings for this patient profile."""

@mcp.tool()
def flag_drug_interaction(medications: list[str]) -> list[dict]:
    """Return known interactions from hardcoded interaction rules."""

@mcp.tool()
def get_synthetic_patient(mrn: str) -> dict:
    """Return synthetic patient data. Maria Chen MRN 4829341 is the canonical demo patient."""
```

#### 4.5 Guardrail pipeline (implement all three layers before any Claude call goes live)

**Layer 1 — Input validation (`input_validator.py`)**
- PHI detection: scan for 18 HIPAA identifiers using regex (SSN, DOB, MRN patterns, full names in combination with dates)
- Jailbreak screening: check for role-override phrases ("ignore previous instructions", "pretend you are", "as a doctor tell me definitively")
- Scope check: reject requests outside clinical decision support scope
- Emotional tone flag: detect hopeful/minimizing framing that could bias output toward benign interpretation

**Layer 2 — Generation (`mcp_server.py` orchestration)**
- Load role-specific system prompt from XML
- Inject relevant guidelines into `{{GUIDELINES_PLACEHOLDER}}`
- Always pass `max_tokens=1024` — never allow unbounded generation
- Model: `claude-sonnet-4-20250514`

**Layer 3 — Output validation (`output_validator.py`)**
- Citation presence check: every recommendation must reference a guideline source + version
- PHI leakage scan on generated output
- Escalation keyword check: if output contains "diagnose", "you have", "I can confirm" → flag and rewrite
- Drug name verification: extract drug names from output, verify against medications_mentioned in retrieved guidelines

#### 4.6 JavaScript integration layer in prototypes

Add `shared/claude-client.js` (single shared file, imported by all prototypes):
```javascript
// claude-client.js
// Wraps calls to FastMCP server, handles loading states, error display

async function queryClinical(query, role, patientContext) {
  // POST to FastMCP server endpoint
  // Return { status, recommendation, citations, escalation_flags }
  // Handle blocked/escalated responses with UI-appropriate messaging
}

async function checkScreeningsDue(patientAge, sex, conditions) {
  // Returns array of { screening_name, due_date, uspstf_grade, action_url }
}
```

The ambient surface (`shared/ambient-surface.js`) calls these functions based on the current R, C, P, T state. The surface never calls Claude API directly — all AI calls route through the FastMCP server's guardrail pipeline.

---

### PHASE 2 — pgvector + MedCPT Embeddings
**Status:** 🔴 Not started — begin only after Phase 1 exit criteria are met
**Goal:** Replace hardcoded guidelines with hybrid semantic + keyword retrieval

Key additions:
- pgvector extension in PostgreSQL (or Supabase for hosted option)
- MedCPT embeddings (`ncbi/MedCPT-Article-Encoder`, 768 dimensions)
- BM25 lexical index on guideline text
- Reciprocal Rank Fusion (k=60) for hybrid search
- Chunk size: 500 words, 10-15% overlap, always on recommendation boundaries
- Metadata filter schema: source, version, evidence_grade, patient_population[], contraindications[], is_current
- FastMCP tool upgrade: `search_guidelines(query, filters)` replaces `get_guideline(id)`

Database schema:
```sql
CREATE TABLE guidelines (
  id UUID PRIMARY KEY,
  recommendation_id TEXT UNIQUE,
  guideline_source TEXT,         -- 'ADA', 'USPSTF', 'ACC', 'AHA'
  version TEXT,
  chapter TEXT,
  section TEXT,
  text TEXT,
  evidence_grade CHAR(1),        -- 'A', 'B', 'C', 'D', 'I'
  recommendation_strength TEXT,
  patient_population TEXT[],
  contraindications TEXT[],
  medications_mentioned TEXT[],
  last_reviewed DATE,
  is_current BOOLEAN DEFAULT true,
  embedding VECTOR(768),         -- MedCPT dense embedding
  bm25_tokens TSVECTOR           -- PostgreSQL full-text search
);
```

---

### PHASE 3 — Full RAG + Ambient Surface Integration
**Status:** 🔴 Not started — begin only after Phase 2 exit criteria are met
**Goal:** S = f(R, C, P, T) rendering engine dynamically invokes RAG; pre-session overnight inference pipeline

Key additions:
- GARAG pattern: generate diagnostic entities from P, use entities to retrieve guideline passages
- MedCPT cross-encoder reranker for top-k chunks
- Overnight pre-computation: retrieve + stage encounter surfaces before clinical day begins
- Token-Level Uncertainty Quantification (TL-UQ): flag low-confidence spans in output
- Full audit trail: log every query, retrieved chunk, generated response, validation result
- Post-generation fact-checking: NER on output → verify against retrieved chunks
- Four-tier escalation: automated guardrail → evaluator model → clinician review → human handoff

---

## 5. Test Criteria (Exit Gates by Phase)

### Phase 1 Exit Gate — must pass ALL before starting Phase 2
| Test | Method | Pass Threshold |
|---|---|---|
| Clinical accuracy | 50-question validation set, manually reviewed by clinician | ≥ 80% correct |
| No definitive diagnoses | Scan 100 outputs for "you have", "I diagnose", "confirmed" | 0 violations |
| Guideline citation | Every recommendation references source + version | 100% |
| Adversarial blocking | 20-case red-team suite (jailbreaks, PHI extraction, scope override) | 100% blocked |
| Tool availability | All 5 FastMCP tools callable and returning correct shapes | 100% functional |
| Prototype wiring | All 4 HTML prototypes call `claude-client.js`, no direct API calls | 100% |
| Escalation triggers | Test 5 escalation scenarios (URGENT, controlled substance, pediatric, pregnancy, insufficient evidence) | 100% triggered correctly |

### Phase 2 Exit Gate — must pass ALL before starting Phase 3
| Test | Method | Pass Threshold |
|---|---|---|
| Retrieval precision | Domain-specific test set, Precision@5 | ≥ 0.80 |
| Retrieval latency | p95 query latency | ≤ 200ms |
| Clinical accuracy with RAG | Same 50-question set, now using vector retrieval | ≥ 90% |
| Guideline versioning | Query for 2024 vs 2026 ADA recommendations correctly returns different versions | 100% correct |
| Metadata filtering | 10 queries with population/contraindication filters, verify filtered results only | 100% accurate |

### Phase 3 Exit Gate
| Test | Method | Pass Threshold |
|---|---|---|
| End-to-end latency | Chart open → rendered surface | ≤ 3 seconds p95 |
| Clinical accuracy | Expanded 100-question set | ≥ 92% |
| Safety escalation | Expanded 30-case safety suite | 0 false negatives |
| Audit trail completeness | Every interaction has query + chunks + response + validation logged | 100% |
| All three contracts | PCP encounter, care manager queue, patient companion all functional with RAG | 100% |

---

## 6. File Naming & Code Conventions

- Python files: snake_case, type hints required, docstrings required
- JS files: camelCase, JSDoc comments on exported functions
- JSON guideline files: human-readable, validated against schema before commit
- System prompt XML: comment every section explaining clinical rationale
- Never hardcode patient data outside `get_synthetic_patient()` — always use Maria Chen MRN 4829341 as demo
- Never call Claude API from HTML prototypes directly — always route through FastMCP server
- Every tool in `mcp_server.py` must have an integration test before it is wired to a prototype
- Commit message format: `[phase-N] what-changed — why-it-matters`

---

## 7. Do Not Do (Hard Constraints for Claude Code)

- ❌ Do NOT use HealthEx MCP — incompatible with Claude Code, cannot generate synthetic data
- ❌ Do NOT use `claude-opus-*` models — use `claude-sonnet-4-20250514` only
- ❌ Do NOT allow Claude API calls from HTML prototypes directly
- ❌ Do NOT chunk guideline text at token boundaries — always chunk at recommendation boundaries
- ❌ Do NOT skip the output validation layer — it is not optional in any phase
- ❌ Do NOT start Phase 2 until Phase 1 exit gate passes fully
- ❌ Do NOT generate real patient data — Maria Chen is fictional and all data is synthetic
- ❌ Do NOT use `localStorage` or `sessionStorage` in prototypes — use in-memory state only
- ❌ Do NOT remove the "Clinician judgment required" fallback — it must always exist when evidence is insufficient

---

## 8. References

- ADA Standards of Medical Care in Diabetes 2026: https://diabetesjournals.org/care/issue/49/Supplement_1
- USPSTF Recommendations: https://www.uspreventiveservicestaskforce.org/uspstf/recommendation-topics
- MedCPT embeddings: https://huggingface.co/ncbi/MedCPT-Article-Encoder
- FastMCP docs: https://github.com/jlowin/fastmcp
- Anthropic API reference: https://docs.anthropic.com/en/api/getting-started
- pgvector: https://github.com/pgvector/pgvector
- Ambient Action Model paper (Google Drive): see project shared drive
