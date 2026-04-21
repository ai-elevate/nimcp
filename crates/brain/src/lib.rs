//! NIMCP V2 — top-level brain integration.
//!
//! This crate composes the smaller crates into a runnable `Brain`. It owns:
//!
//! - The scheduler (hosts all actors)
//! - The event log (the source of truth)
//! - A collection of network actors (adaptive / SNN / LNN)
//! - The memory actor (Z-Ladder)
//! - The checkpoint coordinator
//!
//! **No 800-field struct.** A `Brain` is a small handle that routes requests
//! to the right actor; each actor owns its own state.
//!
//! # Phase 1..4c scope
//!
//! Phase 1 wired an [`AdaptiveNet`] (MLP). Phase 4c wires in the remaining
//! two networks of the Phase 4 ensemble — [`SnnNetwork`] (spiking) and
//! [`LnnNetwork`] (liquid time-constant). All three are **optional** so
//! callers can keep a lightweight single-network brain, and the joint
//! checkpoint is a directory whose contents round-trip atomically.
//!
//! The scheduler still sits in the struct as a placeholder — actor-per-
//! network routing and a shared loss aggregator ride in later phases
//! (4d+, per V2_PLAN.md).

#![forbid(unsafe_code)]

pub mod actors;

use std::path::Path;

use ndarray::Array1;
use nimcp_adaptive::{AdaptiveConfig, AdaptiveError, AdaptiveNet};
use nimcp_core::{Error, Result};
use nimcp_lnn::{LnnConfig, LnnNetwork, LtcState, TrainParams};
use nimcp_scheduler::{Scheduler, SchedulerConfig};
use nimcp_snn::{SnnConfig, SnnNetwork};
use serde::{Deserialize, Serialize};

/// Top-level brain configuration.
#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct BrainConfig {
    /// Seed for deterministic init.
    pub rng_seed: u64,
    /// Whether to run in deterministic (single-threaded, virtual time) mode.
    pub deterministic: bool,
    /// Path where the event log + checkpoints live.
    pub state_dir: std::path::PathBuf,
    /// Adaptive network config — the MLP the brain trains against.
    pub adaptive: AdaptiveConfig,
    /// Optional SNN config. `None` → this brain has no spiking network;
    /// `snn_*` methods return errors.
    #[serde(default)]
    pub snn: Option<SnnConfig>,
    /// Optional LNN config. Same semantics as `snn`.
    #[serde(default)]
    pub lnn: Option<LnnConfig>,
}

impl Default for BrainConfig {
    fn default() -> Self {
        Self {
            rng_seed: 0x5EED,
            deterministic: false,
            state_dir: std::path::PathBuf::from("./nimcp-state"),
            adaptive: AdaptiveConfig::default(),
            snn: None,
            lnn: None,
        }
    }
}

/// The top-level brain handle.
pub struct Brain {
    config: BrainConfig,
    #[allow(dead_code)] // scheduler wires up in later phases
    scheduler: Scheduler,
    adaptive: AdaptiveNet,
    snn: Option<SnnNetwork>,
    lnn: Option<LnnNetwork>,
    /// Transient LNN runtime state — mirrors `lnn.new_state()`, reset on
    /// `lnn_reset` or fresh brain.
    lnn_state: Option<Vec<LtcState>>,
}

impl Brain {
    /// Boot a new brain with the given config. SNN / LNN are constructed
    /// only if the corresponding config is `Some`.
    pub fn new(config: BrainConfig) -> Result<Self> {
        let sched_cfg = SchedulerConfig {
            deterministic: config.deterministic,
            mailbox_capacity: 1024,
            rng_seed: config.rng_seed,
            ..SchedulerConfig::default()
        };
        let scheduler = Scheduler::new(sched_cfg);

        // Propagate the brain's rng_seed into adaptive unless the caller
        // overrode it explicitly. Same seed → same init, bit-for-bit.
        let mut adaptive_cfg = config.adaptive.clone();
        if adaptive_cfg.rng_seed == AdaptiveConfig::default().rng_seed {
            adaptive_cfg.rng_seed = config.rng_seed;
        }
        let adaptive = AdaptiveNet::new(adaptive_cfg);

        let snn = if let Some(cfg) = config.snn.clone() {
            Some(SnnNetwork::new(cfg).map_err(|e| Error::Config(format!("snn: {e}")))?)
        } else {
            None
        };

        let (lnn, lnn_state) = if let Some(cfg) = config.lnn.clone() {
            let net = LnnNetwork::new(cfg).map_err(|e| Error::Config(format!("lnn: {e}")))?;
            let state = net.new_state();
            (Some(net), Some(state))
        } else {
            (None, None)
        };

        tracing::info!(
            layers = ?config.adaptive.layers,
            seed = config.rng_seed,
            has_snn = snn.is_some(),
            has_lnn = lnn.is_some(),
            "brain created"
        );
        Ok(Self {
            config,
            scheduler,
            adaptive,
            snn,
            lnn,
            lnn_state,
        })
    }

