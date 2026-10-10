//! sc-12796 (epic 12732) — **real-Mac footprint + parity** for the Wan2.2 **TI2V-5B** (dense)
//! sequential component offload.
//!
//! Drives the public product path (`provider_registry().load(id, spec)` → `Generator::generate`) twice
//! over the SAME seeded request — once [`OffloadPolicy::Resident`] (the byte-identical pre-offload path)
//! and once [`OffloadPolicy::Sequential`] (the staged `clear_cache` flush) — and asserts the story's two
//! acceptance criteria on a Mac.
//!
//! **What differs from the A14B expert-swap harness ([`expert_swap_footprint`]):** the dense 5B has NO
//! experts to swap, and it **already stages** TE → DiT → z48 VAE (each `Weights`/encoder dropped by
//! scope, `eval`'d before the next loads). So its **active** high-water mark (`get_peak_memory`, which
//! tracks live-array bytes — NOT the buffer cache) is already bounded by the largest single stage under
//! BOTH policies — Sequential does **not** lower it. What Sequential changes is the **buffer cache**:
//! `clear_cache` returns each dead component's freed buffers to the OS immediately, instead of leaving
//! the ~11 GB f32 UMT5 TE (and, for TI2V, the VAE encoder) warm in MLX's cache — RSS / wired-memory
//! pressure — through denoise + decode. So the discriminating metric here is the **footprint**
//! (`get_active_memory() + get_cache_memory()`) sampled during the denoise steps, not the active peak.
//!
//! 1. **Denoise footprint drops by ~the dead TE.** The `Sequential` peak footprint (active + cache
//!    sampled across the denoise/decode callbacks) is meaningfully below the `Resident` one — the flushed
//!    TE (and VAE-encoder) are off-GPU during denoise instead of cache-resident.
//! 2. **Output parity preserved.** The two runs produce **bit-identical** frames (`clear_cache` changes
//!    residency/lifetime, never numerics). And the **active** peak is ≈ equal (staging already bounds it).
//!
//! **sc-12831 addition — the quantized-tier active-peak floor.** sc-12796 found that on the quantized 5B
//! the residual ~12 GiB active peak *is* the f32 UMT5 TE encode stage, which no further offload could
//! lower. sc-12831 packs the UMT5 projections (Q8 — the near-lossless floor; `encode_text_staged` →
//! `model::effective_te_quant`, keyed on the on-disk `config.quantization` manifest), so on a
//! **quantized** tier the encode no longer holds ~11 GB of bf16 TE and the whole-generation active peak
//! drops to ~7.7 GiB. [`assert_quantized_te_active_peak_floor`] asserts that new floor (< 10 GiB) — the
//! third acceptance criterion, discriminating (a bf16 TE returns the peak to ~11.8 GiB). It is a no-op on
//! a bf16 tier (nothing packs the TE there).
//!
//! Both the **T2V** (pure noise, no VAE encode) and **TI2V** (a `Reference` image → the z48 VAE-encoder
//! staged, then flushed) paths are covered.
//!
//! `#[ignore]` + env-gated (needs the converted TI2V-5B snapshot), GPU-heavy. Point
//! `WAN_TI2V_5B_MODEL_DIR` at a converted snapshot **tier** dir (q4 / q8 / bf16 — each has
//! `model.safetensors` + `t5_encoder.safetensors` + `vae.safetensors` + `config.json` +
//! `tokenizer.json`). The TE weights are ~11 GB bf16 on disk at **every** tier; on a quantized tier they
//! are packed at load, on the bf16 tier they stay dense (so the offload footprint win is ~the TE at every
//! tier, while the sc-12831 active-peak floor applies only to the quantized tiers).
//!
//! ```text
//! WAN_TI2V_5B_MODEL_DIR=/path/to/models--SceneWorks--wan2.2-ti2v-5b-mlx/snapshots/<hash>/q4 \
//!   cargo test -p mlx-gen-wan --test ti2v_5b_offload_footprint -- --ignored --nocapture
//! ```

use std::path::PathBuf;

use mlx_rs::memory::{
    clear_cache, get_active_memory, get_cache_memory, get_peak_memory, reset_peak_memory,
};

