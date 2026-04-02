# SpecPrefill Implementation Plan

## Goal
Reduce TTFT (Time-To-First-Token) by 3-5x for long prompts (>8k tokens) using attention-based token importance scoring and sparse prefill.

## Architecture

### Phase 1: Token Importance Scoring (Week 1)
```rust
// crates/higgs-models/src/spec_prefill/scoring.rs

pub struct TokenImportance {
    pub scores: Array,      // [M] per-token importance
    pub n_tokens: usize,
}

pub fn score_tokens(
    draft_model: &AnyModel,
    tokens: &[u32],
    n_lookahead: usize,     // 8-16 decode steps
    pool_kernel: usize,     // 13 (from paper)
) -> Result<TokenImportance, ModelError>
```

**Implementation:**
1. Load draft model (0.6B-4B, separate from main model)
2. Prefill draft with all prompt tokens
3. Run N lookahead decode steps
4. Capture query vectors during attention
5. Compute importance = Q_lookahead @ K_prompt^T
6. Aggregate across heads/layers, apply avg_pool1d smoothing

**Draft Model Options:**
- Qwen3.5-0.6B-4bit (smallest, fastest)
- Qwen3.5-4B-4bit (better quality, slower)
- Configurable via `HIGGS_DRAFT_MODEL` env var

### Phase 2: Chunk Selection (Week 1)
```rust
// crates/higgs-models/src/spec_prefill/selection.rs

pub fn select_chunks(
    importance: &TokenImportance,
    keep_pct: f32,        // 0.20 for >8k, 1.0 for <8k
    chunk_size: usize,    // 32 tokens
) -> Result<Vec<usize>, Exception>
```

**Implementation:**
1. Divide tokens into chunks of 32
2. Compute average importance per chunk
3. Select top-K% chunks by importance
4. Return sorted token indices

**Keep Rate Presets:**
```rust
pub const KEEP_RATE_PRESETS: &[(usize, f32)] = &[
    (8192, 1.0),    // No pruning <8k
    (16384, 0.30),  // 30% for 16k
    (32768, 0.25),  // 25% for 32k
    (65536, 0.20),  // 20% for 64k+
];
```

### Phase 3: Manual RoPE (Week 2)
```rust
// crates/higgs-models/src/spec_prefill/rope.rs

pub fn manual_rope(
    x: &Array,            // [B, n_heads, L, head_dim]
    positions: &Array,    // [L] non-contiguous positions
    dims: i32,
    base: f32,
    scale: f32,
) -> Result<Array, Exception>

pub struct PositionMappedRoPE {
    original: RoPE,
    positions: Array,
    cache_start: i32,
}

pub struct OffsetAdjustedRoPE {
    original: RoPE,
    adjustment: i32,      // M - N (total - selected)
}
```

**Implementation:**
1. `manual_rope()` - Apply RoPE at arbitrary positions using freq table
2. `PositionMappedRoPE` - Wrapper for sparse prefill phase
3. `OffsetAdjustedRoPE` - Wrapper for decode phase (adds M-N offset)

**Key Insight:** RoPE is relative - Q_m @ K_p^T depends only on (m - p). Selected keys stored contiguously with correct RoPE angles produce correct attention during decode.

### Phase 4: Sparse Prefill (Week 2)
```rust
// crates/higgs-models/src/spec_prefill/prefill.rs

pub fn sparse_prefill(
    model: &mut AnyModel,
    tokens: &[u32],           // [M] all prompt tokens
    selected_indices: &[usize], // [N] sorted indices to keep
    cache: &mut AnyCache,
    position_offset: i32,     // For system prompt cache
) -> Result<(Array, SparsePrefillState), ModelError>

pub struct SparsePrefillState {
    total_prompt_len: i32,
    selected_len: i32,
    adjustment: i32,          // M - N
}

pub fn cleanup_sparse_prefill(
    model: &mut AnyModel,
    state: &SparsePrefillState,
) -> Result<(), ModelError>
```

**Implementation:**
1. Map selected indices to tokens + positions
2. Patch RoPE on all attention layers with `PositionMappedRoPE`
3. Run prefill on selected tokens only
4. Replace RoPE with `OffsetAdjustedRoPE` for decode
5. Return state for cleanup after generation

**Side Effects:**
- Populates cache with KV for selected tokens only
- Installs OffsetAdjustedRoPE on attention layers
- Must call `cleanup_sparse_prefill()` after generation