    /// Accessor for the config.
    pub fn config(&self) -> &BrainConfig {
        &self.config
    }

    /// One training step against an MSE target. Returns pre-update loss.
    ///
    /// # Panics
    /// Panics if `features.len()` or `target.len()` don't match the first
    /// or last configured layer width. Callers that can't guarantee shape
    /// should validate before calling — the bindings layer does this.
    pub fn learn(&mut self, features: &Array1<f32>, target: &Array1<f32>, lr: f32) -> f32 {
        self.adaptive.learn(features, target, lr)
    }

    /// Forward pass. Returns the brain's output vector.
    pub fn predict(&self, features: &Array1<f32>) -> Array1<f32> {
        self.adaptive.forward(features)
    }

    /// Persist the brain's weights to `path`. Phase 1 only saves the
    /// adaptive net; later phases extend via CheckpointCoordinator.
    pub fn save<P: AsRef<Path>>(&self, path: P) -> Result<()> {
        let bytes = self.adaptive.save().map_err(adaptive_to_core_err)?;
        std::fs::write(path.as_ref(), bytes).map_err(Error::from)
    }

    /// Reload weights from a previous [`Brain::save`]. Shape is inferred
    /// from disk; the config's `layers` must match (shape-mismatched
    /// loads are a `Error::Config`).
    pub fn load<P: AsRef<Path>>(&mut self, path: P) -> Result<()> {
        let bytes = std::fs::read(path.as_ref()).map_err(Error::from)?;
        self.adaptive.load(&bytes).map_err(adaptive_to_core_err)?;
        Ok(())
    }

    // -------------------------------------------------------------------------
    // SNN access — all return `Error::Config` if the brain was constructed
    // without an SNN config.
    // -------------------------------------------------------------------------

    /// Immutable handle to the SNN, if present.
    pub fn snn(&self) -> Option<&SnnNetwork> {
        self.snn.as_ref()
    }

    /// Mutable handle to the SNN, if present.
    pub fn snn_mut(&mut self) -> Option<&mut SnnNetwork> {
        self.snn.as_mut()
    }

    /// One SNN integration step. See [`SnnNetwork::step`].
    pub fn snn_step(&mut self, external_i_syn: &[&[f32]], reward: f32, dt_ms: f32) -> Result<u32> {
        let snn = self
            .snn
            .as_mut()
            .ok_or_else(|| Error::Config("snn not configured on this brain".into()))?;
        Ok(snn.step(external_i_syn, reward, dt_ms))
    }

    // -------------------------------------------------------------------------
    // LNN access — same pattern as SNN.
    // -------------------------------------------------------------------------

    /// Immutable handle to the LNN, if present.
    pub fn lnn(&self) -> Option<&LnnNetwork> {
        self.lnn.as_ref()
    }

    /// Reset transient LNN state to zeros. No-op if no LNN.
    pub fn lnn_reset(&mut self) {
        if let (Some(net), Some(state)) = (self.lnn.as_ref(), self.lnn_state.as_mut()) {
            *state = net.new_state();
        }
    }

    /// Step the LNN forward one sample; returns the readout. Carries
    /// state across calls; use [`lnn_reset`] to start a new sequence.
    pub fn lnn_forward_step(&mut self, input: &Array1<f32>) -> Result<Array1<f32>> {
        let (Some(net), Some(state)) = (self.lnn.as_ref(), self.lnn_state.as_mut()) else {
            return Err(Error::Config("lnn not configured on this brain".into()));
        };
        Ok(net.forward_step(state, input))
    }

