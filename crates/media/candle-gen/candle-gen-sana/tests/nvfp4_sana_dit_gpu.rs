//! **sc-11045 — NVFP4 validation on a real Sana-1.6B denoise, consumer Blackwell `sm_120`** (epic
//! 11037). The end-to-end half of the epic's validation: everything before this measured *layers*
//! (sc-11041/sc-11044, synthetic or single-weight); this drives the **whole SANA-1.6B Linear-DiT trunk
//! through a real 20-step flow-match denoise with real weights and a real prompt**, on the FP4 tensor
//! cores, and compares it against the dense f32 baseline.
//!
//! What each gate pins:
//!
//! 1. [`nvfp4_sana_dit_real_denoise_no_nan_and_parity_vs_dense`] — **SC#3 + SC#2.** A full txt2img
//!    (real gemma-2-2b-it caption encode → 20-step true-CFG flow-match Euler denoise over the NVFP4
//!    trunk → DC-AE decode) with the NaN guard armed on **every** projection at **every** step, then
//!    the same seed/prompt through the dense f32 trunk. Asserts no NaN/inf anywhere, output coherence,
//!    and quality parity (latent rel-RMS / cosine, decoded-image PSNR).
//! 2. [`nvfp4_sana_dit_real_throughput_dense_vs_w4a16_vs_w4a4`] — **NOT SC#1** (Sana has no bf16
//!    baseline or Q4 tier; see the test's docs and sc-12110). Post-sc-12111 ms/step for the dense
//!    baseline vs NVFP4 W4A16 vs W4A4, after removing Candle's launch-bound depthwise-conv defect.
//! 3. [`nvfp4_sana_dit_real_model_vram_footprint`] — **SC#6, scoped to blanket W4A4.** Model-level
//!    resident weight bytes == the NVFP4 footprint under the packed path, by contention-immune tensor
//!    byte-accounting — and the honest per-regime cost (mixed 0.70×, blanket W4A16 1.00×) alongside it.
//! 4. [`nvfp4_sana_dit_real_activation_outlier_sparsity`] — **the spike's residual empirical gate.**
//!    Real per-layer activation-outlier sparsity captured across real denoise steps, checked against
//!    the assumed benign→W4A4 / outlier→W4A16 partition. Emulation could not close this; a live model
//!    can.
//!
//! All are `#[cfg(feature = "cuda")]` + `#[ignore]`d + weight-gated per repo convention (the CPU lane
//! compiles test targets WITHOUT cuda). The negative half of the SC#4 capability gate — an NVFP4 plan
//! falling back cleanly off `sm_120` — is a CPU-lane unit test
//! (`transformer::tests::nvfp4_plan_falls_back_cleanly_off_blackwell`); the positive half (`fp4_lit >
//! 0` on real `sm_120`) is asserted here in gates 1–3.
//!
//! Weights: the whole `Efficient-Large-Model/Sana_1600M_1024px_diffusers` HF snapshot (transformer +
//! text_encoder + tokenizer + vae). Passed in via `SC11045_SANA_SNAPSHOT` — inference never
//! self-fetches or derives a cache location (epic 13657); unset ⇒ the test SKIPs.
//!
//! Run (exclusive GPU, `--release`; `-j 1` avoids lld OOM):
//! ```text
//! CUDA_COMPUTE_CAP=120 cargo test --locked -j 1 -p candle-gen-sana --test nvfp4_sana_dit_gpu \
//!     --features cuda --release -- --ignored --nocapture
//! ```

#![cfg(feature = "cuda")]

use std::path::PathBuf;
use std::sync::Arc;
use std::time::Instant;

use candle_gen::candle_core::{DType, Device, Tensor};
use candle_gen::gen_core::{CancelFlag, Image, PreviewSink, Progress};
use candle_gen::preview::PreviewHook;
use candle_gen::quant::{ActPrecision, CublasLt, OutlierClass};
use candle_gen::Weights;
use candle_gen_sana::pipeline::{
    create_noise, decode_to_image, denoise_cfg, load_text_encoder, resolve_component_files,
    sana_sigmas, DEFAULT_GUIDANCE,
};
use candle_gen_sana::{
    summarize, ActProbe, DcAeConfig, DcAeDecoder, DitPlan, LayerRole, Nvfp4Quant, SanaTransformer,
    SanaTransformerConfig,
};

/// The HF repo the validation runs against.
// retained as provenance; TODO(sc-13685/epic-13678) — the HF-cache snapshot fallback that read this
// pin was removed under epic 13657 (inference never self-fetches; the snapshot is passed in via
// SC11045_SANA_SNAPSHOT), leaving the pin as the provenance record of the parity target.
#[allow(dead_code)]
const SANA_REPO: &str = "Efficient-Large-Model/Sana_1600M_1024px_diffusers";
/// A concrete, detail-rich prompt — a degenerate/empty prompt would not exercise the caption path the
/// outlier class lives on.
const PROMPT: &str =
    "a photograph of a red fox standing in tall grass at golden hour, sharp detail, shallow depth of field";
