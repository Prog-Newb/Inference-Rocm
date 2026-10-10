//! sc-2365: FLUX.2-**dev** end-to-end txt2img on real weights. `#[ignore]`d — needs the real
//! `black-forest-labs/FLUX.2-dev` snapshot (~60 GB DiT + ~45 GB TE):
//!
//!   cargo test -p mlx-gen-flux2 --release --test dev_e2e_real_weights -- --ignored --nocapture
//!
//! Proves the whole dev vertical end to end: assemble a pre-quantized Q4 snapshot (sc-5917 convert
//! for DiT + TE, VAE/tokenizer symlinked from the source), load it through the registry
//! (`provider_registry().load("flux2_dev", …)` → `load_dev`), and render an image. This exercises the Mistral3
//! TE → the **embedded guidance** embedder (the one genuinely new dev piece) → the dev DiT denoise →
//! the (klein-shared) VAE decode. Rust runs f32 activations vs the BFL bf16 reference, so — like the
//! klein e2e — this is a coherence/quality floor (finite + non-degenerate render at the dev
//! defaults), not a bit-parity claim; a wiring bug (guidance dropped, TE mis-shaped, wrong DiT dims)
//! collapses the render to a flat field, which the variance gate catches.
//!
//! Env overrides for a faster local run: `MLX_GEN_FLUX2_DEV_SIZE` (default 1024), the acceptance
//! target; `MLX_GEN_FLUX2_DEV_STEPS` (default = the dev default, ~28); `MLX_GEN_FLUX2_DEV_PROMPT`.
//! Wrap the test binary in `/usr/bin/time -l` for the steady-state footprint (cf. sc-5917).

use std::path::PathBuf;

use mlx_gen::media::Image;
use mlx_gen::{Conditioning, GenerationOutput, GenerationRequest, LoadSpec, WeightsSource};
use mlx_gen_flux2::{quantize_flux2_dit, quantize_flux2_text_encoder_dir};

#[path = "../../tests/support/atomic_cache.rs"]
mod atomic_cache;

const BITS: i32 = 4;
const GROUP_SIZE: i32 = 64;

/// Root for this suite's **deliberately persistent** artifacts. `MLX_GEN_FLUX2_PREQUANT_DIR` points them
/// somewhere durable; the `$TMPDIR` default is intentional and must NOT become a `tempfile`
/// guard — these outputs outlive the test on purpose (a pre-quantized snapshot the NEXT run is meant to reuse), so a guard
/// would delete the very thing the test exists to produce (sc-17791).
fn prequant_root() -> PathBuf {
    std::env::var("MLX_GEN_FLUX2_PREQUANT_DIR")
        .map(PathBuf::from)
        .unwrap_or_else(|_| std::env::temp_dir())
}

fn snapshot() -> PathBuf {
    let p = std::env::var("MLX_GEN_FLUX2_DEV_SNAPSHOT").unwrap_or_else(|_| panic!("set MLX_GEN_FLUX2_DEV_SNAPSHOT to the required snapshot dir; inference never self-fetches or derives a cache location (epic 13657)"));
    PathBuf::from(p)
}

/// Assemble a complete pre-quantized Q4 dev snapshot at a stable temp path: pre-quantize the DiT +
/// Mistral TE (reusing a prior run's output if present, shared with `quant_prequantize_real_weights`),
/// and symlink the unchanged VAE + tokenizer from the source. Returns the assembled snapshot dir.
fn prequantized_dev_snapshot() -> PathBuf {
    let src = snapshot();
    let dst = prequant_root().join(format!("mlx_gen_flux2_dev_prequant_q{BITS}"));

    if !dst
        .join("transformer/diffusion_pytorch_model.safetensors")
        .exists()
    {
        println!("pre-quantizing dev DiT → Q{BITS}…");
        let final_dir = dst.join("transformer");
        let staging =
            atomic_cache::prepare_staging(&final_dir).expect("prepare dev DiT staging dir");
        quantize_flux2_dit(&src.join("transformer"), &staging, BITS, GROUP_SIZE)
            .expect("pre-quantize dev DiT");
        atomic_cache::publish(&staging, &final_dir).expect("publish dev DiT");
    }
    if !dst.join("text_encoder/model.safetensors").exists() {
        println!("pre-quantizing dev Mistral TE → Q{BITS}…");
        let final_dir = dst.join("text_encoder");
        let staging =
            atomic_cache::prepare_staging(&final_dir).expect("prepare dev TE staging dir");
        quantize_flux2_text_encoder_dir(&src.join("text_encoder"), &staging, BITS, GROUP_SIZE)
            .expect("pre-quantize dev TE");
        atomic_cache::publish(&staging, &final_dir).expect("publish dev TE");
    }
    // VAE (dense, identical to klein) + tokenizer: symlink straight from the source snapshot.
    for sub in ["vae", "tokenizer"] {
        let link = dst.join(sub);
        let source = std::fs::canonicalize(src.join(sub)).expect("canonicalize component");
        atomic_cache::symlink_or_reuse(&source, &link).expect("publish component symlink");
    }
    dst
}

