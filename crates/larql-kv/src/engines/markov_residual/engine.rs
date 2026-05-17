//! MarkovResidualEngine — KvEngine implementation.

use larql_compute::ComputeBackend;
use larql_vindex::VectorIndex;
use ndarray::Array2;

use super::compute::{rs_decode_step, rs_decode_step_profiled, rs_prefill};
use super::store::RsStore;
use super::walk::{ensure_attn_tensors_dequantised, rs_decode_step_walk, rs_prefill_walk};
use crate::profiler::EngineProfiler;
use crate::{DecodeStageSummary, EngineInfo, KvEngine};
use larql_inference::ffn::FfnBackend;
use larql_inference::model::ModelWeights;
use larql_inference::{cpu_engine_backend, EngineBackend};

pub struct MarkovResidualEngine {
    window_size: Option<usize>,
    store: Option<RsStore>,
    backend: Box<dyn EngineBackend>,
    profiling: bool,
    profile: EngineProfiler,
    metal_prefill_done: bool,
}

impl MarkovResidualEngine {
    pub fn new(window_size: Option<usize>) -> Self {
        Self::with_backend(window_size, cpu_engine_backend())
    }

    pub fn with_backend(window_size: Option<usize>, backend: Box<dyn EngineBackend>) -> Self {
        Self {
            window_size,
            store: None,
            backend,
            profiling: false,
            profile: EngineProfiler::default(),
            metal_prefill_done: false,
        }
    }

    pub fn with_profiling(mut self, enabled: bool) -> Self {
        self.profiling = enabled;
        self
    }

    pub fn total_memory_bytes(&self) -> usize {
        self.store.as_ref().map_or(0, |s| s.memory_bytes())
    }
}

impl KvEngine for MarkovResidualEngine {
    fn name(&self) -> &str {
        "markov-rs"
    }

    fn info(&self) -> EngineInfo {
        let config = match self.window_size {
            Some(w) => format!("window={w}"),
            None => "window=full".into(),
        };
        let mem = self.store.as_ref().map_or(0, |s| s.memory_bytes());
        EngineInfo {
            name: "markov-rs".into(),
            description: format!(
                "residual-stream KV replacement — K/V recomputed from stored residuals (mem={:.1}MB)",
                mem as f64 / 1_048_576.0,
            ),
            backend: self.backend.name().to_string(),
            config,
        }
    }

    fn prefill(
        &mut self,
        weights: &ModelWeights,
        _ffn: &dyn FfnBackend,
        token_ids: &[u32],
    ) -> Option<Array2<f32>> {
        let result = rs_prefill(weights, token_ids, self.window_size, self.backend.as_ref());
        let hidden = result.hidden.clone();
        self.store = Some(result.store);
        Some(hidden)
    }

    fn decode_step(
        &mut self,
        weights: &ModelWeights,
        _ffn: &dyn FfnBackend,
        token_id: u32,
    ) -> Option<Array2<f32>> {
        let rs = self.store.take()?;
        let (hidden, new_rs) = if self.profiling {
            rs_decode_step_profiled(
                weights,
                token_id,
                rs,
                self.backend.as_ref(),
                &mut self.profile,
            )?
        } else {
            rs_decode_step(weights, token_id, rs, self.backend.as_ref())?
        };
        self.store = Some(new_rs);
        Some(hidden)
    }

    fn memory_bytes(&self) -> usize {
        self.total_memory_bytes()
    }

    fn window_tokens(&self) -> usize {
        self.store.as_ref().map_or(0, |s| s.window_tokens())
    }

    fn cold_bytes(&self) -> usize {
        self.store.as_ref().map_or(0, |s| s.cold_bytes())
    }

    fn stage_summary(&self) -> Option<DecodeStageSummary> {
        if !self.profiling || self.profile.decode_total.count == 0 {
            return None;
        }
        Some(self.profile.summary("markov-rs", self.backend.name()))
    }

    fn prefill_quant(
        &mut self,
        weights: &mut ModelWeights,
        _ffn: &dyn FfnBackend,
        index: &VectorIndex,
        token_ids: &[u32],
        backend: &dyn ComputeBackend,
    ) -> Option<Array2<f32>> {
        use crate::engines::unlimited_context::engine::fused_prefill;
        if let Some(h) = fused_prefill(weights, index, token_ids, backend) {
            self.metal_prefill_done = true;
            self.store = None;
            return Some(h);
        }
        self.metal_prefill_done = false;
        ensure_attn_tensors_dequantised(weights, index);
        let result = rs_prefill_walk(weights, index, token_ids, self.window_size, backend);
        let hidden = result.hidden.clone();
        self.store = Some(result.store);
        Some(hidden)
    }

