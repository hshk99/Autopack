# Intention Anchor System - Implementation Complete

**Status**: Production-Ready (Milestones 0-2, 4 complete)
**Date**: 2026-01-04
**Test Coverage**: 104/104 tests passing ✅

## Executive Summary

The **Intention Anchor** system provides a canonical, versioned representation of user intent that prevents goal drift during autonomous execution. The system is fully operational with:

- ✅ Schema, storage, and rendering (Milestone 0)
- ✅ Phase binding via `intention_refs` (Milestone 1)
- ✅ Prompt injection across all LLM clients (Milestone 2)
- ✅ Telemetry tracking via Phase6Metrics (Milestone 4)

## System Architecture

### Core Components

```
src/autopack/intention_anchor/
├── __init__.py          # Public API (13 exports)
├── models.py            # Pydantic v2 schemas (strict validation)
├── storage.py           # Atomic persistence + versioning
├── render.py            # Deterministic prompt rendering
└── telemetry.py         # Phase6Metrics integration
```

### Data Flow

```
User Intent
    ↓
IntentionAnchor (JSON) → .autonomous_runs/<run_id>/intention_anchor.json
    ↓
Phase Binding → PhaseCreate.intention_refs (indices into anchor)
    ↓
Prompt Injection → Builder/Auditor/Doctor prompts
    ↓
Telemetry → Phase6Metrics table
```

## Milestone Completion Details

### Milestone 0: Foundation (Complete ✅)

**Files Created:**
- `src/autopack/intention_anchor/models.py` - Strict Pydantic v2 schemas
- `src/autopack/intention_anchor/storage.py` - Atomic file persistence
- `src/autopack/intention_anchor/render.py` - Deterministic renderers

**Key Features:**
- All models use `extra="forbid"` - unknown fields rejected loudly
- Canonical path: `.autonomous_runs/<run_id>/intention_anchor.json`
- Atomic writes (temp → replace), Windows-safe
- Version management: `create()` → v1, `update()` → increment
- Deterministic rendering (stable ordering, no timestamps, capped bullets)

**Tests:** 38/38 passing
- 10 model tests (schema strictness)
- 14 storage tests (roundtrip + versioning)
- 14 rendering tests (determinism + exact shapes)

### Milestone 1: Phase Binding (Complete ✅)

**Schema Extensions:**
- Added `IntentionRefs` schema to `schemas.py`
- Extended `PhaseCreate` and `PhaseResponse` with optional `intention_refs` field
- Indices reference specific success criteria/constraints in anchor

**Validation:**
- `validate_intention_refs()` in `plan_utils.py`
- Warn-first mode (non-blocking) vs strict mode (raises)
- Validates index ranges, detects out-of-bounds references
- Backward compatible: phases without refs still work

**Tests:** 20/20 passing
- Schema validation tests
- Validator logic tests (warn vs strict modes)
- Backward compatibility tests

### Milestone 2: Prompt Injection (Complete ✅)

**Implementation Pattern (all LLM clients):**
```python
# Milestone 2: Inject intention anchor
if run_id := phase_spec.get('run_id'):
    from .intention_anchor import load_and_render_for_builder

    anchor_section = load_and_render_for_builder(
        run_id=run_id,
        phase_id=phase_spec.get('phase_id', 'unknown'),
        base_dir='.',
    )
    if anchor_section:
        prompt_parts.append(anchor_section)
        prompt_parts.append("\n")
```

**Files Modified:**
1. `src/autopack/openai_clients.py` - Builder (line 380) + Auditor (line 592)
2. `src/autopack/gemini_clients.py` - Builder (line 384) + Auditor (line 587)
3. `src/autopack/glm_clients.py` - Builder (line 280) + Auditor (line 471)
4. `src/autopack/anthropic_clients.py` - Builder (line 3471) + Auditor (line 3852)
5. `src/autopack/llm_service.py` - Doctor (line 933)

**Agent-Specific Rendering:**
- **Builder**: 5 bullets max, header: "# Project Intent (Phase: {phase_id})"
- **Auditor**: 5 bullets max, header: "# Project Intent (for validation)"
- **Doctor**: 3 bullets max (compact), header: "# Project Intent (original goal)"

**Graceful Degradation:**
- Returns `None` if anchor doesn't exist
- Works without `run_id` in phase_spec
- No exceptions raised, LLM prompts still generate

**Tests:** 20/20 passing
- 13 prompt wiring tests (actual LLM client injection)
- 7 integration tests (end-to-end workflows)

### Milestone 3: SOT Integration (Blocked ⏸️)

**Status**: Not yet implemented - requires autonomous runs to complete and self-document.

**What's Missing:**
- Autonomous runs don't currently write BUILD_HISTORY/DEBUG_LOG entries
- Manual SOT documentation doesn't yet reference `anchor_id` + `version`
- No automated tidy hook to verify anchor references