/// (mean, std) of the image's bytes — a coherent render has real spatial variance; a wiring bug that
/// drops guidance / mis-shapes the TE collapses it toward a flat field (std → 0).
fn mean_std(img: &Image) -> (f32, f32) {
    let n = img.pixels.len() as f32;
    let mean = img.pixels.iter().map(|&p| p as f32).sum::<f32>() / n;
    let var = img
        .pixels
        .iter()
        .map(|&p| (p as f32 - mean).powi(2))
        .sum::<f32>()
        / n;
    (mean, var.sqrt())
}

#[test]
#[ignore = "needs real FLUX.2-dev snapshot (~105 GB); assembles a Q4 snapshot in TMPDIR"]
fn dev_txt2img_renders_coherent_image() {
    let size: u32 = std::env::var("MLX_GEN_FLUX2_DEV_SIZE")
        .ok()
        .and_then(|s| s.parse().ok())
        .unwrap_or(1024);
    let steps: Option<u32> = std::env::var("MLX_GEN_FLUX2_DEV_STEPS")
        .ok()
        .and_then(|s| s.parse().ok());
    let prompt = std::env::var("MLX_GEN_FLUX2_DEV_PROMPT")
        .unwrap_or_else(|_| "a red fox resting in fresh snow under soft winter light".into());

    let dst = prequantized_dev_snapshot();
    let gen = mlx_gen_flux2::provider_registry()
        .unwrap()
        .load("flux2_dev", &LoadSpec::new(WeightsSource::Dir(dst)))
        .expect("dev loads through the registry");

    let req = GenerationRequest {
        prompt: prompt.clone(),
        width: size,
        height: size,
        count: 1,
        seed: Some(0),
        steps, // None ⇒ the dev default (~28)
        ..Default::default()
    };
    let mut last = 0u32;
    let out = gen
        .generate(&req, &mut |p| {
            if let mlx_gen::Progress::Step { current, total } = p {
                if current == 1 || current == total || current % 8 == 0 {
                    println!("  step {current}/{total}");
                }
                last = current;
            }
        })
        .expect("dev generate");
    let _ = last;

    let GenerationOutput::Images(images) = out else {
        panic!("expected images");
    };
    let img = &images[0];
    assert_eq!((img.width, img.height), (size, size), "output dimensions");
    assert_eq!(
        img.pixels.len(),
        (size * size * 3) as usize,
        "RGB8 pixel count"
    );

    let (mean, std) = mean_std(img);
    println!(
        "flux2-dev T2I OK: {size}² prompt={prompt:?} steps={steps:?} → mean={mean:.1} std={std:.1}"
    );
    // A coherent photo spans a wide tonal range; a degenerate/flat render (wiring bug) has std≈0
    // and a mean pinned at an extreme. Generous floor — this is a smoke, not an aesthetic judge.
    assert!(std > 10.0, "render looks degenerate (flat): std={std:.2}");
    assert!(
        mean > 2.0 && mean < 253.0,
        "render pinned to an extreme: mean={mean:.2}"
    );
}

// ---- sc-5919: FLUX.2-dev EDIT (single + multi reference) --------------------------------------
//
// dev has no mflux fork reference (mflux is klein-only), so — like the dev T2I e2e above — these are
// **coherence floors**, not bit-parity. They prove the dev *edit* vertical runs end to end: the
// `flux2_dev_edit` variant loads the dev snapshot, the (klein-shared) edit chain VAE-encodes the
// reference(s) and concatenates them to the DiT image stream at t=10+10·i, the embedded-guidance dev
// DiT denoises the joint sequence, and the VAE decodes a non-degenerate image. A wiring bug (edit
// tokens dropped, guidance lost, wrong variant routing) collapses the render to a flat field.