const NEGATIVE: &str = "";
/// Fixed seed — parity is measured on the SAME seed/prompt through both trunks.
const SEED: u64 = 11045;
/// diffusers `SanaPipeline` default; the full denoise, not a truncated one.
const STEPS: usize = 20;
/// 1024px → a 32×32 DC-AE latent → 1024 DiT tokens (the real serving shape).
const EDGE: u32 = 1024;

/// The Sana snapshot root from the `SC11045_SANA_SNAPSHOT` env (a passed-in snapshot dir). Unset or
/// non-dir → the test SKIPs. Inference never self-fetches or derives a cache location (epic 13657).
fn snapshot_root() -> Option<PathBuf> {
    let Ok(p) = std::env::var("SC11045_SANA_SNAPSHOT") else {
        eprintln!("[sc-11045] SC11045_SANA_SNAPSHOT unset; skipping");
        return None;
    };
    let p = PathBuf::from(p);
    if p.is_dir() {
        Some(p)
    } else {
        eprintln!("[sc-11045] SC11045_SANA_SNAPSHOT={p:?} is not a directory; skipping");
        None
    }
}

/// A CUDA device iff one exists AND it is Blackwell `sm_120` (the NVFP4 floor) — else `None` + a SKIP
/// note. This is the SC#4 gate in its positive form: below the floor these gates do not claim anything.
fn nvfp4_device() -> Option<Device> {
    let dev = match Device::cuda_if_available(0) {
        Ok(d @ Device::Cuda(_)) => d,
        _ => {
            eprintln!("[sc-11045] no CUDA device; skipping");
            return None;
        }
    };
    let lt = CublasLt::new(&dev).expect("cuBLASLt handle");
    match lt.meets_nvfp4_floor() {
        Ok(true) => {
            eprintln!(
                "[sc-11045] device cap = {:?} (NVFP4 eligible)",
                lt.compute_cap().unwrap()
            );
            Some(dev)
        }
        _ => {
            eprintln!(
                "[sc-11045] device not sm_120 ({:?}); skipping — NVFP4 is Blackwell-only (SC#4)",
                lt.compute_cap().ok()
            );
            None
        }
    }
}

/// Encode the prompt + negative prompt with the **real** gemma-2-2b-it caption encoder, then drop the
/// encoder (≈10 GB f32) before any trunk is built. Returns `(cond, uncond)` `[1, 300, 2304]`.
fn encode_conditioning(root: &std::path::Path, dev: &Device) -> (Tensor, Tensor) {
    let te = load_text_encoder(root, dev).expect("load gemma-2-2b-it caption encoder");
    let cond = te.encode(PROMPT).expect("encode prompt");
    let uncond = te.encode(NEGATIVE).expect("encode negative prompt");
    drop(te);
    eprintln!(
        "[sc-11045] conditioning encoded (real gemma-2-2b-it): cond {:?}, uncond {:?}",
        cond.dims(),
        uncond.dims()
    );
    (cond, uncond)
}

/// The trunk's f32 weights, loaded once (the caller builds several plans against them).
fn trunk_weights(root: &std::path::Path, dev: &Device) -> Weights {
    let files = resolve_component_files(&root.join("transformer")).expect("resolve trunk shards");
    Weights::from_files(&files, dev, DType::F32).expect("load Sana-1.6B trunk weights")
}

fn to_vec_f32(t: &Tensor) -> Vec<f32> {
    t.to_dtype(DType::F32)
        .unwrap()
        .flatten_all()
        .unwrap()
        .to_vec1::<f32>()
        .unwrap()
}

fn rel_rms(got: &[f32], reference: &[f32]) -> f64 {
    let (mut num, mut den) = (0f64, 0f64);
    for (g, r) in got.iter().zip(reference) {
        num += (*g as f64 - *r as f64).powi(2);
        den += (*r as f64).powi(2);
    }
    (num / den.max(1e-30)).sqrt()
}

/// PSNR (dB) between two RGB8 images — the standard "no visible quality regression" metric.
fn psnr(a: &Image, b: &Image) -> f64 {
    assert_eq!(a.pixels.len(), b.pixels.len(), "image size mismatch");
    let mse = a
        .pixels
        .iter()
        .zip(&b.pixels)
        .map(|(x, y)| {
            let d = *x as f64 - *y as f64;
            d * d
        })
        .sum::<f64>()
        / a.pixels.len() as f64;
    if mse <= f64::EPSILON {
        return f64::INFINITY;
    }
    10.0 * (255.0f64 * 255.0 / mse).log10()
}

/// Std-dev of an image's pixels — a coherence floor. A collapsed/garbage denoise produces a flat or
/// saturated field; a real image has structure.
fn pixel_std(img: &Image) -> f64 {
    let n = img.pixels.len() as f64;
    let mean = img.pixels.iter().map(|p| *p as f64).sum::<f64>() / n;
    (img.pixels
        .iter()
        .map(|p| (*p as f64 - mean).powi(2))
        .sum::<f64>()
        / n)
        .sqrt()
}