    /// Run the LNN over an entire sequence (resets state at the start).
    /// Returns per-step readouts.
    pub fn lnn_forward_sequence(&mut self, inputs: &[Array1<f32>]) -> Result<Vec<Array1<f32>>> {
        let (Some(net), Some(state)) = (self.lnn.as_ref(), self.lnn_state.as_mut()) else {
            return Err(Error::Config("lnn not configured on this brain".into()));
        };
        *state = net.new_state();
        let mut out = Vec::with_capacity(inputs.len());
        for u in inputs {
            out.push(net.forward_step(state, u));
        }
        Ok(out)
    }

    /// One LNN training step (MSE over sequence) with the supplied hyperparams.
    /// Returns `(loss, grad_norm)`.
    pub fn lnn_train_step_mse(
        &mut self,
        inputs: &[Array1<f32>],
        targets: &[Array1<f32>],
        params: &TrainParams,
    ) -> Result<(f32, f32)> {
        let lnn = self
            .lnn
            .as_mut()
            .ok_or_else(|| Error::Config("lnn not configured on this brain".into()))?;
        Ok(nimcp_lnn::train_step_mse(lnn, inputs, targets, params))
    }

    // -------------------------------------------------------------------------
    // Joint atomic ensemble checkpoint.
    // -------------------------------------------------------------------------

    /// Save every configured network into `dir`, atomically. Writes:
    ///
    /// - `adaptive.rkyv` — MLP weights (always present)
    /// - `snn.json` — SNN weight snapshot (only if SNN configured)
    /// - `lnn.json` — LNN full network (only if LNN configured)
    /// - `manifest.json` — which subfiles are present, plus a format version
    ///
    /// Atomicity is achieved by writing to `<dir>.tmp/` first and then
    /// `rename(<dir>.tmp, <dir>)` — the old ensemble stays intact if any
    /// subfile write fails.
    pub fn save_ensemble<P: AsRef<Path>>(&self, dir: P) -> Result<()> {
        let final_dir = dir.as_ref().to_path_buf();
        let tmp_dir = {
            let mut d = final_dir.clone();
            let file_name = d.file_name().ok_or_else(|| {
                Error::Config("save_ensemble: target must have a filename component".into())
            })?;
            let mut tmp_name = file_name.to_owned();
            tmp_name.push(".tmp");
            d.set_file_name(tmp_name);
            d
        };

        // Nuke any leftover `tmp_dir` from a crashed prior save.
        if tmp_dir.exists() {
            std::fs::remove_dir_all(&tmp_dir).map_err(Error::from)?;
        }
        std::fs::create_dir_all(&tmp_dir).map_err(Error::from)?;

        // Adaptive.
        let adaptive_bytes = self.adaptive.save().map_err(adaptive_to_core_err)?;
        std::fs::write(tmp_dir.join("adaptive.rkyv"), &adaptive_bytes).map_err(Error::from)?;

        let mut manifest = EnsembleManifest::default();
        manifest.files.push("adaptive.rkyv".into());

        // SNN.
        if let Some(snn) = &self.snn {
            let snap = snn.snapshot();
            let bytes = serde_json::to_vec(&snap)
                .map_err(|e| Error::Serialization(format!("snn snapshot: {e}")))?;
            std::fs::write(tmp_dir.join("snn.json"), bytes).map_err(Error::from)?;
            manifest.files.push("snn.json".into());
        }

        // LNN — serialize the whole network (weights + hyperparams).
        if let Some(lnn) = &self.lnn {
            let bytes = serde_json::to_vec(lnn)
                .map_err(|e| Error::Serialization(format!("lnn serialize: {e}")))?;
            std::fs::write(tmp_dir.join("lnn.json"), bytes).map_err(Error::from)?;
            manifest.files.push("lnn.json".into());
        }

        // Manifest — last so its presence signals "this dir is complete".
        let manifest_bytes = serde_json::to_vec_pretty(&manifest)
            .map_err(|e| Error::Serialization(format!("manifest: {e}")))?;
        std::fs::write(tmp_dir.join("manifest.json"), manifest_bytes).map_err(Error::from)?;

        // Atomic swap: remove any old dir, rename tmp into place.
        if final_dir.exists() {
            std::fs::remove_dir_all(&final_dir).map_err(Error::from)?;
        }
        std::fs::rename(&tmp_dir, &final_dir).map_err(Error::from)?;

        tracing::info!(dir = ?final_dir, files = ?manifest.files, "ensemble saved");
        Ok(())
    }