    fn decode_step_quant(
        &mut self,
        weights: &mut ModelWeights,
        _ffn: &dyn FfnBackend,
        index: &VectorIndex,
        token_id: u32,
        backend: &dyn ComputeBackend,
    ) -> Option<Array2<f32>> {
        use crate::engines::unlimited_context::engine::fused_decode_step;
        if self.metal_prefill_done {
            if let Some(h) = fused_decode_step(weights, index, token_id, backend) {
                return Some(h);
            }
        }
        ensure_attn_tensors_dequantised(weights, index);
        let rs = self.store.take()?;
        let (hidden, new_rs) = rs_decode_step_walk(weights, index, token_id, rs, backend)?;
        self.store = Some(new_rs);
        Some(hidden)
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::KvEngine;
    use larql_inference::ffn::WeightFfn;
    use larql_inference::forward::hidden_to_raw_logits;
    use larql_inference::test_utils::make_test_weights;

    // ── Construction ──────────────────────────────────────────────────────────

    #[test]
    fn engine_name() {
        assert_eq!(MarkovResidualEngine::new(None).name(), "markov-rs");
    }

    #[test]
    fn engine_memory_zero_before_prefill() {
        let eng = MarkovResidualEngine::new(None);
        assert_eq!(eng.memory_bytes(), 0);
        assert_eq!(eng.window_tokens(), 0);
        assert_eq!(eng.cold_bytes(), 0);
    }

    #[test]
    fn engine_info_full_window() {
        let eng = MarkovResidualEngine::new(None);
        let info = eng.info();
        assert!(
            info.config.contains("full"),
            "expected 'full' in config, got '{}'",
            info.config
        );
    }

    #[test]
    fn engine_info_fixed_window() {
        let eng = MarkovResidualEngine::new(Some(16));
        let info = eng.info();
        assert!(
            info.config.contains("16"),
            "expected window size in config, got '{}'",
            info.config
        );
    }

    // ── Prefill → decode cycle ────────────────────────────────────────────────

    #[test]
    fn prefill_stores_residuals_for_all_layers() {
        let weights = make_test_weights();
        let ffn = WeightFfn { weights: &weights };
        let mut engine = MarkovResidualEngine::new(None);
        let h = engine
            .prefill(&weights, &ffn, &[0u32, 1, 2])
            .expect("prefill");
        assert_eq!(h.shape(), &[1, weights.hidden_size]);
        assert!(
            engine.memory_bytes() > 0,
            "store should be non-empty after prefill"
        );
    }

    #[test]
    fn decode_step_produces_finite_logits() {
        let weights = make_test_weights();
        let ffn = WeightFfn { weights: &weights };
        let mut engine = MarkovResidualEngine::new(None);
        engine.prefill(&weights, &ffn, &[0u32, 1]).expect("prefill");
        let h = engine.decode_step(&weights, &ffn, 2).expect("decode");
        assert_eq!(h.shape(), &[1, weights.hidden_size]);
        assert!(hidden_to_raw_logits(&weights, &h)
            .iter()
            .all(|v| v.is_finite()));
    }

    #[test]
    fn memory_grows_with_each_decode_step() {
        let weights = make_test_weights();
        let ffn = WeightFfn { weights: &weights };
        let mut engine = MarkovResidualEngine::new(None);
        engine.prefill(&weights, &ffn, &[0u32]).expect("prefill");
        let mem_after_prefill = engine.memory_bytes();
        engine.decode_step(&weights, &ffn, 1).expect("decode 1");
        let mem_after_1 = engine.memory_bytes();
        engine.decode_step(&weights, &ffn, 2).expect("decode 2");
        let mem_after_2 = engine.memory_bytes();
        assert!(
            mem_after_1 > mem_after_prefill,
            "memory should grow with decode steps"
        );
        assert!(mem_after_2 > mem_after_1);
    }

    #[test]
    fn window_clipping_limits_hot_store() {
        let weights = make_test_weights();
        let ffn = WeightFfn { weights: &weights };
        let mut engine = MarkovResidualEngine::new(Some(2)); // window=2 tokens
        engine
            .prefill(&weights, &ffn, &[0u32, 1, 2, 3, 4])
            .expect("prefill 5 tokens");
        // After clipping, hot store ≤ window
        assert!(
            engine.window_tokens() <= 2,
            "window_tokens={} should be ≤ 2",
            engine.window_tokens()
        );
        // Cold bytes should now be non-zero (overflow clipped to cold)
        assert!(
            engine.cold_bytes() > 0,
            "cold tier should have bytes after clipping"
        );
    }

    #[test]
    fn multiple_decode_steps_produce_consistent_shapes() {
        let weights = make_test_weights();
        let ffn = WeightFfn { weights: &weights };
        let mut engine = MarkovResidualEngine::new(None);
        engine.prefill(&weights, &ffn, &[0u32]).expect("prefill");
        for step in 0..3 {
            let h = engine
                .decode_step(&weights, &ffn, step as u32)
                .expect("decode");
            assert_eq!(h.shape(), &[1, weights.hidden_size], "step {step}");
        }
    }

    // ── Profiling ─────────────────────────────────────────────────────────────

    #[test]
    fn with_profiling_enables_profiling_branch() {
        let weights = make_test_weights();
        let ffn = WeightFfn { weights: &weights };
        let mut engine = MarkovResidualEngine::new(None).with_profiling(true);
        // No decode yet → stage_summary returns None even with profiling on.
        assert!(engine.stage_summary().is_none());

        engine.prefill(&weights, &ffn, &[0u32, 1]).expect("prefill");
        engine.decode_step(&weights, &ffn, 2).expect("decode");

        let summary = engine.stage_summary().expect("profiling summary");
        assert_eq!(summary.engine, "markov-rs");
        assert_eq!(summary.steps, 1);
        assert!(summary.avg_total_decode_us > 0.0);
    }

    #[test]
    fn stage_summary_none_without_profiling() {
        let weights = make_test_weights();
        let ffn = WeightFfn { weights: &weights };
        let mut engine = MarkovResidualEngine::new(None); // profiling: false
        engine.prefill(&weights, &ffn, &[0u32]).expect("prefill");
        engine.decode_step(&weights, &ffn, 1).expect("decode");
        assert!(
            engine.stage_summary().is_none(),
            "stage_summary must be None when profiling is disabled"
        );
    }

    #[test]
    fn profiling_decode_path_matches_unprofiled_shape() {
        // Two engines: one profiled, one not. Both should yield hidden states
        // of the same shape after the same prefill+decode sequence.
        let weights = make_test_weights();
        let ffn = WeightFfn { weights: &weights };
        let mut profiled = MarkovResidualEngine::new(None).with_profiling(true);
        let mut plain = MarkovResidualEngine::new(None);
        profiled.prefill(&weights, &ffn, &[0u32, 1]).unwrap();
        plain.prefill(&weights, &ffn, &[0u32, 1]).unwrap();
        let h_p = profiled.decode_step(&weights, &ffn, 2).unwrap();
        let h_n = plain.decode_step(&weights, &ffn, 2).unwrap();
        assert_eq!(h_p.shape(), h_n.shape());
    }

    // ── Q4K paths via CPU fallback ────────────────────────────────────────
    //
    // On a CPU backend, `fused_prefill` returns `None`, so the engine
    // falls through to `rs_prefill_walk` against the synthetic VectorIndex.
    // This exercises the prefill_quant / decode_step_quant branches that the
    // Metal-only happy path also takes (apart from the Metal early-return).

    #[test]
    fn prefill_q4k_cpu_fallback_runs_walk_path() {
        use larql_inference::ffn::NullFfn;
        let mut weights = make_test_weights();
        let index = larql_inference::test_utils::make_test_vindex(&weights);
        let backend = larql_compute::cpu_backend();
        // `NullFfn` satisfies the trait without borrowing `weights`, which is
        // `&mut` here. The engine ignores the FFN parameter on this path.
        let ffn = NullFfn;
        let mut engine = MarkovResidualEngine::new(None);
        let h = engine
            .prefill_quant(&mut weights, &ffn, &index, &[0u32, 1, 2], &*backend)
            .expect("prefill_quant cpu fallback");
        assert_eq!(h.shape(), &[1, weights.hidden_size]);
        assert!(engine.memory_bytes() > 0);
    }

    #[test]
    fn decode_step_q4k_cpu_fallback_extends_store() {
        use larql_inference::ffn::NullFfn;
        let mut weights = make_test_weights();
        let index = larql_inference::test_utils::make_test_vindex(&weights);
        let backend = larql_compute::cpu_backend();
        let ffn = NullFfn;
        let mut engine = MarkovResidualEngine::new(None);
        engine
            .prefill_quant(&mut weights, &ffn, &index, &[0u32, 1], &*backend)
            .expect("prefill_quant");
        let mem_before = engine.memory_bytes();
        let h = engine
            .decode_step_quant(&mut weights, &ffn, &index, 2, &*backend)
            .expect("decode_step_quant cpu fallback");
        assert_eq!(h.shape(), &[1, weights.hidden_size]);
        assert!(
            engine.memory_bytes() > mem_before,
            "store should grow after decode_step_quant"
        );
    }

    // ── Walk-path overflow branches (markov_residual/walk.rs) ────────────
    //
    // The two tests above use `window=None` so the cold tier never
    // populates — leaving the walk.rs cold-K/V precompute (lines 66-76)
    // and cold-residual decode branch (lines 162-186) uncovered. The
    // tests below drive them with a small window + multiple decode steps.

    #[test]
    fn prefill_quant_walk_with_window_populates_cold_kv() {
        use larql_inference::ffn::NullFfn;
        let mut weights = make_test_weights();
        let index = larql_inference::test_utils::make_test_vindex(&weights);
        let backend = larql_compute::cpu_backend();
        let ffn = NullFfn;
        let mut engine = MarkovResidualEngine::new(Some(2));
        engine
            .prefill_quant(&mut weights, &ffn, &index, &[0u32, 1, 2, 3], &*backend)
            .expect("prefill_quant with overflow");
        // window=2 + 4 prompt tokens → cold tier populated → walk.rs
        // lines 67-75 fire.
        assert!(engine.window_tokens() <= 2);
        assert!(engine.cold_bytes() > 0);
    }

    #[test]
    fn decode_step_quant_walk_first_overflow_creates_cold_residuals() {
        // walk.rs lines 305-307: `None => updated_rs.cold_residuals =
        // Some(overflow)`. Fires when prefill didn't overflow (cold = None)
        // but the first decode does (window cap exceeded mid-decode).
        use larql_inference::ffn::NullFfn;
        let mut weights = make_test_weights();
        let index = larql_inference::test_utils::make_test_vindex(&weights);
        let backend = larql_compute::cpu_backend();
        let ffn = NullFfn;
        // window=2, prefill=1 token → no overflow on prefill (cold=None).
        let mut engine = MarkovResidualEngine::new(Some(2));
        engine
            .prefill_quant(&mut weights, &ffn, &index, &[0u32], &*backend)
            .expect("prefill_quant");
        // Decode until hot exceeds window → first-time cold population.
        engine
            .decode_step_quant(&mut weights, &ffn, &index, 1, &*backend)
            .expect("decode 1");
        engine
            .decode_step_quant(&mut weights, &ffn, &index, 2, &*backend)
            .expect("decode 2 — triggers first-overflow None branch");
        // After overflow, cold tier is populated.
        assert!(engine.cold_bytes() > 0);
    }

    #[test]
    fn decode_step_quant_walk_after_overflow_hits_cold_residuals_branch() {
        use larql_inference::ffn::NullFfn;
        let mut weights = make_test_weights();
        let index = larql_inference::test_utils::make_test_vindex(&weights);
        let backend = larql_compute::cpu_backend();
        let ffn = NullFfn;
        let mut engine = MarkovResidualEngine::new(Some(2));
        engine
            .prefill_quant(&mut weights, &ffn, &index, &[0u32, 1, 2, 3], &*backend)
            .expect("prefill_quant");
        // First decode: exercises walk.rs cold_kv branch (lines 132-161).
        engine
            .decode_step_quant(&mut weights, &ffn, &index, 4, &*backend)
            .expect("first decode_step_quant");
        // Second decode: cold_kv was cleared by overflow at the first
        // decode (walk.rs line 309), so this hits the cold_residuals
        // recompute branch (lines 162-187).
        let h = engine
            .decode_step_quant(&mut weights, &ffn, &index, 5, &*backend)
            .expect("second decode_step_quant");
        assert_eq!(h.shape(), &[1, weights.hidden_size]);
    }
}