/// Run the real 20-step true-CFG flow-match denoise over `model`, driving `probe`'s step counter from
/// the sampler's own progress events when one is attached. Returns the final latent.
fn run_denoise(
    model: &SanaTransformer,
    cond: &Tensor,
    uncond: &Tensor,
    dev: &Device,
    probe: Option<&Arc<ActProbe>>,
    steps: usize,
) -> Tensor {
    let sigmas = sana_sigmas(None, steps);
    let latents = create_noise(dev, SEED, EDGE, EDGE).expect("seed latent");
    let cancel = CancelFlag::default();
    let mut on_progress = |p: Progress| {
        if let (Progress::Step { current, .. }, Some(pr)) = (p, probe) {
            pr.set_step(current as usize);
        }
    };
    // sc-16959: the denoise takes its preview hook by reference rather than as an `Option`, so this
    // NVFP4 harness supplies one over an inert sink — byte-identical to a run without the seam, and
    // one `is_active()` check per evaluation.
    let inert = PreviewSink::default();
    let preview = PreviewHook::new(&inert, candle_gen_sana::preview::project_base_latents);
    denoise_cfg(
        model,
        &sigmas,
        None,
        SEED,
        latents,
        cond,
        Some(uncond),
        DEFAULT_GUIDANCE,
        dev,
        &cancel,
        &mut on_progress,
        &preview,
    )
    .expect("denoise must not fail (a NaN guard trip surfaces here)")
}

// ==============================================================================================
// (1) SC#3 denoise stability + SC#2 quality parity, on a real end-to-end generation.
// ==============================================================================================