    /// Restore from a directory produced by [`save_ensemble`]. Every
    /// configured network is restored; subfiles missing from the
    /// directory leave the corresponding network unchanged.
    pub fn load_ensemble<P: AsRef<Path>>(&mut self, dir: P) -> Result<()> {
        let dir = dir.as_ref();
        if !dir.is_dir() {
            return Err(Error::Config(format!(
                "load_ensemble: {dir:?} is not a directory"
            )));
        }
        let manifest_bytes = std::fs::read(dir.join("manifest.json")).map_err(Error::from)?;
        let manifest: EnsembleManifest = serde_json::from_slice(&manifest_bytes)
            .map_err(|e| Error::Serialization(format!("manifest decode: {e}")))?;
        if manifest.version != EnsembleManifest::default().version {
            return Err(Error::Config(format!(
                "manifest version {} unsupported (expected {})",
                manifest.version,
                EnsembleManifest::default().version
            )));
        }

        // Adaptive.
        if manifest.files.iter().any(|f| f == "adaptive.rkyv") {
            let bytes = std::fs::read(dir.join("adaptive.rkyv")).map_err(Error::from)?;
            self.adaptive.load(&bytes).map_err(adaptive_to_core_err)?;
        }

        // SNN — apply WeightSnapshot via `restore`. Returns `false` on
        // shape mismatch, which we surface as `Error::Config`.
        if manifest.files.iter().any(|f| f == "snn.json") {
            let snn = self.snn.as_mut().ok_or_else(|| {
                Error::Config("snapshot has snn.json but brain was built without snn".into())
            })?;
            let bytes = std::fs::read(dir.join("snn.json")).map_err(Error::from)?;
            let snap: nimcp_snn::network::WeightSnapshot = serde_json::from_slice(&bytes)
                .map_err(|e| Error::Serialization(format!("snn snapshot decode: {e}")))?;
            if !snn.restore(&snap) {
                return Err(Error::Config(
                    "snn snapshot shape does not match current brain".into(),
                ));
            }
        }

        // LNN — replace whole network. Verify the shape matches the
        // brain's current LNN config before overwriting.
        if manifest.files.iter().any(|f| f == "lnn.json") {
            let lnn_slot = self.lnn.as_mut().ok_or_else(|| {
                Error::Config("snapshot has lnn.json but brain was built without lnn".into())
            })?;
            let bytes = std::fs::read(dir.join("lnn.json")).map_err(Error::from)?;
            let restored: LnnNetwork = serde_json::from_slice(&bytes)
                .map_err(|e| Error::Serialization(format!("lnn decode: {e}")))?;
            if restored.input_dim != lnn_slot.input_dim
                || restored.output_dim != lnn_slot.output_dim
                || restored.layers.len() != lnn_slot.layers.len()
            {
                return Err(Error::Config(
                    "lnn snapshot shape does not match current brain".into(),
                ));
            }
            *lnn_slot = restored;
            // Reset transient state to fresh zeros so the restored
            // network starts with a clean runtime state.
            if let Some(state) = self.lnn_state.as_mut() {
                *state = lnn_slot.new_state();
            }
        }

        tracing::info!(dir = ?dir, files = ?manifest.files, "ensemble loaded");
        Ok(())
    }
}

/// Manifest describing which subfiles are in an ensemble checkpoint dir.
#[derive(Debug, Clone, Serialize, Deserialize)]
struct EnsembleManifest {
    /// Manifest schema version — bump on breaking layout change.
    version: u32,
    /// Subfile names present in this snapshot.
    files: Vec<String>,
}