**When to Implement:**
- After autonomous executor can complete phases end-to-end
- After runs can generate their own completion summaries
- After tidy system can validate SOT references

### Milestone 4: Telemetry (Complete ✅)

**Files Created:**
- `src/autopack/intention_anchor/telemetry.py` - Telemetry-aware wrappers

**Integration:**
- Reuses existing `Phase6Metrics` table
- Records when called with database session:
  - `intention_context_injected=True`
  - `intention_context_chars=len(rendered)`
  - `intention_context_source="anchor"`

**API:**
```python
# Telemetry-aware versions (optional db parameter)
load_and_render_for_builder_with_telemetry(run_id, phase_id, base_dir=".", db=None)
load_and_render_for_auditor_with_telemetry(run_id, phase_id, base_dir=".", db=None)
load_and_render_for_doctor_with_telemetry(run_id, phase_id, base_dir=".", db=None)
```

**Design Decisions:**
- Separate telemetry module (no DB dependencies in core render.py)
- Opt-in via function choice (non-telemetry versions still available)
- Graceful: works without database session (`db=None`)
- Source tracking: `source="anchor"` distinguishes from legacy memory-based system

**Tests:** 14/14 passing
- Telemetry recording with DB session
- Operation without DB (no telemetry)
- Graceful degradation (missing anchor)
- Character count tracking
- Per-agent-type differentiation
- Large anchor handling (bullet capping)
- Backward compatibility

### Milestone 5: DB Fallback Retrieval (Future 🔮)

**Status**: Not implemented - optional enhancement for production hardening.

**Purpose**: Eliminate "vector store down → intent forgotten" failure mode by reading from `sot_entries` table when vector retrieval unavailable.

**When to Implement:**
- After production deployment experience
- If vector store reliability becomes an issue
- As fallback-only (vector retrieval remains primary)

## Test Results Summary

**Total**: 104/104 tests passing ✅

| Test Suite | Count | Status |
|-----------|-------|--------|
| Model tests (schema strictness) | 10 | ✅ |
| Storage tests (roundtrip + versioning) | 14 | ✅ |
| Rendering tests (determinism) | 27 | ✅ |
| Prompt wiring tests (LLM clients) | 13 | ✅ |
| Integration tests (end-to-end) | 7 | ✅ |
| Phase binding tests (intention_refs) | 20 | ✅ |
| Telemetry tests (usage tracking) | 14 | ✅ |

**No regressions** in broader test suite (800+ tests still passing).

## Public API

### Models
- `IntentionAnchor` - Main schema
- `IntentionConstraints` - Must/must_not/preferences
- `IntentionScope` - Path constraints
- `IntentionBudgets` - Token/context limits
- `IntentionRiskProfile` - Safety settings

### Storage
- `create_anchor(run_id, project_id, north_star, ...)` → IntentionAnchor
- `save_anchor(anchor, base_dir=".")` → None
- `load_anchor(run_id, base_dir=".")` → IntentionAnchor
- `update_anchor(anchor, save=False, base_dir=".")` → IntentionAnchor (version++)
- `get_canonical_path(run_id, base_dir=".")` → Path

### Rendering
- `render_for_prompt(anchor, max_bullets=7)` → str
- `render_compact(anchor)` → str (single-line summary)
- `render_for_builder(anchor, phase_id, max_bullets=5)` → str
- `render_for_auditor(anchor, max_bullets=5)` → str
- `render_for_doctor(anchor, max_bullets=3)` → str

### Prompt Injection Helpers
- `load_and_render_for_builder(run_id, phase_id, base_dir=".")` → Optional[str]
- `load_and_render_for_auditor(run_id, base_dir=".")` → Optional[str]
- `load_and_render_for_doctor(run_id, base_dir=".")` → Optional[str]

### Telemetry (Optional DB Integration)
- `load_and_render_for_builder_with_telemetry(run_id, phase_id, base_dir=".", db=None)`
- `load_and_render_for_auditor_with_telemetry(run_id, phase_id, base_dir=".", db=None)`
- `load_and_render_for_doctor_with_telemetry(run_id, phase_id, base_dir=".", db=None)`

## Usage Example