/// **SC#3 (no NaN across all steps + coherence) and SC#2 (no quality regression).**
///
/// Runs the complete SANA-1.6B txt2img twice from the same seed and prompt — once through the NVFP4
/// trunk under the shipping mixed-precision policy with [`DitPlan::checked`] arming the sc-11044
/// NaN/inf guard on every projection at every step, once through the dense f32 trunk — then compares.
///
/// The NaN gate is **stronger than a final-latent check**: `forward_checked` reduces every projection's
/// output at every step, so a non-finite value fails loud at the layer and step that produced it. 20
/// steps × 2 CFG branches × 163 projections = 6,520 guarded forwards.
#[test]
#[ignore = "real-weight GPU test: needs the Sana-1.6B snapshot + an sm_120 device"]
fn nvfp4_sana_dit_real_denoise_no_nan_and_parity_vs_dense() {
    let Some(dev) = nvfp4_device() else { return };
    let Some(root) = snapshot_root() else { return };

    let (cond, uncond) = encode_conditioning(&root, &dev);
    let w = trunk_weights(&root, &dev);
    let cfg = SanaTransformerConfig::sana_1600m();

    // The DC-AE decoder (shared by every run).
    let dcfg = DcAeConfig::sana_f32c32();
    let vae_files = resolve_component_files(&root.join("vae")).expect("resolve vae");
    let vae_w = Weights::from_files(&vae_files, &dev, DType::F32).expect("load vae");
    let decoder = DcAeDecoder::from_weights(&vae_w, dcfg.clone()).expect("build DC-AE decoder");
    drop(vae_w);

    // One regime's full generation: build the trunk, denoise, decode.
    struct Run {
        label: &'static str,
        latent: Vec<f32>,
        img: Image,
        secs: f64,
    }

    let run_regime = |label: &'static str, plan: DitPlan| -> Run {
        let model =
            SanaTransformer::from_weights_planned(&w, cfg.clone(), &plan).expect("build trunk");
        let r = model.nvfp4_report();
        if plan.is_nvfp4() {
            // Report RESIDENT bytes next to the ratio, not the packed host container. This line is
            // where the sc-11045 review caught MAJOR 3: it used to print the format's 437.56 MiB and
            // "ratio 0.2822" for THIS leg — the one reporting 163/163 dequant→bf16, with nothing
            // packed on-device. Resident and packed are different questions; print both, labelled.
            let mib = |b: usize| b as f64 / (1024.0 * 1024.0);
            eprintln!(
                "[sc-11045] {label}: {} projections quantized — {} FP4-lit (W4A4), {} dequant→bf16 \
                 (W4A16); RESIDENT {:.2} MiB (= {:.2} FP4 + {:.2} bf16) vs dense bf16 {:.2} MiB \
                 → ratio {:.4}. [packed NVFP4 format: {:.2} MiB, {:.2} eff bits/wt]",
                r.n_quantized,
                r.fp4_lit,
                r.dequant_bf16,
                mib(r.resident_bytes()),
                mib(r.resident_fp4_bytes),
                mib(r.dequant_bf16_bytes),
                mib(r.bf16_bytes),
                r.footprint_ratio(),
                mib(r.nvfp4_bytes),
                r.effective_bits(),
            );
        }
        let t0 = Instant::now();
        // A NaN-guard trip inside any projection at any step panics here — the SC#3 gate.
        let latent = run_denoise(&model, &cond, &uncond, &dev, None, STEPS);
        dev.synchronize().unwrap();
        let secs = t0.elapsed().as_secs_f64();
        let lat = to_vec_f32(&latent);
        assert!(
            lat.iter().all(|v| v.is_finite()),
            "{label}: non-finite latent after {STEPS} steps (SC#3)"
        );
        let img = decode_to_image(&decoder, &dcfg, &latent).expect("decode latent");
        Run {
            label,
            latent: lat,
            img,
            secs,
        }
    };

    // Three regimes, same seed + prompt. The W4A16 leg is the diagnostic that separates **weight**
    // quantization error from **activation** quantization error: it packs the same NVFP4 weights but
    // keeps activations full-precision, so `mixed − w4a16` is the cost of FP4 activations alone.
    let dense = run_regime("dense f32 baseline", DitPlan::dense());
    let w4a16 = run_regime(
        "NVFP4 W4A16 (storage tier, shipping default)",
        DitPlan::nvfp4(Nvfp4Quant::BlanketW4A16).checked(),
    );
    let mixed = run_regime(
        "NVFP4 mixed policy (W4A4 on the benign class)",
        DitPlan::nvfp4(Nvfp4Quant::Mixed).checked(),
    );

    // ---- SC#3: stability + coherence. The NaN guard armed on every projection at every step never
    // tripped (a trip panics in `run_regime`); and no image may be a flat/degenerate field. ----
    eprintln!("\n[sc-11045] ===== SC#3 STABILITY (real {STEPS}-step denoise, seed {SEED}) =====");
    for r in [&dense, &w4a16, &mixed] {
        let s = pixel_std(&r.img);
        eprintln!(
            "[sc-11045]   {:<46} no NaN/inf across all steps; pixel std {:.2}; {:.1}s",
            r.label, s, r.secs
        );
        assert!(
            s > 10.0,
            "{}: image is degenerate (pixel std {s:.2}) — denoise collapsed (SC#3)",
            r.label
        );
    }

    // ---- SC#2: quality parity vs the dense f32 baseline. ----
    let metrics = |r: &Run| -> (f64, f32, f64) {
        (
            rel_rms(&r.latent, &dense.latent),
            candle_gen::testkit::cosine(&r.latent, &dense.latent),
            psnr(&r.img, &dense.img),
        )
    };
    let (rr_a, cos_a, p_a) = metrics(&w4a16);
    let (rr_m, cos_m, p_m) = metrics(&mixed);
    eprintln!(
        "\n[sc-11045] ===== SC#2 PARITY vs dense f32 (real {STEPS}-step denoise, seed {SEED}) =====\n\
         [sc-11045]   {:<46} rel-RMS {:.5}  cosine {:.5}  PSNR {:6.2} dB\n\
         [sc-11045]   {:<46} rel-RMS {:.5}  cosine {:.5}  PSNR {:6.2} dB\n\
         [sc-11045]   ⇒ NVFP4 4-bit WEIGHTS account for {:.5} of the cosine divergence from f32.\n\
         [sc-11045]   ⇒ FP4 ACTIVATIONS on the benign class add {:+.5} on top of that — the isolated\n\
         [sc-11045]     cost of W4A4 once the weight tier is held fixed (negative = no cost).",
        w4a16.label,
        rr_a,
        cos_a,
        p_a,
        mixed.label,
        rr_m,
        cos_m,
        p_m,
        1.0 - cos_a,
        cos_a - cos_m,
    );

    // ---- What is and is NOT gated here, and why. ----
    //
    // Both NVFP4 regimes diverge from the f32 trajectory by a similar, substantial margin (cosine
    // ~0.82, PSNR ~16 dB) while producing coherent images. That divergence is **4-bit weight
    // quantization**, not an NVFP4 defect: a 20-step flow-match denoise is chaotic, so a per-step
    // perturbation of the size a ~4.5-bit weight tier necessarily introduces walks the sampler onto a
    // different — but equally valid — trajectory. Reference-trajectory cosine/PSNR against **f32**
    // therefore measures *divergence*, not *quality*, and no 4-bit tier of any kind would pass a
    // "cosine > 0.95 vs f32" bar. (The spike's own weight-only figure was rel-RMS ~0.094 per layer,
    // matching the shipping int4 tier — sc-11038.) Settling SC#2 properly needs a comparison against
    // **the int4 Q4 tier NVFP4 replaces**, not against f32 — recorded as a follow-up, not asserted here.
    //
    // What this test CAN gate — and what the epic's actual W4A4 risk is — is the **marginal** cost of
    // FP4 activations over the W4A16 storage tier, holding the weight tier fixed. That isolates exactly
    // the sc-7702 collapse mechanism the mixed policy exists to prevent.

    // GATE 1: W4A4 on the benign class must cost no meaningful quality over W4A16. If the partition
    // were wrong, collapsing layers would show up here as a quality drop.
    //
    // Scope this honestly: this gate is an end-to-end *quality* check, and it is **not** the evidence
    // that sc-11045's original partition was too permissive — that finding comes from the direct
    // per-layer measurement in `nvfp4_sana_dit_real_activation_outlier_sparsity` (27 of 109 W4A4-
    // assigned projections measured `OutlierClass::Dense`, crush up to 5124×), which is the gate that
    // actually re-partitions. Whether a given Dense layer's damage survives 20 denoise steps into a
    // measurable cosine drop here is a separate question this test does not answer, and asserting it
    // does would be claiming a demonstration we have not run.
    assert!(
        cos_m >= cos_a - 0.02,
        "NVFP4 W4A4 on the benign class costs {:.5} cosine vs the W4A16 storage tier ({cos_m:.5} vs \
         {cos_a:.5}) — FP4 activations are degrading the denoise, i.e. the benign→W4A4 partition is \
         letting an outlier-carrying layer through (sc-7702 mechanism)",
        cos_a - cos_m
    );

    // GATE 2: neither regime may COLLAPSE. The spike's dense-outlier collapse drove cosine to ~0.000;
    // a real quantization trajectory stays far above this floor.
    for (label, cos) in [(w4a16.label, cos_a), (mixed.label, cos_m)] {
        assert!(
            cos > 0.5,
            "{label}: latent cosine {cos:.5} is the sc-7702 collapse signature, not quantization noise"
        );
    }
}