use mlx_gen::{
    Conditioning, GenerationOutput, GenerationRequest, Image, LoadSpec, OffloadPolicy, Progress,
    WeightsSource,
};
use mlx_gen_wan::MODEL_ID;

fn env_path(var: &str) -> Option<PathBuf> {
    std::env::var_os(var).map(|s| {
        let s = s.to_string_lossy();
        if let Some(rest) = s.strip_prefix("~/") {
            if let Some(home) = std::env::var_os("HOME") {
                return PathBuf::from(format!("{}/{rest}", home.to_string_lossy()));
            }
        }
        PathBuf::from(s.to_string())
    })
}

fn gib(bytes: usize) -> f64 {
    bytes as f64 / (1024.0 * 1024.0 * 1024.0)
}

/// The whole-generation **active** peak floor a **quantized** tier must clear (sc-12831). With the UMT5
/// projections packed (Q8 in production — the near-lossless floor; see `model::effective_te_quant`), the
/// Stage-1 encode no longer holds ~11 GB of bf16 f32-TE — the component sc-12796 measured as the 5B's
/// residual ~12 GiB active peak — so the peak drops to ~7.7 GiB (the isolated Q8 TE-encode measures 7.72
/// GiB; the whole generation is ~that). 10 GiB is a **discriminating** ceiling: above the real Q8 peak
/// with margin, far below the ~11.8 GiB an un-packed bf16 TE reaches. Revert the TE quant (the
/// `text_encoder.rs` packing or the `effective_te_quant` plumbing) and this assertion goes red.
const QUANTIZED_TE_ACTIVE_PEAK_FLOOR: f64 = 10.0; // GiB

/// True when the snapshot tier at `model_dir` is pre-quantized — its `config.json` carries a
/// `"quantization"` block, the case in which `encode_text_staged` packs the UMT5 TE (the footprint
/// harness loads with no `spec.quantize`, so the on-disk manifest is the only TE-quant trigger). A bf16
/// tier keeps the dense ~12 GiB f32-TE encode peak, so the floor does not apply.
fn tier_is_quantized(model_dir: &std::path::Path) -> bool {
    std::fs::read_to_string(model_dir.join("config.json"))
        .map(|s| s.contains("\"quantization\""))
        .unwrap_or(false)
}

/// Assert the sc-12831 acceptance on a quantized tier: every measured active peak is below
/// [`QUANTIZED_TE_ACTIVE_PEAK_FLOOR`] (the packed UMT5 TE retired the ~12 GiB f32-TE encode peak). No-op
/// on a bf16 tier (nothing packs the TE there — the peak stays ~12 GiB by design). Mutation guard: leave
/// the TE bf16 and the peak returns to ~12 GiB, failing this.
fn assert_quantized_te_active_peak_floor(
    label: &str,
    model_dir: &std::path::Path,
    profiles: &[&Profile],
) {
    if !tier_is_quantized(model_dir) {
        println!(
            "[{label}] bf16 tier — TE stays dense; active-peak floor N/A (peak stays ~12 GiB)"
        );
        return;
    }
    for p in profiles {
        assert!(
            gib(p.peak_active) < QUANTIZED_TE_ACTIVE_PEAK_FLOOR,
            "{label}: quantized-tier active peak {:.2} GiB is NOT below the sc-12831 floor {:.1} GiB — \
             the packed UMT5 TE should have dropped the ~12 GiB f32-TE encode peak; is the TE actually \
             quantized (effective_te_quant / Umt5Encoder::from_weights_quantized)?",
            gib(p.peak_active),
            QUANTIZED_TE_ACTIVE_PEAK_FLOOR
        );
    }
    println!(
        "[{label}] quantized-tier active peak below the {:.1} GiB sc-12831 floor ✓ (packed UMT5 TE)",
        QUANTIZED_TE_ACTIVE_PEAK_FLOOR
    );
}

/// A small non-flat RGB gradient — the TI2V `Reference` (first-frame) conditioning image.
fn gradient_image(w: u32, h: u32) -> Image {
    let mut pixels = Vec::with_capacity((w * h * 3) as usize);
    for y in 0..h {
        for x in 0..w {
            pixels.push((x * 255 / w.max(1)) as u8);
            pixels.push((y * 255 / h.max(1)) as u8);
            pixels.push(128);
        }
    }
    Image {
        width: w,
        height: h,
        pixels,
    }
}

