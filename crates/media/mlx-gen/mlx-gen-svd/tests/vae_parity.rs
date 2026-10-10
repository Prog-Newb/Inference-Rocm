//! SVD VAE parity vs diffusers `AutoencoderKLTemporalDecoder` (epic 3040 / sc-3372). Gates both
//! directions of `SvdVae` — `encode_mode` (the 2-D SD encoder + `quant_conv` + `mode()`) and
//! `decode` (the spatio-temporal decoder + `time_conv_out`) — against a golden dumped from the real
//! model (`tools/dump_svd_vae_golden.py`), in f32 so the gate isolates the math from fp16 rounding.
//! Needs the SVD checkpoint locally → `--ignored`.
//!
//! Run: `cargo test -p mlx-gen-svd --test vae_parity -- --ignored --nocapture`

use mlx_rs::ops::{abs, max as max_op, sqrt, square, subtract, sum};
use mlx_rs::{Array, Dtype};

use mlx_gen::weights::Weights;
use mlx_gen_svd::{SvdVae, VaeConfig};

const GOLDEN: &str = concat!(
    env!("CARGO_MANIFEST_DIR"),
    "/tests/fixtures/svd_vae_golden.safetensors"
);

/// Locate the SVD `vae/diffusion_pytorch_model.safetensors` (f32) in the HF cache.
fn vae_path() -> std::path::PathBuf {
    let cache = std::path::PathBuf::from(std::env::var("MLX_GEN_MODELS_ROOT").expect("set MLX_GEN_MODELS_ROOT to the explicit models root (holds models--*/snapshots); inference never self-fetches or derives a cache location (epic 13657)"));
    let snaps = cache
        .join("models--stabilityai--stable-video-diffusion-img2vid-xt")
        .join("snapshots");
    let snap = std::fs::read_dir(&snaps)
        .expect("svd snapshot dir")
        .next()
        .unwrap()
        .unwrap()
        .path();
    snap.join("vae/diffusion_pytorch_model.safetensors")
}

/// `(max|a−b|, peak-rel = max|a−b|/max|b|, relative-L2 = ‖a−b‖₂/‖b‖₂)`. The peak-rel is the headline
/// gate (matching the other SVD parity tests); the relative-L2 separates an outlier-driven peak
/// (tiny L2) from a structural gap (large L2).
fn errors(a: &Array, b: &Array) -> (f32, f32, f32) {
    let diff = abs(subtract(a, b).unwrap()).unwrap();
    let max_abs = max_op(&diff, None).unwrap().item::<f32>();
    let denom = max_op(abs(b).unwrap(), None).unwrap().item::<f32>();
    let l2_diff = sqrt(sum(square(&diff).unwrap(), None).unwrap())
        .unwrap()
        .item::<f32>();
    let l2_ref = sqrt(sum(square(b).unwrap(), None).unwrap())
        .unwrap()
        .item::<f32>();
    (
        max_abs,
        max_abs / denom.max(1e-6),
        l2_diff / l2_ref.max(1e-6),
    )
}

#[test]
#[ignore = "needs the SVD checkpoint in the HF cache"]
fn svd_vae_matches_diffusers() {
    let mut w = Weights::from_file(vae_path()).expect("svd vae weights");
    w.cast_all(Dtype::Float32).expect("cast f32");
    let vae = SvdVae::from_weights(&w, &VaeConfig::default()).expect("vae");

    let g = Weights::from_file(GOLDEN).expect("vae golden");
    let num_frames = g.require("num_frames").unwrap().item::<i32>();

    // --- encode: image NCHW [1,3,64,64] → NHWC; mode NHWC → compare to golden NCHW→NHWC. ---
    let image = g
        .require("image")
        .unwrap()
        .transpose_axes(&[0, 2, 3, 1])
        .unwrap();
    let mode = vae.encode_mode(&image).unwrap();
    let mode_want = g
        .require("encode_mode")
        .unwrap()
        .transpose_axes(&[0, 2, 3, 1])
        .unwrap();
    assert_eq!(mode.shape(), mode_want.shape(), "encode_mode shape");
    let (e_abs, e_rel, e_l2) = errors(&mode, &mode_want);
    println!("encode_mode parity: max|Δ| {e_abs}, peak-rel {e_rel}, rel-L2 {e_l2}");

    // --- decode: latent NCHW [F,4,8,8] → NHWC; frames NHWC → compare to golden NCHW→NHWC. ---
    let z = g
        .require("z")
        .unwrap()
        .transpose_axes(&[0, 2, 3, 1])
        .unwrap();
    let frames = vae.decode(&z, num_frames).unwrap();
    let frames_want = g
        .require("decode_frames")
        .unwrap()
        .transpose_axes(&[0, 2, 3, 1])
        .unwrap();
    assert_eq!(frames.shape(), frames_want.shape(), "decode_frames shape");
    let (d_abs, d_rel, d_l2) = errors(&frames, &frames_want);
    println!("decode parity: max|Δ| {d_abs}, peak-rel {d_rel}, rel-L2 {d_l2}");

    // f32 cross-backend accumulation over the conv/group-norm/sdpa stack — a numeric-ordering gap,
    // not a structural one. The N(0,1) input is worst-case for a conv VAE (max high-frequency content
    // → max accumulation divergence); a real image is far tamer. The encode peak (0.74%) sits on the
    // single largest latent value (|z|≈11), so rel-L2 (0.29%) is the better structural measure — and
    // the decoder, which reuses the *same* spatial resnet/attention blocks, lands at 0.11% rel-L2,
    // confirming the building blocks are exact. rel-L2 is the primary structural gate; peak-rel is a
    // loose ceiling for the outlier. The mode latent only feeds the diffusion as image conditioning.
    assert!(
        e_l2 < 5e-3,
        "encode_mode rel-L2 {e_l2} (peak-rel {e_rel}, max|Δ| {e_abs})"
    );
    assert!(
        e_rel < 1e-2,
        "encode_mode peak-rel {e_rel} (max|Δ| {e_abs})"
    );
    assert!(
        d_l2 < 2e-3,
        "decode rel-L2 {d_l2} (peak-rel {d_rel}, max|Δ| {d_abs})"
    );
    assert!(d_rel < 5e-3, "decode peak-rel {d_rel} (max|Δ| {d_abs})");
}