// ==============================================================================================
// (2) Throughput — informational. NOT SC#1's number of record; see the doc comment.
// ==============================================================================================

/// **Throughput of the real trunk — dense f32 baseline vs NVFP4 W4A16 vs NVFP4 W4A4.**
///
/// Times whole denoise steps (both CFG branches) on the real SANA-1.6B trunk at the real serving shape,
/// on the exclusive GPU. Informational assertions only.
///
/// # Do NOT quote the vs-dense ratios as SC#1
///
/// **Sana cannot settle SC#1** (sc-11045 review; tracked as
/// [sc-12110](https://app.shortcut.com/trefry/story/12110)) because it has no bf16 path (the trunk is
/// f32-only) and no Q4 tier, so neither SC#1's specified baseline nor SC#2's honest comparison exists.
///
/// Before sc-12111, SANA's Mix-FFN `conv_depth` (3×3 depthwise, `groups = 2·hidden = 11200`) cost
/// **982 ms/call**: Candle launched one convolution per group and concatenated 11,200 tensors. Across
/// 20 blocks that was **19.65 s of a 21.05 s step**, so the old end-to-end ratios were not useful.
/// The pinned Candle PR #3531 removes that launch-bound path. This benchmark is now the post-fix
/// number of record for SANA and re-exposes the linear/activation-quantization work, while SC#1/SC#2
/// remain settled on a Flux-family DiT under sc-12110.
///
/// Post-fix record on the exclusive RTX PRO 6000 rig: **4.042 ms/call** for the isolated realistic
/// `conv_depth` shape, **315.1 ms/step dense f32**, and **316.7 ms/step W4A16** (down from
/// 982 ms/call and 21.05 s/step). With the convolution bottleneck gone, the unfused activation
/// quantizer tracked by sc-12078 is explicit: **8.42 s/step blanket W4A4** and **4.34 s/step mixed
/// W4A4/W4A16**.
#[test]
#[ignore = "real-weight GPU bench: needs the Sana-1.6B snapshot + an exclusive sm_120 device"]
fn nvfp4_sana_dit_real_throughput_dense_vs_w4a16_vs_w4a4() {
    let Some(dev) = nvfp4_device() else { return };
    let Some(root) = snapshot_root() else { return };

    let (cond, uncond) = encode_conditioning(&root, &dev);
    let w = trunk_weights(&root, &dev);
    let cfg = SanaTransformerConfig::sana_1600m();
    // Fewer steps than the parity run: per-step cost is what is measured, and each variant pays a full
    // trunk build. 6 steps amortizes warmup while keeping three model builds affordable.
    let bench_steps = 6usize;

    let time_plan = |label: &str, plan: DitPlan| -> f64 {
        let model =
            SanaTransformer::from_weights_planned(&w, cfg.clone(), &plan).expect("build trunk");
        let r = model.nvfp4_report();
        // Warmup (kernel autotune / allocator) — one full step, untimed.
        let _ = run_denoise(&model, &cond, &uncond, &dev, None, 1);
        dev.synchronize().unwrap();
        let t0 = Instant::now();
        let out = run_denoise(&model, &cond, &uncond, &dev, None, bench_steps);
        dev.synchronize().unwrap();
        let per_step = t0.elapsed().as_secs_f64() / bench_steps as f64;
        assert!(
            to_vec_f32(&out).iter().all(|v| v.is_finite()),
            "{label} bench produced a non-finite latent"
        );
        eprintln!(
            "[sc-11045] {label}: {:.1} ms/step ({} quantized, {} FP4-lit, {} dequant-bf16)",
            per_step * 1e3,
            r.n_quantized,
            r.fp4_lit,
            r.dequant_bf16
        );
        per_step
    };

    let t_dense = time_plan("dense f32 baseline", DitPlan::dense());
    let t_w4a16 = time_plan(
        "NVFP4 W4A16 (blanket, storage tier)",
        DitPlan::nvfp4(Nvfp4Quant::BlanketW4A16),
    );
    let t_w4a4 = time_plan(
        "NVFP4 W4A4 (blanket, FP4 compute)",
        DitPlan::nvfp4(Nvfp4Quant::BlanketW4A4),
    );
    let t_mixed = time_plan(
        "NVFP4 mixed policy (shipping default)",
        DitPlan::nvfp4(Nvfp4Quant::Mixed),
    );

    eprintln!(
        "\n[sc-12111] ===== POST-FIX SANA THROUGHPUT, NOT SC#1 (real SANA-1.6B trunk, {EDGE}px, {bench_steps} steps, \
         true CFG, EXCLUSIVE GPU) =====\n\
         [sc-11045]   dense f32 baseline : {:8.1} ms/step   (1.00×)\n\
         [sc-11045]   NVFP4 W4A16        : {:8.1} ms/step   ({:.2}× vs dense)\n\
         [sc-11045]   NVFP4 W4A4         : {:8.1} ms/step   ({:.2}× vs dense, {:.2}× vs W4A16)\n\
         [sc-11045]   NVFP4 mixed policy : {:8.1} ms/step   ({:.2}× vs dense)\n",
        t_dense * 1e3,
        t_w4a16 * 1e3,
        t_dense / t_w4a16,
        t_w4a4 * 1e3,
        t_dense / t_w4a4,
        t_w4a16 / t_w4a4,
        t_mixed * 1e3,
        t_dense / t_mixed,
    );
    assert!(t_dense > 0.0 && t_w4a16 > 0.0 && t_w4a4 > 0.0 && t_mixed > 0.0);
}