/// One render's memory profile: the **active** peak (live-array high-water, `get_peak_memory`) and the
/// peak **footprint** (`active + cache` — the RSS proxy — sampled across the denoise/decode callbacks).
struct Profile {
    frames: Vec<Image>,
    peak_active: usize,
    peak_footprint: usize,
}

/// Run one seeded 5B generation under `policy` and return its [`Profile`]. `clear_cache` +
/// `reset_peak_memory` before the render so the measurements reflect only this generation. The
/// `on_progress` closure samples `active + cache` on every denoise/decode event — the window where the
/// dead TE (cache-resident under `Resident`, flushed under `Sequential`) is or isn't off-GPU.
fn render_and_measure(
    model_dir: &std::path::Path,
    policy: OffloadPolicy,
    conditioning: Vec<Conditioning>,
) -> Profile {
    let gen = mlx_gen_wan::provider_registry()
        .unwrap()
        .load(
            MODEL_ID,
            &LoadSpec::new(WeightsSource::Dir(model_dir.to_path_buf())).with_offload_policy(policy),
        )
        .unwrap_or_else(|e| panic!("load {MODEL_ID}: {e}"));

    // Small-but-real geometry so all four renders finish quickly. 480 = 15·32 is the on-grid MIN_SIZE
    // floor; 5 = 1 + 4·1 frames is one VAE temporal chunk. `unipc` is the native solver.
    let req = GenerationRequest {
        prompt: "a red fox trotting across a snowy meadow at sunrise, cinematic".into(),
        width: 480,
        height: 480,
        frames: Some(5),
        steps: Some(6),
        seed: Some(42),
        sampler: Some("unipc".into()),
        conditioning,
        ..Default::default()
    };
    gen.validate(&req).expect("validate");

    clear_cache();
    reset_peak_memory();
    let mut peak_footprint = 0usize;
    let mut on_progress = |p: Progress| {
        if matches!(p, Progress::Step { .. } | Progress::Decoding) {
            let f = get_active_memory() + get_cache_memory();
            if f > peak_footprint {
                peak_footprint = f;
            }
        }
    };
    let out = gen.generate(&req, &mut on_progress).expect("generate");
    let peak_active = get_peak_memory();

    let frames = match out {
        GenerationOutput::Video { frames, .. } => frames,
        other => panic!("expected Video, got {other:?}"),
    };
    Profile {
        frames,
        peak_active,
        peak_footprint,
    }
}