impl Default for EnsembleManifest {
    fn default() -> Self {
        Self {
            version: 1,
            files: Vec::new(),
        }
    }
}

fn adaptive_to_core_err(e: AdaptiveError) -> Error {
    match e {
        AdaptiveError::ShapeMismatch { expected, got } => Error::Config(format!(
            "adaptive shape mismatch: expected {expected}, got {got}"
        )),
        AdaptiveError::Serialization(msg) => Error::Serialization(msg),
        AdaptiveError::Checkpoint(msg) => Error::Config(format!("checkpoint: {msg}")),
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use ndarray::Array1;

    #[tokio::test]
    async fn brain_boots_with_default_config() {
        let brain = Brain::new(BrainConfig::default()).unwrap();
        assert_eq!(brain.config().rng_seed, 0x5EED);
    }

    /// End-to-end XOR inside the Brain API — this is the Phase 1 exit
    /// criterion: 100-neuron toy brain trains on XOR in <5s.
    #[tokio::test]
    async fn brain_trains_xor_end_to_end() {
        let cfg = BrainConfig {
            rng_seed: 0x42,
            deterministic: true,
            adaptive: AdaptiveConfig {
                layers: vec![2, 16, 1],
                rng_seed: 0x42,
                activation: nimcp_adaptive::Activation::Tanh,
            },
            ..Default::default()
        };
        let mut brain = Brain::new(cfg).unwrap();

        let samples: [(Array1<f32>, Array1<f32>); 4] = [
            (
                Array1::from_vec(vec![0.0, 0.0]),
                Array1::from_vec(vec![0.0]),
            ),
            (
                Array1::from_vec(vec![0.0, 1.0]),
                Array1::from_vec(vec![1.0]),
            ),
            (
                Array1::from_vec(vec![1.0, 0.0]),
                Array1::from_vec(vec![1.0]),
            ),
            (
                Array1::from_vec(vec![1.0, 1.0]),
                Array1::from_vec(vec![0.0]),
            ),
        ];

        let start = std::time::Instant::now();
        let mut final_loss = f32::INFINITY;
        for _step in 0..5000 {
            let mut mean = 0.0;
            for (x, y) in &samples {
                mean += brain.learn(x, y, 0.1);
            }
            final_loss = mean / 4.0;
            if final_loss < 0.05 {
                break;
            }
        }
        let elapsed = start.elapsed();
        assert!(
            final_loss < 0.05,
            "XOR didn't converge: final_loss={final_loss}"
        );
        assert!(elapsed.as_secs() < 5, "XOR took too long: {:?}", elapsed);

        // Prediction sanity: (1, 0) should be close to 1; (1, 1) close to 0.
        let p10 = brain.predict(&Array1::from_vec(vec![1.0, 0.0]))[0];
        let p11 = brain.predict(&Array1::from_vec(vec![1.0, 1.0]))[0];
        assert!(p10 > 0.5, "predict(1,0)={p10}, expected >0.5");
        assert!(p11 < 0.5, "predict(1,1)={p11}, expected <0.5");
    }

    #[tokio::test]
    async fn save_load_round_trip() {
        let cfg = BrainConfig {
            adaptive: AdaptiveConfig {
                layers: vec![3, 5, 2],
                rng_seed: 7,
                activation: nimcp_adaptive::Activation::Relu,
            },
            ..Default::default()
        };
        let mut a = Brain::new(cfg.clone()).unwrap();
        let x = Array1::from_vec(vec![1.0, -0.5, 0.25]);

        // Train for a few steps so a != b initially.
        for _ in 0..20 {
            a.learn(&x, &Array1::from_vec(vec![0.0, 1.0]), 0.05);
        }
        let y_a = a.predict(&x);

        let tmp = tempfile::NamedTempFile::new().unwrap();
        a.save(tmp.path()).unwrap();

        let mut b = Brain::new(cfg).unwrap();
        b.load(tmp.path()).unwrap();
        let y_b = b.predict(&x);

        for (pa, pb) in y_a.iter().zip(y_b.iter()) {
            assert!((pa - pb).abs() < 1e-6, "save/load drift: {pa} vs {pb}");
        }
    }

    // -------------------------------------------------------------------------
    // Phase 4c tests — 3-network ensemble.
    // -------------------------------------------------------------------------

    fn ensemble_config(seed: u64) -> BrainConfig {
        use nimcp_lnn::LtcParams;
        use nimcp_plasticity::HomeostaticParams;
        use nimcp_snn::network::{EdgeSpec, PopulationSpec};
        use nimcp_snn::{LifParams, RstdpParams};

        let adaptive = AdaptiveConfig {
            layers: vec![4, 8, 2],
            rng_seed: seed,
            activation: nimcp_adaptive::Activation::Tanh,
        };

        // Tiny SNN — just enough to exercise save/load + step.
        let snn = Some(SnnConfig {
            populations: vec![
                PopulationSpec {
                    name: "in".into(),
                    n_neurons: 32,
                    lif: LifParams::default(),
                    target_rate: 0.1,
                    homeostatic: HomeostaticParams::default(),
                },
                PopulationSpec {
                    name: "out".into(),
                    n_neurons: 32,
                    lif: LifParams::default(),
                    target_rate: 0.1,
                    homeostatic: HomeostaticParams::default(),
                },
            ],
            edges: vec![EdgeSpec {
                src: 0,
                dst: 1,
                fan_in: 8,
                weight_init: 1.0,
                weight_jitter: 0.2,
                rstdp: RstdpParams {
                    warmup_samples: 0,
                    w_max: 5.0,
                    ..RstdpParams::default()
                },
            }],
            rng_seed: seed.wrapping_add(1),
            rate_ema_alpha: 0.05,
        });

        let lnn = Some(LnnConfig {
            input_dim: 3,
            output_dim: 1,
            layers: vec![LtcParams {
                n_in: 3,
                n_rec: 8,
                tau_init: 1.0,
                init_scale: 1.0,
            }],
            rng_seed: seed.wrapping_add(2),
            dt_ms: 0.1,
        });

        BrainConfig {
            rng_seed: seed,
            deterministic: true,
            adaptive,
            snn,
            lnn,
            ..Default::default()
        }
    }

    #[tokio::test]
    async fn ensemble_brain_boots_all_three_networks() {
        let brain = Brain::new(ensemble_config(42)).unwrap();
        assert!(brain.snn().is_some(), "SNN should be present");
        assert!(brain.lnn().is_some(), "LNN should be present");
        assert_eq!(brain.snn().unwrap().n_populations(), 2);
        assert_eq!(brain.lnn().unwrap().layers.len(), 1);
    }

    #[tokio::test]
    async fn lnn_train_reduces_loss_inside_brain() {
        let mut brain = Brain::new(ensemble_config(42)).unwrap();
        let inputs: Vec<Array1<f32>> = (0..15)
            .map(|t| Array1::from_vec(vec![(t as f32 * 0.2).sin(), 0.3, -0.1]))
            .collect();
        let targets: Vec<Array1<f32>> = (0..15).map(|_| Array1::from_vec(vec![0.5])).collect();

        let y_before = brain.lnn_forward_sequence(&inputs).unwrap();
        let loss_before = nimcp_lnn::mse_sequence_loss(&y_before, &targets);

        let params = TrainParams {
            lr: 2.0e-2,
            grad_clip: 1.0,
        };
        for _ in 0..50 {
            brain
                .lnn_train_step_mse(&inputs, &targets, &params)
                .unwrap();
        }
        let y_after = brain.lnn_forward_sequence(&inputs).unwrap();
        let loss_after = nimcp_lnn::mse_sequence_loss(&y_after, &targets);

        assert!(
            loss_after < loss_before,
            "brain-routed LNN train did not reduce loss: {loss_before} -> {loss_after}"
        );
    }

    #[tokio::test]
    async fn snn_step_inside_brain_does_not_panic() {
        let mut brain = Brain::new(ensemble_config(42)).unwrap();
        let drive: Vec<f32> = vec![500.0; 32];
        let empty: Vec<f32> = Vec::new();
        let slices: Vec<&[f32]> = vec![&drive, &empty];
        for _ in 0..20 {
            brain.snn_step(&slices, 0.0, 1.0).unwrap();
        }
    }

    /// Phase 4c exit criterion (partial): train all three networks,
    /// save the ensemble atomically to a directory, reboot a fresh
    /// brain with the same config, restore, and verify every network's
    /// output is bit-identical on matched inputs.
    #[tokio::test]
    async fn ensemble_save_load_round_trip() {
        let cfg = ensemble_config(7);
        let mut a = Brain::new(cfg.clone()).unwrap();

        // Train the adaptive + LNN a bit so weights diverge from init.
        let feat = Array1::from_vec(vec![0.2, -0.4, 0.1, 0.9]);
        let tgt = Array1::from_vec(vec![0.7, -0.2]);
        for _ in 0..30 {
            a.learn(&feat, &tgt, 0.05);
        }

        let inputs: Vec<Array1<f32>> = (0..6)
            .map(|t| Array1::from_vec(vec![(t as f32 * 0.1).cos(), 0.2, 0.3]))
            .collect();
        let lnn_targets: Vec<Array1<f32>> = (0..6).map(|_| Array1::from_vec(vec![0.2])).collect();
        let params = TrainParams {
            lr: 1.0e-2,
            grad_clip: 1.0,
        };
        for _ in 0..20 {
            a.lnn_train_step_mse(&inputs, &lnn_targets, &params)
                .unwrap();
        }

        // Step SNN a few times so its weights have moved.
        let drive: Vec<f32> = vec![500.0; 32];
        let empty: Vec<f32> = Vec::new();
        let slices: Vec<&[f32]> = vec![&drive, &empty];
        for _ in 0..20 {
            a.snn_step(&slices, 0.1, 1.0).unwrap();
        }

        // Capture reference outputs.
        let y_adaptive_a = a.predict(&feat);
        let y_lnn_a = a.lnn_forward_sequence(&inputs).unwrap();
        let snn_weights_a: Vec<f32> = a.snn().unwrap().edge_weights(0).to_vec();

        // Save into a directory.
        let tmp = tempfile::tempdir().unwrap();
        let ensemble_dir = tmp.path().join("brain");
        a.save_ensemble(&ensemble_dir).unwrap();
        assert!(ensemble_dir.join("manifest.json").exists());
        assert!(ensemble_dir.join("adaptive.rkyv").exists());
        assert!(ensemble_dir.join("snn.json").exists());
        assert!(ensemble_dir.join("lnn.json").exists());

        // Reboot + load.
        let mut b = Brain::new(cfg).unwrap();
        b.load_ensemble(&ensemble_dir).unwrap();

        // Every network matches a's output.
        let y_adaptive_b = b.predict(&feat);
        for (pa, pb) in y_adaptive_a.iter().zip(y_adaptive_b.iter()) {
            assert!((pa - pb).abs() < 1e-6, "adaptive drift: {pa} vs {pb}");
        }

        let y_lnn_b = b.lnn_forward_sequence(&inputs).unwrap();
        for (t, (ya, yb)) in y_lnn_a.iter().zip(y_lnn_b.iter()).enumerate() {
            for (pa, pb) in ya.iter().zip(yb.iter()) {
                assert!(
                    (pa - pb).abs() < 1e-6,
                    "lnn drift at step {t}: {pa} vs {pb}"
                );
            }
        }

        let snn_weights_b: Vec<f32> = b.snn().unwrap().edge_weights(0).to_vec();
        assert_eq!(
            snn_weights_a, snn_weights_b,
            "snn weights differ after load"
        );
    }

    #[tokio::test]
    async fn ensemble_save_is_atomic_under_partial_failure() {
        // If the target dir already exists with arbitrary contents, a
        // successful save_ensemble must leave only the new layout (no
        // leftover files from the prior content).
        let cfg = ensemble_config(11);
        let a = Brain::new(cfg).unwrap();

        let tmp = tempfile::tempdir().unwrap();
        let dir = tmp.path().join("brain");
        std::fs::create_dir(&dir).unwrap();
        std::fs::write(dir.join("stale.txt"), b"leftover").unwrap();

        a.save_ensemble(&dir).unwrap();
        assert!(
            !dir.join("stale.txt").exists(),
            "stale file survived atomic swap"
        );
        assert!(dir.join("manifest.json").exists());
    }
}