// ==============================================================================================
// (3) SC#6 — model-level resident VRAM == the NVFP4 footprint.
// ==============================================================================================

/// **SC#6 — scoped to what it actually proves: under BLANKET W4A4, the NVFP4-loaded trunk is served
/// natively packed**, its resident weight bytes equal the NVFP4 footprint (~4.5 effective
/// bits/weight), never a bf16 expansion.
///
/// **Read the scope.** Blanket W4A4 is *not* a shipping regime ([`Nvfp4Quant::BlanketW4A4`]'s own
/// docs say so) — it is the controlled bench that isolates the packed path. SC#6's claim is therefore
/// a claim about **the packed serving path**, not about what SceneWorks ships. This test now measures
/// and prints **all three regimes** so the shipping cost is on the record next to the claim
/// (sc-11045 review, MAJOR 3):
///
/// * **blanket W4A4** — every projection packed on-device. ~0.28× bf16. This is the SC#6 gate.
/// * **mixed (the shipping policy)** — the outlier class holds *dense bf16*, so resident VRAM sits
///   well above the NVFP4 footprint, in proportion to how much of the trunk the outlier class covers.
/// * **blanket W4A16 (the README's throughput default)** — **nothing** is packed on-device and every
///   weight is resident dense bf16: **1.0×, i.e. no footprint win at all.** The NVFP4 packing buys
///   numerical stability and load-time storage here, not VRAM.
///
/// Measured the contention-immune way (as sc-11041 did at layer level): sum the actual resident
/// buffers the trunk holds, rather than reading `nvidia-smi`/`mem_get_info` (which any other workload,
/// allocator slack, or cuBLASLt workspace would contaminate).
#[test]
#[ignore = "real-weight GPU test: needs the Sana-1.6B snapshot + an sm_120 device"]
fn nvfp4_sana_dit_real_model_vram_footprint() {
    let Some(dev) = nvfp4_device() else { return };
    let Some(root) = snapshot_root() else { return };

    let w = trunk_weights(&root, &dev);
    let cfg = SanaTransformerConfig::sana_1600m();
    let mib = |b: usize| b as f64 / (1024.0 * 1024.0);

    // ---- Report the truth for EVERY regime, not just the flattering one. --------------------
    eprintln!(
        "\n[sc-11045] ===== MODEL-LEVEL RESIDENT VRAM by regime (real SANA-1.6B trunk) =====\n\
         [sc-11045] {:<22} {:>6} {:>7} {:>12} {:>12} {:>12} {:>8}",
        "regime", "lit", "dequant", "resid FP4", "resid bf16", "resid total", "ratio"
    );
    let mut measured = Vec::new();
    for (label, quant) in [
        ("blanket W4A4", Nvfp4Quant::BlanketW4A4),
        ("mixed (shipping)", Nvfp4Quant::Mixed),
        ("blanket W4A16", Nvfp4Quant::BlanketW4A16),
    ] {
        let m = SanaTransformer::from_weights_planned(&w, cfg.clone(), &DitPlan::nvfp4(quant))
            .unwrap_or_else(|e| panic!("build {label} trunk: {e}"));
        let r = m.nvfp4_report();
        eprintln!(
            "[sc-11045] {:<22} {:>6} {:>7} {:>9.2} MiB {:>8.2} MiB {:>8.2} MiB {:>8.4}",
            label,
            r.fp4_lit,
            r.dequant_bf16,
            mib(r.resident_fp4_bytes),
            mib(r.dequant_bf16_bytes),
            mib(r.resident_bytes()),
            r.footprint_ratio(),
        );
        measured.push((label, r));
        drop(m);
    }
    let bf16_total = measured[0].1.bf16_bytes;
    eprintln!(
        "[sc-11045]\n\
         [sc-11045]   dense bf16 equivalent : {:10.2} MiB  (the 1.0× baseline)\n\
         [sc-11045]   packed NVFP4 format   : {:10.2} MiB  ({:.4}× — the FORMAT's size, resident only \
         under W4A4; {:.2} effective bits/weight)\n",
        mib(bf16_total),
        mib(measured[0].1.nvfp4_bytes),
        measured[0].1.packed_footprint_ratio(),
        measured[0].1.effective_bits(),
    );

    // ---- The SC#6 gate itself: the BLANKET W4A4 packed path. --------------------------------
    let r = &measured[0].1;
    assert!(
        r.fp4_lit > 0,
        "blanket W4A4 must light the FP4 cores on sm_120"
    );
    assert_eq!(
        r.fp4_lit, r.n_quantized,
        "every quantized projection should be FP4-resident under blanket W4A4"
    );
    assert_eq!(
        r.dequant_bf16_bytes, 0,
        "blanket W4A4 must not hold a single dequantized bf16 weight (SC#6)"
    );
    // The gate: resident device bytes == the packed NVFP4 footprint, ~0.28× bf16 (never ~1.0).
    assert_eq!(
        r.resident_fp4_bytes, r.nvfp4_bytes,
        "resident device bytes must equal the NVFP4 footprint — no bf16 expansion (SC#6)"
    );
    assert!(
        r.footprint_ratio() < 0.35,
        "footprint ratio {:.4} is not NVFP4-scale — the model expanded toward bf16 (SC#6)",
        r.footprint_ratio()
    );
    assert!(
        r.effective_bits() < 5.0,
        "{:.2} effective bits/weight exceeds the ~4.5-bit NVFP4 budget (SC#6)",
        r.effective_bits()
    );

    // ---- ...and pin the honest converse, so the SC#6 claim can never be over-read. -----------
    // Blanket W4A16 lights NOTHING and holds every weight dense bf16. If `footprint_ratio()` ever
    // reports an NVFP4-scale number here again, the report has gone regime-blind (the exact defect
    // the sc-11045 review caught: it printed "ratio 0.2822" for a leg that was 163/163 dequant→bf16).
    let (_, w4a16) = &measured[2];
    assert_eq!(w4a16.fp4_lit, 0, "blanket W4A16 must light no FP4 core");
    assert_eq!(
        w4a16.resident_fp4_bytes, 0,
        "blanket W4A16 stages nothing to the packed path"
    );
    assert!(
        w4a16.footprint_ratio() >= 0.99,
        "blanket W4A16 holds dense bf16 — its resident ratio must be ~1.0, got {:.4}. An NVFP4-scale \
         number here means the report is counting the host packed container, not VRAM.",
        w4a16.footprint_ratio()
    );

    // The shipping mixed policy sits strictly between the two — and that cost is real, not a rounding
    // error: every outlier-class projection holds a full dense bf16 weight.
    let (_, mixed) = &measured[1];
    assert!(
        mixed.footprint_ratio() > r.footprint_ratio()
            && mixed.footprint_ratio() < w4a16.footprint_ratio(),
        "mixed resident ratio {:.4} must sit between blanket W4A4 ({:.4}) and blanket W4A16 ({:.4})",
        mixed.footprint_ratio(),
        r.footprint_ratio(),
        w4a16.footprint_ratio(),
    );
}