/// Assert the story's acceptance: (1) the `Sequential` denoise footprint (active + cache) drops
/// meaningfully below `Resident` (the dead TE/VAE flushed off-GPU), and (2) the frames are bit-identical
/// AND the active peak is ≈ equal (staging already bounds it; only the cache/RSS moves).
fn assert_offload_wins(label: &str, res: &Profile, seq: &Profile) {
    println!(
        "[{label}] Resident   active peak = {:.2} GiB",
        gib(res.peak_active)
    );
    println!(
        "[{label}] Sequential active peak = {:.2} GiB",
        gib(seq.peak_active)
    );
    println!(
        "[{label}] Resident   footprint (active+cache) peak = {:.2} GiB",
        gib(res.peak_footprint)
    );
    println!(
        "[{label}] Sequential footprint (active+cache) peak = {:.2} GiB",
        gib(seq.peak_footprint)
    );
    println!(
        "[{label}] footprint drop = {:.2} GiB ({:.0}% of the Resident footprint)",
        gib(res.peak_footprint.saturating_sub(seq.peak_footprint)),
        100.0 * (res.peak_footprint.saturating_sub(seq.peak_footprint)) as f64
            / res.peak_footprint as f64
    );

    // (2a) Parity — the flush only changes residency/lifetime, so frames must be bit-identical.
    assert_eq!(
        res.frames.len(),
        seq.frames.len(),
        "{label}: frame count differs across residency policies"
    );
    for (i, (r, s)) in res.frames.iter().zip(&seq.frames).enumerate() {
        assert_eq!(
            (r.width, r.height),
            (s.width, s.height),
            "{label}: frame {i} dims"
        );
        assert_eq!(
            r.pixels, s.pixels,
            "{label}: frame {i} differs between Resident and Sequential — the offload must be \
             numerics-preserving (same weights per timestep, only residency changes)"
        );
    }

    // (2b) Active peak ≈ equal — the dense 5B already stages, so `get_peak_memory` (live arrays) is
    // bounded by the largest single stage under both policies; `clear_cache` touches the cache, not the
    // active set. A small tolerance for allocator noise; Sequential must not be materially WORSE.
    assert!(
        seq.peak_active as f64 <= res.peak_active as f64 * 1.05,
        "{label}: Sequential active peak {:.2} GiB unexpectedly ABOVE Resident {:.2} GiB — the flush \
         should never raise the active high-water mark",
        gib(seq.peak_active),
        gib(res.peak_active)
    );

    // (1) Footprint — Sequential flushes the ~11 GB f32 TE (and, for TI2V, the VAE encoder) out of the
    // cache before/through denoise, so its active+cache peak must be meaningfully below Resident's.
    // Mutation guard: drop the `clear_cache` calls in `generate_impl` and the two footprints converge —
    // this assertion then fails. The floor (≥ 10% below) is conservative; the real drop is ~the TE.
    assert!(
        seq.peak_footprint < res.peak_footprint,
        "{label}: Sequential footprint {:.2} GiB must be below Resident {:.2} GiB (TE/VAE flushed)",
        gib(seq.peak_footprint),
        gib(res.peak_footprint)
    );
    assert!(
        (seq.peak_footprint as f64) <= 0.90 * (res.peak_footprint as f64),
        "{label}: Sequential footprint {:.2} GiB is only marginally below Resident {:.2} GiB — \
         expected ~the dead f32 TE (~11 GB) less; is the TE really `clear_cache`-flushed off-GPU?",
        gib(seq.peak_footprint),
        gib(res.peak_footprint)
    );
}

#[test]
#[ignore = "needs a converted Wan2.2-TI2V-5B snapshot tier (WAN_TI2V_5B_MODEL_DIR); GPU-heavy"]
fn t2v_5b_offload_drops_the_footprint_and_preserves_output() {
    let model_dir = match env_path("WAN_TI2V_5B_MODEL_DIR") {
        Some(p) => p,
        None => {
            eprintln!("skip: set WAN_TI2V_5B_MODEL_DIR to a converted TI2V-5B snapshot tier dir");
            return;
        }
    };
    // Pure-noise T2V (no conditioning) — Stage 1b loads no VAE encoder, so the win is the dead TE alone.
    let res = render_and_measure(&model_dir, OffloadPolicy::Resident, vec![]);
    let seq = render_and_measure(&model_dir, OffloadPolicy::Sequential, vec![]);
    assert_offload_wins("t2v", &res, &seq);
    // sc-12831: on a quantized tier the packed UMT5 TE must have dropped the active peak below ~8 GiB.
    assert_quantized_te_active_peak_floor("t2v", &model_dir, &[&res, &seq]);
}

#[test]
#[ignore = "needs a converted Wan2.2-TI2V-5B snapshot tier (WAN_TI2V_5B_MODEL_DIR); GPU-heavy"]
fn ti2v_5b_offload_drops_the_footprint_and_preserves_output() {
    let model_dir = match env_path("WAN_TI2V_5B_MODEL_DIR") {
        Some(p) => p,
        None => {
            eprintln!("skip: set WAN_TI2V_5B_MODEL_DIR to a converted TI2V-5B snapshot tier dir");
            return;
        }
    };
    // TI2V mask-blend: a `Reference` image → the z48 VAE **encoder** is staged in Stage 1b, then flushed
    // under Sequential before the DiT loads (the second `clear_cache` site, on top of the TE flush).
    let reference = || {
        vec![Conditioning::Reference {
            image: gradient_image(128, 128),
            strength: None,
        }]
    };
    let res = render_and_measure(&model_dir, OffloadPolicy::Resident, reference());
    let seq = render_and_measure(&model_dir, OffloadPolicy::Sequential, reference());
    assert_offload_wins("ti2v", &res, &seq);
    // sc-12831: on a quantized tier the packed UMT5 TE must have dropped the active peak below ~8 GiB.
    assert_quantized_te_active_peak_floor("ti2v", &model_dir, &[&res, &seq]);
}