/// A deterministic, non-degenerate synthetic reference: a 2-axis gradient with a per-index tint.
/// (No fork golden to load — the smoke only needs a real, structured image to condition on.)
fn synthetic_reference(size: u32, idx: u8) -> Image {
    let mut pixels = Vec::with_capacity((size * size * 3) as usize);
    let denom = size.max(1);
    for y in 0..size {
        for x in 0..size {
            pixels.push(((x * 255) / denom) as u8);
            pixels.push(((y * 255) / denom) as u8);
            pixels.push(idx.wrapping_mul(83).wrapping_add(40));
        }
    }
    Image {
        width: size,
        height: size,
        pixels,
    }
}

/// Render through the public `flux2_dev_edit` path with `n_refs` synthetic references (1 ⇒
/// `Reference`, ≥2 ⇒ `MultiReference`). Returns the decoded image.
fn render_dev_edit(size: u32, steps: Option<u32>, n_refs: usize, prompt: &str) -> Image {
    let dst = prequantized_dev_snapshot();
    let gen = mlx_gen_flux2::provider_registry()
        .unwrap()
        .load("flux2_dev_edit", &LoadSpec::new(WeightsSource::Dir(dst)))
        .expect("dev-edit loads through the registry");

    let refs: Vec<Image> = (0..n_refs)
        .map(|i| synthetic_reference(size, i as u8))
        .collect();
    let conditioning = if n_refs == 1 {
        vec![Conditioning::Reference {
            image: refs.into_iter().next().unwrap(),
            strength: None,
        }]
    } else {
        vec![Conditioning::MultiReference { images: refs }]
    };

    let req = GenerationRequest {
        prompt: prompt.into(),
        width: size,
        height: size,
        count: 1,
        seed: Some(0),
        steps,
        conditioning,
        ..Default::default()
    };
    let GenerationOutput::Images(mut images) = gen
        .generate(&req, &mut |p| {
            if let mlx_gen::Progress::Step { current, total } = p {
                if current == 1 || current == total || current % 8 == 0 {
                    println!("  step {current}/{total}");
                }
            }
        })
        .expect("dev-edit generate")
    else {
        panic!("expected images");
    };
    images.pop().unwrap()
}

/// Env-tunable for a fast local run: `MLX_GEN_FLUX2_DEV_EDIT_SIZE` (default 512 — edit is heavier
/// than T2I since references add sequence tokens), `MLX_GEN_FLUX2_DEV_EDIT_STEPS` (default 8),
/// `MLX_GEN_FLUX2_DEV_EDIT_REFS` (default 1; ≥2 exercises `MultiReference`).
#[test]
#[ignore = "needs real FLUX.2-dev snapshot (~105 GB); assembles a Q4 snapshot in TMPDIR"]
fn dev_edit_renders_coherent_image() {
    let size: u32 = std::env::var("MLX_GEN_FLUX2_DEV_EDIT_SIZE")
        .ok()
        .and_then(|s| s.parse().ok())
        .unwrap_or(512);
    let steps: Option<u32> = Some(
        std::env::var("MLX_GEN_FLUX2_DEV_EDIT_STEPS")
            .ok()
            .and_then(|s| s.parse().ok())
            .unwrap_or(8),
    );
    let n_refs: usize = std::env::var("MLX_GEN_FLUX2_DEV_EDIT_REFS")
        .ok()
        .and_then(|s| s.parse().ok())
        .unwrap_or(1);

    let img = render_dev_edit(
        size,
        steps,
        n_refs,
        "make it a vivid impressionist oil painting",
    );
    assert_eq!((img.width, img.height), (size, size), "output dimensions");
    assert_eq!(
        img.pixels.len(),
        (size * size * 3) as usize,
        "RGB8 pixel count"
    );
    let (mean, std) = mean_std(&img);
    println!(
        "flux2-dev EDIT OK: {size}² refs={n_refs} steps={steps:?} → mean={mean:.1} std={std:.1}"
    );
    assert!(
        std > 10.0,
        "edit render looks degenerate (flat): std={std:.2}"
    );
    assert!(
        mean > 2.0 && mean < 253.0,
        "edit render pinned to an extreme: mean={mean:.2}"
    );
}