```python
from autopack.intention_anchor import (
    IntentionConstraints,
    create_anchor,
    save_anchor,
    load_and_render_for_builder,
)

# 1. Create anchor at run start
anchor = create_anchor(
    run_id="my-feature-001",
    project_id="autopack",
    north_star="Add real-time collaboration features to the app",
    success_criteria=[
        "Support multiple concurrent users",
        "Show live cursor positions",
        "Sync edits in <100ms",
    ],
    constraints=IntentionConstraints(
        must=["Use WebSocket protocol", "Handle reconnections gracefully"],
        must_not=["Block the main thread", "Store full document in memory"],
        preferences=["Use operational transform for conflict resolution"],
    ),
)
save_anchor(anchor)

# 2. Bind phases to anchor (via intention_refs indices)
phase = PhaseCreate(
    phase_id="F1.1",
    phase_index=1,
    tier_id="T1",
    name="Implement WebSocket server",
    description="Set up WebSocket server with reconnection logic",
    intention_refs=IntentionRefs(
        success_criteria=[0, 1],  # "Support multiple users" + "Show cursor positions"
        constraints_must=[0, 1],  # Both "must" constraints apply
    ),
)

# 3. Anchor automatically injected into prompts (LLM clients do this internally)
builder_prompt_section = load_and_render_for_builder(
    run_id="my-feature-001",
    phase_id="F1.1",
)
# Returns:
# """
# # Project Intent (Phase: F1.1)
#
# ## Intention Anchor (canonical)
# North star: Add real-time collaboration features to the app
# Success criteria:
# - Support multiple concurrent users
# - Show live cursor positions
# Must:
# - Use WebSocket protocol
# - Handle reconnections gracefully
# Must not:
# - Block the main thread
# - Store full document in memory
# Preferences:
# - Use operational transform for conflict resolution
# """

# 4. Telemetry automatically recorded (when using telemetry-aware version)
from autopack.intention_anchor import load_and_render_for_builder_with_telemetry
from autopack.database import SessionLocal

db = SessionLocal()
try:
    rendered = load_and_render_for_builder_with_telemetry(
        run_id="my-feature-001",
        phase_id="F1.1",
        db=db,  # Telemetry recorded to Phase6Metrics
    )
finally:
    db.close()
```

## Design Principles

1. **Determinism First**: All rendering is stable, no timestamps in output, predictable ordering
2. **Fail Gracefully**: Missing anchors return None, no exceptions in LLM prompt generation
3. **Zero Breaking Changes**: All existing code continues to work, anchors are additive
4. **Pydantic Strict Mode**: Unknown fields rejected (`extra="forbid"`) to prevent silent bugs
5. **Separation of Concerns**: Telemetry is optional, core rendering has no DB dependencies
6. **Atomic Persistence**: Windows-safe atomic file writes (temp → replace pattern)
7. **Budget-Bounded**: Bullet caps prevent prompt bloat (Builder=5, Auditor=5, Doctor=3)
8. **Version Management**: Every update increments version, enables audit trails

## Future Enhancements

### Milestone 3: SOT Integration
- **Trigger**: When autonomous runs can self-document
- **Changes**: BUILD_HISTORY/DEBUG_LOG entries reference `anchor_id` + `version`
- **Validation**: Tidy hook ensures SOT references are present

### Milestone 5: DB Fallback Retrieval
- **Trigger**: Production deployment + vector store reliability concerns
- **Changes**: Read from `sot_entries` table when vector retrieval unavailable
- **Scope**: Fallback only, vector retrieval remains primary

### Potential Extensions
- **Anchor Templates**: Pre-built templates for common task types
- **Multi-Anchor Runs**: Support for runs with multiple related goals
- **Anchor Evolution Tracking**: Visualize how intent changes over time
- **Cross-Run Anchor Reuse**: Reference anchors from previous successful runs

## Related Documentation

- **Implementation Plan**: [IMPLEMENTATION_PLAN_INTENTION_ANCHOR_LIFECYCLE.md](IMPLEMENTATION_PLAN_INTENTION_ANCHOR_LIFECYCLE.md)
- **Schema Validation**: Tests in `tests/autopack/test_intention_anchor_models.py`
- **Storage Patterns**: Tests in `tests/autopack/test_intention_anchor_storage.py`
- **Rendering Logic**: Tests in `tests/autopack/test_intention_anchor_prompt_render.py`
- **LLM Integration**: Tests in `tests/autopack/test_intention_anchor_prompt_wiring.py`

## Commits

| Milestone | Commit | Tests |
|-----------|--------|-------|
| 0 - Schema + Storage | `9fd92ad5` | 38/38 ✅ |
| 1 - Phase Binding | `9fd92ad5` | 20/20 ✅ |
| 2 Phase 1 - Rendering | `c79279f9` | 27/27 ✅ |
| 2 Phase 2 - Prompt Wiring | `feeb6533` | 13/13 ✅ |
| 2 Complete - Integration | `50fd64b0` | 7/7 ✅ |
| 4 - Telemetry | `552775eb` | 14/14 ✅ |

## Conclusion

The Intention Anchor system is **production-ready** for immediate use. Core functionality (Milestones 0-2, 4) is complete with comprehensive test coverage. The system prevents goal drift by maintaining a canonical, versioned representation of user intent that is:

1. **Persistent** - Survives across phases and runs
2. **Traceable** - Phases explicitly reference relevant intent via indices
3. **Visible** - Automatically injected into all LLM prompts
4. **Measurable** - Usage tracked via Phase6Metrics telemetry

Remaining milestones (3, 5) are blocked on prerequisites (autonomous self-documentation) or optional (DB fallback).