### Phase 5: Integration (Week 3)
```rust
// crates/higgs-engine/src/simple.rs

pub struct SpecPrefillConfig {
    pub enabled: bool,
    pub draft_model_path: Option<PathBuf>,
    pub threshold: usize,     // 8192
    pub max_tokens: usize,    // 65536
    pub keep_rate: Option<f32>, // Auto-computed if None
}

impl SpecPrefillEngine {
    pub fn new(config: SpecPrefillConfig) -> Result<Self, ModelError> {
        // Load draft model if enabled
    }
    
    pub fn should_use_spec_prefill(&self, prompt_len: usize) -> bool {
        prompt_len >= self.config.threshold 
            && prompt_len <= self.config.max_tokens
    }
    
    pub fn prefill_with_spec(
        &self,
        main_model: &mut AnyModel,
        tokens: &[u32],
        cache: &mut AnyCache,
    ) -> Result<(Array, LogprobData), ModelError> {
        // 1. Score tokens with draft
        // 2. Select chunks
        // 3. Sparse prefill
        // 4. Return logits + state
    }
}
```

**Integration Points:**
1. Add `SpecPrefillConfig` to `ServerConfig`
2. Add `SpecPrefillEngine` to `Engine` struct
3. Modify `run_prefill()` to branch on `should_use_spec_prefill()`
4. Add `cleanup_after_generation()` call

### Phase 6: Testing & Benchmarks (Week 3)

**Unit Tests:**
- [ ] `test_manual_rope_correctness` - Compare with standard RoPE
- [ ] `test_sparse_prefill_output_match` - Full vs sparse should match
- [ ] `test_offset_adjusted_rope` - Decode positioning correct

**Integration Tests:**
- [ ] `test_spec_prefill_end_to_end` - Full generation loop
- [ ] `test_spec_prefill_with_system_prompt` - position_offset handling
- [ ] `test_spec_prefill_batched` - Multiple concurrent requests

**Benchmarks:**
```bash
# Before (baseline)
./bench_prefill.py --model Qwen3.5-35B-A3B-3bit --ctx 8192
# Expected: ~160 tok/s

# After (SpecPrefill, 20% keep rate)
./bench_prefill.py --model Qwen3.5-35B-A3B-3bit --ctx 8192 --spec-prefill
# Expected: ~480-640 tok/s (3-4x improvement)
```

## Dependencies

**Crate Dependencies:**
- None (pure Rust + mlx-rs)

**Model Dependencies:**
- Draft model: Qwen3.5-0.6B-4bit (~400MB) or Qwen3.5-4B-4bit (~2.5GB)
- Download from HuggingFace on first use (cached)

**Configuration:**
```toml
# higgs.toml
[spec_prefill]
enabled = true
draft_model = "mlx-community/Qwen3.5-0.6B-4bit"
threshold = 8192
max_tokens = 65536
```

## Risks & Mitigations

| Risk | Impact | Mitigation |
|------|--------|------------|
| Draft model loading slow | High | Cache draft model in memory, lazy load |
| Quality degradation | Medium | Use 20-30% keep rate, test on MMLU |
| RoPE correctness bugs | High | Extensive unit tests, compare outputs |
| Memory overhead | Low | Draft model unloaded after scoring |
| Batch request handling | Medium | Per-request scoring, shared draft model |

## Success Criteria

- [ ] **3x prefill improvement** for 8k+ token prompts
- [ ] **<1% quality degradation** on MMLU/GSM8K
- [ ] **Zero correctness bugs** (RoPE, positioning, cache)
- [ ] **<100ms overhead** for token scoring
- [ ] **Works with all model types** (MoE, dense, VLM)

## Timeline & Progress

| Week | Milestone | Status |
|------|-----------|--------|
| 1 | Token scoring + chunk selection | ✅ **DONE** |
| 2 | Manual RoPE + sparse prefill | ✅ **DONE** |
| 3 | Integration + testing + benchmarks | 🔄 IN PROGRESS |

**Phase 1 (Week 1) - Complete:**
- ✅ `TokenImportance` struct
- ✅ `select_chunks()` for top-K% selection
- ✅ `select_topk()` for individual token selection
- ✅ `score_tokens_uniform()` baseline
- ✅ `compute_keep_rate()` presets

**Phase 2 (Week 2) - Complete:**
- ✅ `manual_rope()` - Apply RoPE at arbitrary positions
- ✅ `manual_rope_with_freqs()` - Custom RoPE variants
- ✅ `PositionMappedRoPE` - For sparse prefill phase
- ✅ `OffsetAdjustedRoPE` - For decode phase
- ✅ `sparse_prefill()` - Main integration function
- ✅ `cleanup_sparse_prefill()` - Post-generation cleanup

**Phase 3 (Week 3) - Remaining:**
- [ ] Draft model loading and management
- [ ] Attention-based token scoring (Q@K^T)
- [ ] Integration with engine `run_prefill()`
- [ ] End-to-end tests
- [ ] Benchmarks vs baseline

## Open Questions

1. **Draft model choice**: 0.6B vs 4B? (speed vs scoring quality)
2. **Keep rate tuning**: Should we auto-tune per model/context?
3. **Batch handling**: Score once per batch or per-request?
4. **Fallback**: What if draft model fails to load? (disable gracefully)
