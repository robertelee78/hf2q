//! ADR-020 iter-13b — DWQ-proper training loop substrate.
//!
//! Provides the wiring for a Track 2 DWQ distillation step:
//!
//!   1. Initialize per-group `scales` + `biases` + frozen `q_int` from
//!      a frozen FP32 weight via mlx-native's `qdq_affine_init_f32`
//!      kernel.
//!   2. Build a forward tape: `qdq_affine(scales, biases, q_int)` →
//!      reconstruction loss against the frozen weight (per-tensor MSE);
//!      scales + biases are leaves registered with [`AdamOptimizer`].
//!   3. Back-propagate via the existing tape `backward`, and apply
//!      `Adam.step`.
//!   4. Repeat until convergence.
//!
//! This iteration ships:
//!   - [`init_affine_params_gpu`] — host-side wrapper that spawns the
//!     init kernel against a frozen weight buffer and reads back
//!     `(q_int, scales_init, biases_init)` to host memory.  Used both
//!     by the synthetic test and (later) by the production
//!     dwq_quantize entry point.
//!   - [`buffer_from_f32`] — small helper that creates a fresh
//!     `MlxBuffer` from host data, shared between Adam parameter
//!     registration and tape leaves.
//!
//! The synthetic 2-Linear MLP convergence test (gated by `#[test]` and
//! `cfg(test)`) is the load-bearing falsifier: if Adam over
//! `(scales1, biases1, scales2, biases2)` doesn't drive the
//! reconstruction MSE down by ≥5× from a perturbed start over 200
//! steps, the chain is broken somewhere (qdq_affine forward/backward,
//! tape accumulation, Adam state, or finite-difference equivalence).
//!
//! Loss this iteration is per-tensor reconstruction MSE
//! (Σ (qdq_w − w)²) rather than logit KL-div — the qdq_affine →
//! reshape → matmul → KL chain requires a tape `view`/reshape op
//! that is iter-13c work.  Reconstruction MSE has the same
//! gradient-correctness load-bearing property and is sufficient to
//! prove the full training-loop primitive.

use anyhow::{anyhow, Context, Result};
use mlx_native::ops::qdq_affine::dispatch_qdq_affine_init_f32;
use mlx_native::{DType, KernelRegistry, MlxBuffer, MlxDevice};

/// Run mlx-native's `qdq_affine_init_f32` kernel against a frozen FP32
/// weight buffer and return CPU copies of `(q_int, scales, biases)`.
///
/// `w` shape: `[n_total]` flat; `n_total = n_groups · group_size`.
/// `group_size`: power of two in `[2, 1024]`, divides `n_total`.
/// `bits`: `[2, 8]`; `n_bins = 2^bits` and must satisfy `n_bins ≤ 256`.
pub fn init_affine_params_gpu(
    device: &MlxDevice,
    registry: &mut KernelRegistry,
    w_data: &[f32],
    group_size: usize,
    bits: u32,
) -> Result<(Vec<u8>, Vec<f32>, Vec<f32>)> {
    if !(2..=8).contains(&bits) {
        return Err(anyhow!(
            "init_affine_params_gpu: bits must be in [2, 8]; got {bits}"
        ));
    }
    let n_total = w_data.len();
    if !group_size.is_power_of_two() || !(2..=1024).contains(&group_size) {
        return Err(anyhow!(
            "init_affine_params_gpu: group_size must be a power of two in [2, 1024]; got {group_size}"
        ));
    }
    if n_total % group_size != 0 {
        return Err(anyhow!(
            "init_affine_params_gpu: n_total ({n_total}) must be divisible by group_size ({group_size})"
        ));
    }
    let n_groups = n_total / group_size;
    let n_bins: u32 = 1u32 << bits;

    let mut w_buf = device
        .alloc_buffer(n_total * 4, DType::F32, vec![n_total])
        .map_err(|e| anyhow!("init_affine: alloc w: {e}"))?;
    w_buf
        .as_mut_slice::<f32>()
        .map_err(|e| anyhow!("init_affine: w write: {e}"))?
        .copy_from_slice(w_data);
    let scales_buf = device
        .alloc_buffer(n_groups * 4, DType::F32, vec![n_groups])
        .map_err(|e| anyhow!("init_affine: alloc scales: {e}"))?;
    let biases_buf = device
        .alloc_buffer(n_groups * 4, DType::F32, vec![n_groups])
        .map_err(|e| anyhow!("init_affine: alloc biases: {e}"))?;
    let q_int_buf = device
        .alloc_buffer(n_total, DType::U8, vec![n_total])
        .map_err(|e| anyhow!("init_affine: alloc q_int: {e}"))?;
    let mut meta_buf = device
        .alloc_buffer(8, DType::U32, vec![2])
        .map_err(|e| anyhow!("init_affine: alloc meta: {e}"))?;
    meta_buf
        .as_mut_slice::<u32>()
        .map_err(|e| anyhow!("init_affine: meta write: {e}"))?[..2]
        .copy_from_slice(&[group_size as u32, n_bins]);

    let mut encoder = device
        .command_encoder()
        .map_err(|e| anyhow!("init_affine: encoder: {e}"))?;
    dispatch_qdq_affine_init_f32(
        &mut encoder,
        registry,
        device.metal_device(),
        &w_buf,
        &scales_buf,
        &biases_buf,
        &q_int_buf,
        &meta_buf,
        group_size as u32,
        n_bins,
    )
    .context("init_affine: dispatch qdq_affine_init_f32")?;
    encoder
        .commit_and_wait()
        .map_err(|e| anyhow!("init_affine: commit_and_wait: {e}"))?;

    let scales = scales_buf
        .as_slice::<f32>()
        .map_err(|e| anyhow!("init_affine: scales readback: {e}"))?
        .to_vec();
    let biases = biases_buf
        .as_slice::<f32>()
        .map_err(|e| anyhow!("init_affine: biases readback: {e}"))?
        .to_vec();
    let q_int = q_int_buf
        .as_slice::<u8>()
        .map_err(|e| anyhow!("init_affine: q_int readback: {e}"))?
        .to_vec();
    Ok((q_int, scales, biases))
}