// ==============================================================================================
// (4) The spike's residual empirical gate — REAL per-layer activation-outlier sparsity across steps.
// ==============================================================================================

/// **The gate emulation could not close (sc-11038 → deferred through sc-11044 → here).**
///
/// The spike established that NVFP4 W4A4 damage scales with activation-outlier **sparsity**, and
/// partitioned the trunk's layers on that basis — benign compute-bulk → W4A4, outlier class
/// (caption_projection, cross-attn K/V, first/last blocks) → W4A16. But it only ever measured
/// *synthetic* activations; whether real Sana activations actually fall on that partition was assumed.
///
/// This measures the real thing: an [`ActProbe`] on the **dense f32** trunk (so the activations are
/// unperturbed by quantization — the true distribution) records [`OutlierSparsity`] for every
/// projection's input at every denoise step, across a real prompt's denoise. It then asks, per layer:
/// *does the class the policy assumed match the class the live model measures?*
///
/// The probe moves every activation to host f32, so this runs a short denoise — the question is about
/// the activation distribution's shape across the schedule, not throughput.
#[test]
#[ignore = "real-weight GPU test: needs the Sana-1.6B snapshot + an sm_120 device"]
fn nvfp4_sana_dit_real_activation_outlier_sparsity() {
    let Some(dev) = nvfp4_device() else { return };
    let Some(root) = snapshot_root() else { return };

    let (cond, uncond) = encode_conditioning(&root, &dev);
    let w = trunk_weights(&root, &dev);
    let cfg = SanaTransformerConfig::sana_1600m();

    // Probe the DENSE trunk: real, unquantized activations. The plan is dense, so `ActRecord::act` is
    // not the policy's verdict here — recompute the assignment explicitly per layer below.
    let probe = Arc::new(ActProbe::new());
    let model = SanaTransformer::from_weights_planned(
        &w,
        cfg.clone(),
        &DitPlan::dense().with_probe(probe.clone()),
    )
    .expect("build probed dense trunk");

    // A short but schedule-spanning denoise: σ moves from ~1 to ~0, and the activation distribution is
    // not stationary across it — the gate is a worst-case-across-steps question.
    let probe_steps = 4usize;
    let latent = run_denoise(&model, &cond, &uncond, &dev, Some(&probe), probe_steps);
    assert!(
        to_vec_f32(&latent).iter().all(|v| v.is_finite()),
        "probed denoise non-finite"
    );
    drop(model);

    let records = probe.records();
    assert!(!records.is_empty(), "probe recorded nothing");
    let summaries = summarize(&records);
    eprintln!(
        "\n[sc-11045] ===== REAL ACTIVATION-OUTLIER SPARSITY (SANA-1.6B, {probe_steps} real denoise \
         steps × 2 CFG branches, {} measurements over {} projections) =====",
        records.len(),
        summaries.len()
    );
    eprintln!(
        "[sc-11045] {:<44} {:>8} {:>10} {:>10} {:>9} {:>10}",
        "layer", "policy", "min_benign", "mean_benign", "worst", "max_crush"
    );

    // Cross the MEASURED class against the ASSUMED partition, layer by layer.
    let mut violations: Vec<String> = Vec::new();
    let mut w4a4_layers = 0usize;
    let mut w4a4_benign = 0usize;
    let mut w4a4_sparse = 0usize;
    let mut outlier_layers_measuring_dense = 0usize;
    let mut outlier_layers = 0usize;

    for s in &summaries {
        // What the shipping mixed policy WOULD assign this layer. Mirrors the loader's `LayerRole` in
        // `SanaTransformer::from_weights_planned`: the leading edge is blocks 0 AND 1, plus the last;
        // and SANA's top-level `proj_out` is the trunk's final head, which the loader states
        // explicitly (`LayerRole::final_proj()`) rather than letting a substring infer it —
        // sc-11045 review, MAJOR 1.
        let role = LayerRole {
            is_edge_block: s.layer.contains("transformer_blocks.0.")
                || s.layer.contains("transformer_blocks.1.")
                || s.layer
                    .contains(&format!("transformer_blocks.{}.", cfg.num_layers - 1)),
            is_final_proj: s.layer == "proj_out",
        };
        let assigned = DitPlan::nvfp4(Nvfp4Quant::Mixed).act_for(&s.layer, role);
        eprintln!(
            "[sc-11045] {:<44} {:>8} {:>10.5} {:>10.5} {:>9} {:>10.1}",
            s.layer,
            match assigned {
                ActPrecision::W4A4 => "W4A4",
                ActPrecision::W4A16 => "W4A16",
            },
            s.min_benign_fraction,
            s.mean_benign_fraction,
            format!("{:?}", s.worst_class),
            s.max_crush_ratio,
        );
        match assigned {
            ActPrecision::W4A4 => {
                w4a4_layers += 1;
                match s.worst_class {
                    OutlierClass::Benign => w4a4_benign += 1,
                    OutlierClass::Sparse => w4a4_sparse += 1,
                    // A layer the policy sends to W4A4 that measures DENSE on real activations is a
                    // real partition violation — exactly what this gate exists to catch.
                    OutlierClass::Dense => violations.push(format!(
                        "{} → W4A4 but measures Dense (min benign {:.5}, crush {:.1}×)",
                        s.layer, s.min_benign_fraction, s.max_crush_ratio
                    )),
                }
            }
            ActPrecision::W4A16 => {
                outlier_layers += 1;
                if matches!(s.worst_class, OutlierClass::Dense) {
                    outlier_layers_measuring_dense += 1;
                }
            }
        }
    }

    eprintln!(
        "\n[sc-11045] PARTITION VERDICT: {w4a4_layers} layers assigned W4A4 — {w4a4_benign} measure \
         Benign, {w4a4_sparse} measure Sparse, {} measure Dense (violations).\n\
         [sc-11045] {outlier_layers} layers held at W4A16 (outlier class) — {outlier_layers_measuring_dense} \
         of them do measure Dense on real activations (i.e. the override was earning its keep).",
        violations.len()
    );
    for v in &violations {
        eprintln!("[sc-11045]   VIOLATION: {v}");
    }

    // The gate: no layer the policy sends to W4A4 may collapse on real activations.
    assert!(
        violations.is_empty(),
        "the benign→W4A4 partition does NOT hold on real activations — {} layer(s) assigned W4A4 \
         measure Dense-outlier: {:?}",
        violations.len(),
        violations
    );
    assert!(
        summaries.iter().all(|s| s.partition_holds()),
        "a summarized layer reports the partition broken"
    );
}