/// Build a fresh f32 `MlxBuffer` from host data — used by the
/// training loop to wrap Adam-managed parameter state.
pub fn buffer_from_f32(device: &MlxDevice, data: &[f32]) -> Result<MlxBuffer> {
    let mut buf = device
        .alloc_buffer(data.len() * 4, DType::F32, vec![data.len()])
        .map_err(|e| anyhow!("buffer_from_f32: alloc: {e}"))?;
    buf.as_mut_slice::<f32>()
        .map_err(|e| anyhow!("buffer_from_f32: write: {e}"))?
        .copy_from_slice(data);
    Ok(buf)
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::calibrate::adam::{AdamConfig, AdamOptimizer};
    use crate::calibrate::autograd_gpu_tape::{
        backward, ones_like, qdq_affine, square, sub, GpuTape, GpuTensor,
    };
    use std::collections::BTreeMap;

    /// Synthetic 2-tensor DWQ training loop.  Two frozen FP32 weight
    /// tensors `W1`, `W2` are encoded with affine quantization
    /// (per-group min/max init); scales+biases are then PERTURBED by
    /// +5% and Adam is asked to recover them by minimizing the
    /// per-tensor reconstruction MSE
    ///
    ///   L = Σ_i (qdq_W1[i] − W1[i])² + Σ_i (qdq_W2[i] − W2[i])²
    ///
    /// Acceptance: best loss across the trajectory < 0.2 × initial
    /// loss (5× reduction).  The 5% perturbation creates ~10% of the
    /// init loss as headroom, and Adam converges back toward (but not
    /// to, because the integer codes were chosen for the original s+b
    /// pair) the analytical minimum.
    ///
    /// What this falsifies if it fails:
    ///   - qdq_affine forward (mlx-native kernel + Rust dispatch)
    ///   - qdq_affine backward routing into scales+biases parents
    ///   - tape accumulator semantics for OpKind::QdqAffine
    ///   - Adam state register/step with multi-param BTreeMap
    ///   - sub/square/ones_like/backward chain composition
    #[test]
    fn dwq_loop_synthetic_recovers_perturbed_affine_params() {
        let group_size = 32usize;
        // Tensor shapes: arbitrary multiples of group_size.
        let w1_n = group_size * 4; // 128 elements, 4 groups
        let w2_n = group_size * 6; // 192 elements, 6 groups

        let w1: Vec<f32> = (0..w1_n)
            .map(|i| ((i as f32) * 0.0193 - 0.5).sin() * 0.4)
            .collect();
        let w2: Vec<f32> = (0..w2_n)
            .map(|i| ((i as f32) * 0.0241 + 0.3).cos() * 0.3)
            .collect();

        let device = MlxDevice::new().expect("device");
        let mut init_registry = KernelRegistry::new();

        let (q1, s1_init, b1_init) =
            init_affine_params_gpu(&device, &mut init_registry, &w1, group_size, 4)
                .expect("init w1");
        let (q2, s2_init, b2_init) =
            init_affine_params_gpu(&device, &mut init_registry, &w2, group_size, 4)
                .expect("init w2");

        // Perturb +5% to give Adam something to learn.
        let perturb = |xs: &[f32], factor: f32| -> Vec<f32> {
            xs.iter().map(|v| v * factor).collect()
        };
        let s1_p = perturb(&s1_init, 1.05);
        let b1_p = perturb(&b1_init, 1.05);
        let s2_p = perturb(&s2_init, 1.05);
        let b2_p = perturb(&b2_init, 1.05);

        let cfg = AdamConfig {
            lr: 0.005,
            beta1: 0.9,
            beta2: 0.999,
            eps: 1e-8,
        };
        let mut adam = AdamOptimizer::new(device.clone(), cfg).expect("adam");
        adam.register_param("s1", buffer_from_f32(&device, &s1_p).unwrap())
            .unwrap();
        adam.register_param("b1", buffer_from_f32(&device, &b1_p).unwrap())
            .unwrap();
        adam.register_param("s2", buffer_from_f32(&device, &s2_p).unwrap())
            .unwrap();
        adam.register_param("b2", buffer_from_f32(&device, &b2_p).unwrap())
            .unwrap();

        // Single shared tape — `tape.reset()` between iterations drops
        // per-step nodes without device churn (mantra: avoid Metal
        // residency-set contention from per-iter MlxDevice::new()).
        let tape = GpuTape::new(device.clone());

        let train_step = |adam: &mut AdamOptimizer, tape: &GpuTape| -> Result<f32> {
            let s1 = adam.read_param("s1")?;
            let b1 = adam.read_param("b1")?;
            let s2 = adam.read_param("s2")?;
            let b2 = adam.read_param("b2")?;

            let s1_leaf = GpuTensor::from_vec(tape, &s1, vec![s1.len()])?;
            let b1_leaf = GpuTensor::from_vec(tape, &b1, vec![b1.len()])?;
            let s2_leaf = GpuTensor::from_vec(tape, &s2, vec![s2.len()])?;
            let b2_leaf = GpuTensor::from_vec(tape, &b2, vec![b2.len()])?;

            let qdq1 = qdq_affine(&s1_leaf, &b1_leaf, &q1, group_size)?;
            let qdq2 = qdq_affine(&s2_leaf, &b2_leaf, &q2, group_size)?;
            let w1_const = GpuTensor::from_vec(tape, &w1, vec![w1.len()])?;
            let w2_const = GpuTensor::from_vec(tape, &w2, vec![w2.len()])?;
            let r1 = sub(&qdq1, &w1_const)?;
            let r2 = sub(&qdq2, &w2_const)?;
            let sq1 = square(&r1)?;
            let sq2 = square(&r2)?;

            // Loss = Σ sq1 + Σ sq2 (host reduction; no GPU sum kernel
            // yet).  Backward seeds dy = ones for each subgraph; the
            // accumulator merges contributions to s1/b1/s2/b2 leaves.
            let sq1_host = sq1.to_vec()?;
            let sq2_host = sq2.to_vec()?;
            let loss = sq1_host.iter().map(|v| *v as f64).sum::<f64>()
                + sq2_host.iter().map(|v| *v as f64).sum::<f64>();

            let dy1 = ones_like(tape, sq1.shape())?;
            let g1 = backward(&sq1, dy1)?;
            let dy2 = ones_like(tape, sq2.shape())?;
            let g2 = backward(&sq2, dy2)?;

            let grad_s1 = g1[s1_leaf.node_idx()]
                .as_ref()
                .ok_or_else(|| anyhow!("missing s1 grad"))?
                .clone();
            let grad_b1 = g1[b1_leaf.node_idx()]
                .as_ref()
                .ok_or_else(|| anyhow!("missing b1 grad"))?
                .clone();
            let grad_s2 = g2[s2_leaf.node_idx()]
                .as_ref()
                .ok_or_else(|| anyhow!("missing s2 grad"))?
                .clone();
            let grad_b2 = g2[b2_leaf.node_idx()]
                .as_ref()
                .ok_or_else(|| anyhow!("missing b2 grad"))?
                .clone();

            let mut grads = BTreeMap::new();
            grads.insert("s1".to_string(), grad_s1);
            grads.insert("b1".to_string(), grad_b1);
            grads.insert("s2".to_string(), grad_s2);
            grads.insert("b2".to_string(), grad_b2);
            adam.step(&grads)?;
            Ok(loss as f32)
        };

        let initial_loss = train_step(&mut adam, &tape).expect("initial step");
        // Drop nodes from step 0 — keep device + registry warm.
        tape.reset();
        let mut min_loss = initial_loss;
        let n_steps = 200usize;
        let mut last_loss = initial_loss;
        for step in 1..n_steps {
            let l = train_step(&mut adam, &tape).expect("step");
            tape.reset();
            if l < min_loss {
                min_loss = l;
            }
            last_loss = l;
            if step % 50 == 0 {
                eprintln!(
                    "[dwq_synth] step={step} loss={l:.6} min={min_loss:.6} initial={initial_loss:.6}"
                );
            }
        }

        // Acceptance: 5× reduction floor.  Robust to late-stage Adam
        // jitter at small loss values.
        assert!(
            min_loss < initial_loss * 0.2,
            "DWQ synthetic loop did not converge: initial={initial_loss}, min_seen={min_loss}, last={last_loss}"
        );

        // Sanity: final scales/biases should be CLOSER to the analytical
        // optimum than the perturbed start (norm-of-difference).
        let s1_final = adam.read_param("s1").unwrap();
        let b1_final = adam.read_param("b1").unwrap();
        let dist_init = s1_p
            .iter()
            .zip(s1_init.iter())
            .map(|(a, b)| ((a - b).powi(2)) as f64)
            .sum::<f64>()
            + b1_p
                .iter()
                .zip(b1_init.iter())
                .map(|(a, b)| ((a - b).powi(2)) as f64)
                .sum::<f64>();
        let dist_final = s1_final
            .iter()
            .zip(s1_init.iter())
            .map(|(a, b)| ((a - b).powi(2)) as f64)
            .sum::<f64>()
            + b1_final
                .iter()
                .zip(b1_init.iter())
                .map(|(a, b)| ((a - b).powi(2)) as f64)
                .sum::<f64>();
        assert!(
            dist_final < dist_init,
            "Adam did not move toward analytical optimum: dist_init={dist_init}, dist_final={dist_final}"
        );
    }

    /// Sanity test: init kernel output equals the CPU oracle from the
    /// mlx-native side via the host-side wrapper.
    #[test]
    fn init_affine_params_gpu_round_trip_recovers_w_within_quant_error() {
        let device = MlxDevice::new().expect("device");
        let mut registry = KernelRegistry::new();
        let group_size = 32usize;
        let n_groups = 3usize;
        let n_total = group_size * n_groups;
        let w: Vec<f32> = (0..n_total)
            .map(|i| ((i as f32) * 0.51).sin() + ((i as f32) * 0.123).cos() * 0.3)
            .collect();
        let (q, s, b) =
            init_affine_params_gpu(&device, &mut registry, &w, group_size, 4).unwrap();
        assert_eq!(q.len(), n_total);
        assert_eq!(s.len(), n_groups);
        assert_eq!(b.len(), n_groups);
        for g in 0..n_groups {
            for i in 0..group_size {
                let idx = g * group_size + i;
                let qdq = q[idx] as f32 * s[g] + b[g];
                let bound = s[g] * 0.5 + 1e-6;
                assert!(
                    (qdq - w[idx]).abs() <= bound,
                    "qdq[{idx}]={} w[{idx}]={}",
                    qdq,
                    w[idx]
                );
            }
        }
    }
}
