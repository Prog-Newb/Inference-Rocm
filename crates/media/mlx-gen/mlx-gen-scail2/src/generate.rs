//! The live SCAIL-2 generation pipeline — the runnable end-to-end denoise loop (sc-5443).
//!
//! Ports `wan/scail.py::SCAIL2Pipeline.generate`: preprocess the reference character (+ optional
//! extra characters) and the driving video into conditioning latents, then run a plain-CFG
//! flow-matching denoise (UniPC / DPM++) over one or more 81-frame **segments** with clean-history
//! continuity, and VAE-decode each segment back to pixels.
//!
//! Reuse map — the heavy components are `mlx-gen-wan`'s (SCAIL-2 *is* Wan2.1-14B I2V): the z16
//! [`ProviderVae`] (encode/decode), the [`Umt5Encoder`] text encoder, and the flow-matching
//! [`make_scheduler`] (UniPC/DPM++). SCAIL-2's own pieces are the [`Scail2Dit`] forward, the
//! open-CLIP [`ScailClip`] image encode, the 28-channel [`extract_and_compress_mask_to_latent`] mask
//! build, and the [`interpolate`]/[`downsample_half`] resizes — all already parity-gated.
//!
//! Conditioning shapes (latent dims are `vae_stride`-down; `lat_h = H/8`, `lat_w = W/8`):
//!   * reference char → `ref_latent [16,1,lat_h,lat_w]` + `ref_mask_28 [28,1,lat_h,lat_w]` + CLIP
//!     features `[1,257,1280]`.
//!   * driving video (per segment, **half** spatial res) → `pose_latent [16,T,lat_h/2,lat_w/2]` +
//!     `driving_masks [28,T,lat_h/2,lat_w/2]`.
//!   * the noisy target latent `x [16,T,lat_h,lat_w]`; `ref_masks` is `ref_mask_28` padded with a
//!     zero null-noisy-mask over the latent length (`[28,1+T,lat_h,lat_w]`).

use std::path::Path;

use mlx_gen::array::scalar;
use mlx_gen::weights::Weights;
use mlx_gen::{AdapterSpec, CancelFlag, Error, GenerationOutput, Image, Progress, Quant, Result};
use mlx_gen_wan::pipeline::auto_tiling_budgeted_z16_quality_overlap;
use mlx_gen_wan::{
    frames_to_images, load_tokenizer, make_scheduler, DitMemoryConfig, SolverKind, Umt5Encoder,
};
use mlx_rs::ops::{add, concatenate_axis, maximum, minimum, multiply, subtract};
use mlx_rs::{random, Array, Dtype};

use crate::clip::{ClipVisionConfig, ScailClip};
use crate::config::Scail2Config;
use crate::model::{Scail2Dit, Scail2Inputs};
use crate::preprocess::{extract_and_compress_mask_to_latent, TEMPORAL_STRIDE};
use crate::resize::{clip_preprocess, downsample_half, interpolate, Interp};
use crate::{ProviderVae, VAE_TILING};

/// Wan2.1 flow-matching training horizon (upstream `config.num_train_timesteps`).
const NUM_TRAIN_TIMESTEPS: usize = 1000;

fn decode_tiling(
    height: i32,
    width: i32,
    out_frames: i32,
) -> Result<Option<mlx_gen::tiling::TilingConfig>> {
    auto_tiling_budgeted_z16_quality_overlap(height, width, out_frames)
}
/// SCAIL-2 DiT-denoise activation-memory defaults (sc-5681). NOTE: measurement showed the 832×480/5s
/// high-resolution OOM is the **VAE decode** (see the per-segment decode), not the DiT denoise — MLX's
/// `scaled_dot_product_attention` is flash here, so the 40-layer denoise fits even un-chunked. These
/// levers therefore bound the *denoise* peak for headroom + the larger buckets (1280×704) and are the
/// shared-layer "practice" the story carries to Wan/Bernini; they are not what unblocks 832×480.
///
/// - `eval_per_block` — caps the peak at ~one block's activations instead of the whole 40-block lazy
///   graph. Bit-exact, near-zero cost.
/// - `ffn_seq_chunk` — bounds the `[L, ffn_dim]` FFN intermediate (the largest denoise transient).
/// - `attn_query_chunk` — OFF by default (SDPA is flash here, so chunking the query path only adds
///   overhead); available via env for any bucket/model where SDPA falls back to a materialized
///   `[heads, L, L]` score matrix.
///
/// Numerically equivalent to the un-chunked forward (eval is bit-exact; the chunked GEMM differs only
/// by Metal tile-rounding, cosine ≈ 1). Overridable via `MLX_GEN_WAN_*` env
/// (see [`DitMemoryConfig::from_env`]).
const SCAIL2_MEM_DEFAULT: DitMemoryConfig = DitMemoryConfig {
    ffn_seq_chunk: Some(8192),
    attn_query_chunk: None,
    eval_per_block: true,
};
/// Inputs must be divisible by 32: the pose path halves spatially (→ ÷16) before the ÷8 VAE stride,
/// and the 28-channel mask pools 8×, so both the full and half grids must stay integer + even.
///
/// `pub(crate)` because the geometry gate in `pipeline.rs` (sc-16167) must judge the rendered
/// geometry on the same lattice [`align`] snaps it to, not on the pre-alignment request.
pub(crate) const DIM_ALIGN: u32 = VAE_TILING.spatial_scale as u32 * 4;

/// One masked character reference (the primary subject or an extra character): an RGB image paired
/// with its color-coded segmentation mask.
pub struct CharacterRef<'a> {
    pub image: &'a Image,
    pub mask: &'a Image,
}

/// A fully-specified SCAIL-2 generation job (the engine-internal form the worker maps a
/// `GenerationRequest` onto). `width` and `height` must already be non-zero multiples of the
/// 32-pixel render lattice; [`generate`] rejects an invalid job rather than silently changing its geometry.
/// All images are decoded + resized to `(width, height)` here.
pub struct Scail2Job<'a> {
    pub prompt: &'a str,
    pub negative_prompt: &'a str,
    pub width: u32,
    pub height: u32,
    /// The primary character (reference image + color mask).
    pub reference: CharacterRef<'a>,
    /// Extra characters for multi-reference (experimental); each paired with its mask.
    pub additional: Vec<CharacterRef<'a>>,
    /// Driving video frames (the motion source — raw end-to-end or a pose render).
    pub driving_frames: &'a [Image],
    /// Per-frame color-coded driving masks (same count as `driving_frames`).
    pub driving_masks: &'a [Image],
    /// `true` = cross-identity replacement, `false` = animation.
    pub replace_flag: bool,
    pub seed: u64,
    pub steps: usize,
    pub shift: f32,
    pub guidance: f32,
    pub sampler: SolverKind,
    pub fps: u32,
    pub segment_len: usize,
    pub segment_overlap: usize,
}

/// Align a **resolved driving-clip** dimension to [`DIM_ALIGN`] (down, with a min-one-tile floor —
/// this differs from wan/bernini's `align_dim`, which has no floor and would yield 0 for a sub-tile
/// value). Explicit sizes are rejected before reaching this function unless already on-grid
/// ([`SizeFloor::ResolvedDownstreamExplicitGrid`](mlx_gen::SizeFloor::ResolvedDownstreamExplicitGrid),
/// sc-16198); only source-media geometry the caller did not choose may be adjusted here. The
/// adjustment remains announced for diagnostics.
pub(crate) fn align(value: u32) -> usize {
    let aligned = (value / DIM_ALIGN).max(1) * DIM_ALIGN;
    if aligned != value {
        eprintln!(
            "scail2: requested dimension {value} is not a multiple of {DIM_ALIGN}; \
             aligning to the tile grid -> {aligned}"
        );
    }
    aligned as usize
}

/// Validate the exact render geometry carried by the public [`Scail2Job`] API.
///
/// Provider requests are checked by their advertised capability floor, and auto-sized provider
/// requests are aligned while their source-media origin is still known. Direct callers have neither
/// context, so this lower-level API accepts exact render geometry only.
fn validate_job_geometry(width: u32, height: u32) -> Result<(usize, usize)> {
    if width < DIM_ALIGN
        || height < DIM_ALIGN
        || !width.is_multiple_of(DIM_ALIGN)
        || !height.is_multiple_of(DIM_ALIGN)
    {
        return Err(Error::Msg(format!(
            "scail2: Scail2Job width/height must be non-zero multiples of {DIM_ALIGN} \
             (got {width}×{height})"
        )));
    }
    Ok((width as usize, height as usize))
}

/// Decode an `Image` (RGB24 `u8`) → `[3, th, tw]` f32 in `[-1, 1]`, resizing if its native size
/// differs. `mode` is `Bicubic` for photographic images, `Bilinear` for color masks (bounded — avoids
/// the bicubic overshoot that would invent out-of-gamut colors at mask edges).
fn image_to_chw(img: &Image, tw: usize, th: usize, mode: Interp) -> Result<Array> {
    let (iw, ih) = (img.width as usize, img.height as usize);
    if img.pixels.len()
        != mlx_gen::gen_core::imageops::checked_image_buffer_len(iw, ih, 3).unwrap_or(usize::MAX)
    {
        return Err(Error::Msg(format!(
            "scail2: image pixel buffer {} != {iw}x{ih}x3",
            img.pixels.len()
        )));
    }
    let px: Vec<f32> = img.pixels.iter().map(|&p| p as f32 / 127.5 - 1.0).collect();
    let chw = Array::from_slice(&px, &[ih as i32, iw as i32, 3]).transpose_axes(&[2, 0, 1])?; // [3,H,W]
    let nchw = chw.reshape(&[1, 3, ih as i32, iw as i32])?;
    let out = if (ih, iw) != (th, tw) {
        interpolate(&nchw, th, tw, mode)?
    } else {
        nchw
    };
    Ok(out.reshape(&[3, th as i32, tw as i32])?)
}

/// Stack driving frames → `[T, 3, H, W]` (frames-first, the layout `downsample_half` then `c t h w`
/// rearrange expects).
fn stack_frames(frames: &[Image], tw: usize, th: usize) -> Result<Array> {
    let chw: Vec<Array> = frames
        .iter()
        .map(|f| -> Result<Array> {
            Ok(image_to_chw(f, tw, th, Interp::Bicubic)?.reshape(&[1, 3, th as i32, tw as i32])?)
        })
        .collect::<Result<_>>()?;
    let refs: Vec<&Array> = chw.iter().collect();
    Ok(concatenate_axis(&refs, 0)?) // [T,3,H,W]
}

/// Stack per-frame masks → `[3, T, H, W]` (channels-first, the `extract_and_compress` input layout).
fn stack_masks(masks: &[Image], tw: usize, th: usize) -> Result<Array> {
    let chw: Vec<Array> =
        masks
            .iter()
            .map(|m| -> Result<Array> {
                Ok(image_to_chw(m, tw, th, Interp::Bilinear)?
                    .reshape(&[3, 1, th as i32, tw as i32])?)
            })
            .collect::<Result<_>>()?;
    let refs: Vec<&Array> = chw.iter().collect();
    Ok(concatenate_axis(&refs, 1)?) // [3,T,H,W]
}

/// VAE-encode an `[3, T, H, W]` pixel clip (`[-1,1]`) → `[16, T_lat, H/8, W/8]` (drops the batch dim
/// the `WanVae` API carries).
fn vae_encode_cthw(vae: &ProviderVae, cthw: &Array) -> Result<Array> {
    let s = cthw.shape();
    let z = vae.encode(&cthw.reshape(&[1, s[0], s[1], s[2], s[3]])?)?;
    let zs = z.shape(); // [1,16,T_lat,h,w]
    Ok(z.reshape(&[zs[1], zs[2], zs[3], zs[4]])?)
}

/// `uncond + guidance·(cond − uncond)`.
fn cfg_combine(uncond: &Array, cond: &Array, guidance: f32) -> Result<Array> {
    Ok(add(
        uncond,
        &multiply(&subtract(cond, uncond)?, scalar(guidance))?,
    )?)
}

/// Overwrite the leading `min(history_t, T)` latent frames of `latent [16,T,h,w]` with the clean
/// history (upstream `apply_clean_history`). No-op without history.
fn apply_clean_history(latent: &Array, history: Option<&Array>) -> Result<Array> {
    let Some(h) = history else {
        return Ok(latent.clone());
    };
    let lt = latent.shape()[1];
    let ht = h.shape()[1].min(lt);
    if ht <= 0 {
        return Ok(latent.clone());
    }
    let head = h.take_axis(Array::from_slice(&(0..ht).collect::<Vec<i32>>(), &[ht]), 1)?;
    if ht == lt {
        return Ok(head);
    }
    let tail = latent.take_axis(
        Array::from_slice(&(ht..lt).collect::<Vec<i32>>(), &[lt - ht]),
        1,
    )?;
    Ok(concatenate_axis(&[&head, &tail], 1)?)
}

/// F-039: validate the public `Scail2Job.segment_len` / `segment_overlap` fields. `build_segments`
/// computes `stride = segment_len - segment_overlap` (so `overlap >= len` underflows `usize`), and
/// the clean-history VAE encode in segment 2+ shape-errors when `segment_len` isn't `1 + 4k` (the 4×
/// temporal compression factor). The guards apply only when the clip actually windows
/// (`total_frames > segment_len`): the single-window path in [`build_segments`] never derives a
/// stride or a cross-segment history from the window params, so a short-clip job must not be newly
/// rejected over fields it doesn't use. Extracted so the guards have a unit test (generate() needs
/// weights).
fn validate_segment_params(
    total_frames: usize,
    segment_len: usize,
    segment_overlap: usize,
) -> Result<()> {
    if total_frames <= segment_len {
        return Ok(());
    }
    if segment_len == 0 {
        return Err(Error::Msg("scail2: segment_len must be >= 1".into()));
    }
    if segment_overlap >= segment_len {
        return Err(Error::Msg(format!(
            "scail2: segment_overlap ({}) must be < segment_len ({}) \
             (the window stride is segment_len − segment_overlap)",
            segment_overlap, segment_len
        )));
    }
    if !(segment_len - 1).is_multiple_of(TEMPORAL_STRIDE) {
        return Err(Error::Msg(format!(
            "scail2: segment_len ({}) must be 1 + {TEMPORAL_STRIDE}·k \
             (VAE temporal alignment across overlapping segments)",
            segment_len
        )));
    }
    Ok(())
}

/// Segment plan over `total` driving frames (upstream `build_segments`): a single VAE-aligned segment
/// when the clip fits, else overlapping `segment_len` windows striding by `len − overlap`.
fn build_segments(total: usize, len: usize, overlap: usize) -> Vec<(usize, usize)> {
    if total <= len {
        let keep = ((total - 1) / TEMPORAL_STRIDE) * TEMPORAL_STRIDE + 1;
        return vec![(0, keep)];
    }
    let mut segs = Vec::new();
    let stride = len - overlap;
    let mut start = 0;
    while start < total {
        let end = start + len;
        if end > total {
            break;
        }
        segs.push((start, end));
        start += stride;
    }
    segs
}

/// `[3, T, H, W]` in `[-1,1]` → `[T, H, W, 3]` `u8` in `[0,255]`.
fn pixels_to_u8(video_cthw: &Array) -> Result<Array> {
    let thwc = video_cthw.transpose_axes(&[1, 2, 3, 0])?; // [T,H,W,3]
    let scaled = multiply(&add(&thwc, scalar(1.0))?, scalar(127.5))?;
    let clamped = minimum(&maximum(&scaled, scalar(0.0))?, scalar(255.0))?;
    Ok(mlx_rs::ops::round(&clamped, None)?.as_dtype(Dtype::Uint8)?)
}

/// Run the full SCAIL-2 generation for `job`, loading each component from the snapshot `root`.
pub fn generate(
    root: &Path,
    cfg: &Scail2Config,
    job: &Scail2Job,
    quant: Option<Quant>,
    adapters: &[AdapterSpec],
    cancel: &CancelFlag,
    on_progress: &mut dyn FnMut(Progress),
) -> Result<GenerationOutput> {
    // Validate before touching media, adapter files, or model weights. This is also the exact
    // geometry all image and latent paths consume, so the public job API cannot fall back to
    // `align` and snap.
    let (tw, th) = validate_job_geometry(job.width, job.height)?;
    if job.driving_frames.is_empty() {
        return Err(Error::Msg("scail2: a driving video is required".into()));
    }
    if job.driving_masks.len() != job.driving_frames.len() {
        return Err(Error::Msg(format!(
            "scail2: driving_masks ({}) must match driving_frames ({})",
            job.driving_masks.len(),
            job.driving_frames.len()
        )));
    }
    // F-039: Scail2Job has public fields and nothing else validates them. `build_segments` computes
    // `stride = segment_len - segment_overlap`, so `overlap >= len` underflows `usize` (debug panic;
    // release wraps to a huge stride and silently renders one window). And the clean-history VAE
    // encode in segment 2+ shape-errors when `segment_len` isn't VAE-temporal-aligned (the 4×
    // temporal compression factor: segment_len must be `1 + 4k` so the decoded frame count matches
    // across overlapping windows). Reject both up front with a typed error (windowing jobs only —
    // a short clip takes the single-window path, which ignores these fields).
    validate_segment_params(
        job.driving_frames.len(),
        job.segment_len,
        job.segment_overlap,
    )?;
    // Split the inference LoRAs BY ROLE, not by file (sc-18198). A lightx2v "lightning" file is a
    // hybrid, and its two halves want opposite treatment:
    //   * full-rank `.diff`/`.diff_b` deltas land on the qk-norms, `norm3`, `head.head`,
    //     `img_emb.proj.{0,4}` and the Linear biases — none of which the residual host exposes as
    //     adapter targets, so they are folded into the raw weight map below (sc-5684). Every one of
    //     those tensors stays DENSE bf16 in the pre-quantized q4/q8 tiers (only the 2-D block
    //     projections are packed), so the fold is tier-independent.
    //   * low-rank `lora_down`/`lora_up` factors target exactly the projections that DO get packed.
    //     Those install as forward-time residuals after the build+quantize, which is the one form
    //     that works over a packed base — and is already how the Bias-Aware DPO LoRA loads (sc-5451).
    // So EVERY spec goes to the residual pass, and diff-patch files additionally go to the fold. The
    // two passes are disjoint by key suffix — the low-rank loader groups only `.lora_A`/`.lora_down`/
    // `.lora_B`/`.lora_up`/`.alpha` and ignores every other key, so a hybrid file is never applied
    // twice. This replaces the blanket "needs the DENSE (bf16) snapshot" rejection, which failed the
    // whole file whenever the tier was pre-quantized even though nothing in it actually requires a
    // dense base; a full-rank delta that genuinely CANNOT be carried is now refused per-target by
    // `report_outcome` instead.
    let mut diff_patch: Vec<&AdapterSpec> = Vec::new();
    let mut residual: Vec<AdapterSpec> = Vec::new();
    for spec in adapters {
        // Propagate a header read failure rather than defaulting to "not a diff-patch": treating an
        // unreadable adapter as low-rank-only would drop its `.diff` half without a word.
        if crate::lora::has_diff_patch_keys(&spec.path)? {
            diff_patch.push(spec);
        }
        // A file joins the residual pass unless the diff-patch fold consumed ALL of it. Tested by
        // exclusion rather than by listing LoRA suffixes: the installer also handles LoKr/LoHa (the
        // descriptor advertises `supports_lokr`), and an allow-list would silently drop those.
        if crate::lora::has_residual_installable_keys(&spec.path)? {
            residual.push(spec.clone());
        }
    }
    let cfg_disabled = job.guidance <= 1.0;
    // Experimental bf16 compute opt-in (sc-5681; see the DiT block below). Read once here so the
    // per-segment NaN guard (F-096) keys off the same flag.
    let compute_bf16 = std::env::var("SCAIL2_COMPUTE_BF16").is_ok_and(|v| v == "1");

    // --- decode + resize all pixel inputs to (tw, th) ---
    let ref_chw = image_to_chw(job.reference.image, tw, th, Interp::Bicubic)?; // [3,H,W]
    let ref_mask_chw = image_to_chw(job.reference.mask, tw, th, Interp::Bilinear)?; // [3,H,W]
    let driving = stack_frames(job.driving_frames, tw, th)?; // [T,3,H,W]
    let driving_mask = stack_masks(job.driving_masks, tw, th)?; // [3,T,H,W]

    // --- VAE (kept resident: per-segment pose encode + final decode) ---
    let vae = {
        let w = Weights::from_file(root.join("vae.safetensors"))?;
        ProviderVae::from_weights(&w)?
    };

    // Reference char latent + its 28-ch mask (1 latent frame).
    let ref_latent = vae_encode_cthw(&vae, &ref_chw.reshape(&[3, 1, th as i32, tw as i32])?)?;
    let ref_mask_28 = extract_and_compress_mask_to_latent(
        &ref_mask_chw.reshape(&[3, 1, th as i32, tw as i32])?,
        TEMPORAL_STRIDE,
    )?;
    let lat_h = ref_latent.shape()[2];
    let lat_w = ref_latent.shape()[3];

    // Extra characters (multi-reference): cat latents + masks on the frame axis.
    let (additional_ref_latent, additional_ref_masks) = if job.additional.is_empty() {
        (None, None)
    } else {
        let mut lats = Vec::new();
        let mut masks = Vec::new();
        for c in &job.additional {
            let img = image_to_chw(c.image, tw, th, Interp::Bicubic)?
                .reshape(&[3, 1, th as i32, tw as i32])?;
            lats.push(vae_encode_cthw(&vae, &img)?);
            let mk = image_to_chw(c.mask, tw, th, Interp::Bilinear)?
                .reshape(&[3, 1, th as i32, tw as i32])?;
            masks.push(extract_and_compress_mask_to_latent(&mk, TEMPORAL_STRIDE)?);
        }
        let lr: Vec<&Array> = lats.iter().collect();
        let mr: Vec<&Array> = masks.iter().collect();
        (
            Some(concatenate_axis(&lr, 1)?),
            Some(concatenate_axis(&mr, 1)?),
        )
    };

    // --- UMT5 text encode (loaded → used → freed) ---
    let (context, context_null) = {
        let tok = load_tokenizer(root.join("tokenizer.json"), cfg.wan.text_len)?;
        let w = Weights::from_file(root.join("t5_encoder.safetensors"))?;
        let enc = Umt5Encoder::from_weights(&w, &cfg.wan)?;
        let c = enc.encode(&tok, job.prompt)?;
        let cn = if cfg_disabled {
            c.clone()
        } else {
            enc.encode(&tok, job.negative_prompt)?
        };
        mlx_rs::transforms::eval([&c, &cn])?;
        (c, cn)
    };

    // --- CLIP reference-image features (loaded → used → freed) ---
    let clip_fea = {
        let w = Weights::from_file(root.join("clip.safetensors"))?;
        let clip = ScailClip::from_weights(&w, &ClipVisionConfig::vit_h_14())?;
        let pixel = clip_preprocess(&ref_chw.reshape(&[1, 3, th as i32, tw as i32])?, 224)?;
        let f = clip.encode(&pixel)?;
        mlx_rs::transforms::eval([&f])?;
        f
    };

    // --- DiT (bf16 production compute; optional Q4/Q8 load-time quant, sc-5445) ---
    let dit = {
        let mut w = Weights::from_file(root.join("dit.safetensors"))?;
        // sc-5684: merge any lightx2v diff-patch ("lightning") LoRA(s) into the dense weights *before*
        // building + quantizing — `.diff`/`.diff_b`/low-rank factors fold uniformly into the raw
        // `{stem}.weight`/`.bias` map (handling the qk-norms, the affine LayerNorms, every bias, and
        // the full-rank `head.head` delta the residual host can't reach), with the in_dim-36 vanilla
        // `patch_embedding` deliberately skipped (shape-incompatible) and surfaced loudly.
        if !diff_patch.is_empty() {
            let report = crate::lora::merge_diff_patch_adapters(&mut w, &diff_patch)?;
            crate::lora::report_outcome(&report, crate::pipeline::MODEL_ID)?;
        }
        let mut d = Scail2Dit::from_weights(&w, cfg)?;
        // f32 matmul compute (sc-5681). The bf16 path overflows to NaN at long sequences: traced to a
        // bf16 quantized-matmul (the self-attention `o` projection is the first to blow up — its
        // SDPA input is clean at max ~15 — but f32-ing only `o` just moves the overflow to the next
        // projection), reproduced at L≈42k (832×480·5s) and clean in f32. bf16 was never parity-gated
        // (the gates run f32); f32 is the validated-correct path and the Q4 weights still bound the
        // weight memory. `SCAIL2_COMPUTE_BF16=1` opts back into the (fast, but high-res-unsafe) bf16
        // path for experiments (guarded per segment by the F-096 NaN check below). A mixed-precision
        // pass to recover bf16 speed at high res is a follow-up.
        d.set_compute_dtype(if compute_bf16 {
            Dtype::Bfloat16
        } else {
            Dtype::Float32
        });
        // sc-5681: bound the per-step activation peak so the high-resolution buckets don't OOM.
        d.set_memory_config(DitMemoryConfig::from_env(SCAIL2_MEM_DEFAULT));
        // Quantize the attention + FFN Linears in place (Q4 default in the SceneWorks worker). The
        // packed Q4/Q8 weights are what stays resident; the bf16 source is freed in `quantize`.
        if let Some(q) = quant {
            d.quantize(q.bits(), None)?;
        }
        // Install any pure low-rank inference LoRA(s) — the Bias-Aware DPO refinement LoRA, a
        // diff-stripped lightning subset, … — as forward-time residuals over the (now possibly Q4/Q8)
        // base (sc-5451). Adapters are independent of the base quantization, so they stack cleanly on
        // the packed weights; applying them *after* `quantize` keeps the residual a dense add over the
        // quantized matmul. The family-agnostic strict installer (the Z-Image / Qwen path) resolves the
        // diffusers / PEFT / kohya / LoKr keys against SCAIL-2's raw module names and errors — never
        // silently drops — on a format/prefix mismatch or an unmatched target. (The diff-patch
        // lightning files were already merged into the dense weights above, sc-5684.)
        if !residual.is_empty() {
            mlx_gen::adapters::loader::apply_adapters_strict(
                &mut d,
                &residual,
                crate::pipeline::MODEL_ID,
            )?;
        }
        d
    };

    let segments = build_segments(
        job.driving_frames.len(),
        job.segment_len,
        job.segment_overlap,
    );
    // F-096: `build_segments` VAE-aligns the single window (`1 + 4k` frames kept) or drops the
    // trailing partial window (multi-segment), so driving frames past the last window boundary are
    // silently cut from the output. Surface the drop like the `align` dimension crop above
    // (sc-6983) rather than reinterpreting the request invisibly; the caller stays infallible.
    let total_frames = job.driving_frames.len();
    let covered = segments.last().map_or(0, |&(_, end)| end);
    if covered < total_frames {
        eprintln!(
            "scail2: dropping the trailing {} of {total_frames} driving frame(s) — the segment \
             plan covers {covered} (segment_len {} / overlap {} / VAE {TEMPORAL_STRIDE}-frame \
             alignment)",
            total_frames - covered,
            job.segment_len,
            job.segment_overlap
        );
    }
    let num_segments = segments.len() as u32;
    let mut out_pieces: Vec<Array> = Vec::new();
    let mut prev_history_pixel: Option<Array> = None;

    for (seg_idx, &(seg_start, seg_end)) in segments.iter().enumerate() {
        // Per-segment cancellation checkpoint (F-003): the inter-segment VAE pose-encode +
        // full segment decode are minutes of work outside the inner step loop, so also bail
        // here at each segment boundary.
        if cancel.is_cancelled() {
            return Err(Error::Canceled);
        }

        // Pose latent (half spatial res) + driving mask for this segment.
        let pose_seg = driving.take_axis(
            Array::from_slice(
                &(seg_start as i32..seg_end as i32).collect::<Vec<i32>>(),
                &[(seg_end - seg_start) as i32],
            ),
            0,
        )?; // [T,3,H,W]
        let pose_half = downsample_half(&pose_seg)?; // [T,3,H/2,W/2]
        let pose_cthw = pose_half.transpose_axes(&[1, 0, 2, 3])?; // [3,T,H/2,W/2]
        let pose_latent = vae_encode_cthw(&vae, &pose_cthw)?; // [16,T_lat,h/2,w/2]
        let lat_t = pose_latent.shape()[1];

        let dmask_seg = driving_mask.take_axis(
            Array::from_slice(
                &(seg_start as i32..seg_end as i32).collect::<Vec<i32>>(),
                &[(seg_end - seg_start) as i32],
            ),
            1,
        )?; // [3,T,H,W]
        let dmask_half = downsample_half(&dmask_seg)?; // [3,T,H/2,W/2]
        let driving_masks = extract_and_compress_mask_to_latent(&dmask_half, TEMPORAL_STRIDE)?;

        // ref_masks = ref_mask_28 ++ zero null-noisy-mask over the latent length.
        let null_noisy = Array::zeros::<f32>(&[28, lat_t, lat_h, lat_w])?;
        let ref_masks = concatenate_axis(&[&ref_mask_28, &null_noisy], 1)?; // [28,1+T,h,w]

        // Clean-history latent + i2v mask for segments after the first.
        let (history_latent, history_mask) = match &prev_history_pixel {
            Some(hp) if seg_idx > 0 => {
                let hl = vae_encode_cthw(&vae, hp)?; // [16,h_t,h,w]
                let h_t = hl.shape()[1].min(lat_t);
                let ones = Array::ones::<f32>(&[4, h_t, lat_h, lat_w])?;
                let hm = if h_t < lat_t {
                    let z = Array::zeros::<f32>(&[4, lat_t - h_t, lat_h, lat_w])?;
                    concatenate_axis(&[&ones, &z], 1)?
                } else {
                    ones
                };
                (Some(hl), Some(hm))
            }
            _ => (None, None),
        };

        // Seeded init noise (per-segment key; exact RNG values differ mlx-rs vs torch, as expected).
        let key = random::key(job.seed.wrapping_add(seg_idx as u64))?;
        let noise = random::normal::<f32>(&[16, lat_t, lat_h, lat_w], None, None, Some(&key))?;

        // --- denoise (plain CFG, clean-history pinned) ---
        let mut sched = make_scheduler(job.sampler, NUM_TRAIN_TIMESTEPS);
        sched.set_timesteps(job.steps, job.shift);
        let timesteps: Vec<f32> = sched.timesteps().to_vec();
        // F-096: report progress over the WHOLE job (steps × segments), not per segment — the old
        // per-segment `Step{i, steps}` restarted at 1/N on every segment boundary, so a multi-segment
        // render appeared to loop. The schedule is rebuilt identically per segment, so the per-segment
        // step count is constant.
        let seg_steps = timesteps.len() as u32;
        let total = seg_steps * num_segments;

        let mut latent = apply_clean_history(&noise, history_latent.as_ref())?;
        for (i, &t) in timesteps.iter().enumerate() {
            // Honor the engine cancellation contract (F-003): a SCAIL-2 segment render runs
            // minutes, so check before each (forward + step) iteration. The per-step `eval` below
            // makes this effective — without it MLX's lazy graph defers all compute to the VAE
            // decode and this check would pass for every step (mirrors mlx-gen-wan denoise).
            if cancel.is_cancelled() {
                return Err(Error::Canceled);
            }
            let x = apply_clean_history(&latent, history_latent.as_ref())?;
            let mut inp = Scail2Inputs {
                x: &x,
                ref_latent: &ref_latent,
                ref_masks: &ref_masks,
                pose_latent: &pose_latent,
                driving_masks: &driving_masks,
                history_mask: history_mask.as_ref(),
                additional_ref_latent: additional_ref_latent.as_ref(),
                additional_ref_masks: additional_ref_masks.as_ref(),
                clip_fea: &clip_fea,
                context: &context,
                t,
                replace_flag: job.replace_flag,
            };
            let pred_cond = dit.forward(&inp)?;
            let pred = if cfg_disabled {
                pred_cond
            } else {
                inp.context = &context_null;
                let pred_uncond = dit.forward(&inp)?;
                cfg_combine(&pred_uncond, &pred_cond, job.guidance)?
            };
            latent = sched.step(&pred, &latent)?;
            latent = apply_clean_history(&latent, history_latent.as_ref())?;
            mlx_rs::transforms::eval([&latent])?;
            on_progress(Progress::Step {
                current: seg_idx as u32 * seg_steps + (i + 1) as u32,
                total,
            });
        }
        // F-096: the bf16 opt-in re-enables the sc-5681 long-sequence overflow path with no gate —
        // a NaN latent survives the decode and the `pixels_to_u8` clamp (min/max propagate NaN) and
        // ships garbage pixels as success. Fail loudly at the segment boundary instead. f32 (the
        // validated default) skips the check.
        if compute_bf16 && latent.is_nan()?.any(None)?.item::<bool>() {
            return Err(Error::Msg(format!(
                "scail2: NaN in the denoised latent for segment {}/{num_segments} — the \
                 SCAIL2_COMPUTE_BF16=1 experimental bf16 compute path overflows at long sequences \
                 (sc-5681); unset it to run the validated f32 path",
                seg_idx + 1
            )));
        }
        // sc-5681: release the MLX buffer cache before the VAE decode. The decode is the heaviest
        // phase (Metal conv scratch ~2× its MLX-active), so the cache retained from preprocessing +
        // denoise (~35 GB) would otherwise stack under it — measured 832×480/5s footprint 111 → 76 GB.
        mlx_rs::memory::clear_cache();

        // --- decode this segment → pixels; stitch + carry history ---
        // sc-5681: tile the VAE decode. Decoding the whole `[3, 4·T_lat, 480, 832]` segment in one
        // pass is the high-res activation peak (≈139 GB → OOMs a 128 GB Mac), NOT the DiT denoise
        // (which fits — MLX SDPA is flash). SCAIL-2's hand-rolled loop used the plain `decode` and
        // omitted the tiling the shared wan path already does.
        //
        // sc-15325: this used to size its own **temporal-only** window from a local
        // 3.5e6 px·frames budget, byte-for-byte the same computation
        // `mlx-gen-krea-realtime` had. At every bucket ≥ ~233k px/frame (640×384, 512×512, 768×512,
        // 832×480, 1280×720) that yielded an 8-output-frame window — **two latent frames** — which
        // starves the z16 decoder's temporal convolutions: measured on the sibling krea path against a
        // single-pass reference, 18.5/255 mean abs err with 26.6% of a worst frame blown to white.
        // Content corruption with the period of the tile stride, not a seam the blend could fix.
        //
        // It now goes through the same budgeted core/cost model as the Wan z16 T2V/I2V/VACE decodes,
        // but retains the quality-oriented overlap through
        // `auto_tiling_budgeted_z16_quality_overlap`. gen-core's
        // `MIN_TEMPORAL_TILE_LATENT_FRAMES` floor makes a sub-8-latent-frame
        // temporal tile unselectable at any budget, and memory pressure is relieved on the **spatial**
        // axis instead — which is affordable precisely because sc-5690 verified `tile_decode_accumulate`
        // reconstructs a combined spatial+temporal plan exactly on the real z16 VAE at this geometry,
        // and because a 320 px spatial tile is 40 latent px wide with an 8-latent-px overlap: far more
        // context per axis than the 2/1 latent frames the old temporal window allowed. The budget is
        // free-aware (`free × 0.85`, `free = MLX limit − resident`), so the old "bound the peak as the
        // resolution grows" intent is preserved and now measured against real availability rather than
        // a hard-coded pixel budget. The write-cap safety (sc-12438 Req 3) is inside the selector.
        on_progress(Progress::Decoding);
        let zs = latent.shape();
        let z = latent.reshape(&[1, zs[0], zs[1], zs[2], zs[3]])?;
        let z_shape = z.shape();
        let out_frames = z_shape[2] * VAE_TILING.temporal_scale;
        let out_height = z_shape[3] * VAE_TILING.spatial_scale;
        let out_width = z_shape[4] * VAE_TILING.spatial_scale;
        let video = {
            // `Err` is the catchable over-budget signal (raised before the decode, not as a SIGKILL).
            let cfg = decode_tiling(out_height, out_width, out_frames)?;
            match cfg.as_ref() {
                // [1,3,T_out,H,W]; `decode_tiled` also falls back to a single pass if it doesn't tile.
                Some(cfg) => vae.decode_tiled(&z, cfg, Some(cancel))?,
                None => vae.decode(&z)?,
            }
        };
        let vs = video.shape();
        let seg_video = video.reshape(&[vs[1], vs[2], vs[3], vs[4]])?; // [3,T_out,H,W]
        let t_out = seg_video.shape()[1];

        let keep_from = if seg_idx == 0 {
            0
        } else {
            job.segment_overlap as i32
        };
        let piece = seg_video.take_axis(
            Array::from_slice(
                &(keep_from..t_out).collect::<Vec<i32>>(),
                &[t_out - keep_from],
            ),
            1,
        )?;
        mlx_rs::transforms::eval([&piece])?;
        out_pieces.push(piece);

        if seg_idx + 1 < segments.len() {
            let ov = job.segment_overlap as i32;
            prev_history_pixel = Some(seg_video.take_axis(
                Array::from_slice(&(t_out - ov..t_out).collect::<Vec<i32>>(), &[ov]),
                1,
            )?);
        }
    }

    let piece_refs: Vec<&Array> = out_pieces.iter().collect();
    let full = concatenate_axis(&piece_refs, 1)?; // [3,T_total,H,W]
    let frames_u8 = pixels_to_u8(&full)?;
    let frames = frames_to_images(&frames_u8)?;
    Ok(GenerationOutput::Video {
        frames,
        fps: job.fps,
        audio: None,
    })
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn build_segments_single_window_when_clip_fits() {
        // 13 frames (1 + 4·3, VAE-aligned), len=13 → one window keeping all 13 aligned frames.
        let segs = build_segments(13, 13, 0);
        assert_eq!(segs, vec![(0, 13)]);
    }

    #[test]
    fn build_segments_overlapping_windows() {
        // 25 frames, len=9, overlap=4 → stride 5: (0,9),(5,14),(10,19),(15,24).
        let segs = build_segments(25, 9, 4);
        assert_eq!(segs, vec![(0, 9), (5, 14), (10, 19), (15, 24)]);
    }

    #[test]
    fn build_segments_single_window_drops_trailing_unaligned_frames() {
        // F-096: 15 frames, len=20 → single window VAE-aligned to 1 + 4k = 13, dropping the
        // trailing 2 (generate() surfaces the drop; this pins the plan's coverage).
        let segs = build_segments(15, 20, 0);
        assert_eq!(segs, vec![(0, 13)]);
    }

    #[test]
    fn build_segments_multi_window_drops_trailing_partial_window() {
        // F-096: 23 frames, len=9, overlap=4 → stride 5: (0,9),(5,14),(10,19); the next window
        // (15,24) overruns 23 frames, so frames 19..23 are dropped from the plan.
        let segs = build_segments(23, 9, 4);
        assert_eq!(segs, vec![(0, 9), (5, 14), (10, 19)]);
        assert_eq!(segs.last().unwrap().1, 19);
    }

    #[test]
    fn validate_segment_params_rejects_overlap_ge_len() {
        // F-039: overlap >= len would underflow the usize stride in build_segments (the guards
        // apply because total > segment_len ⇒ the multi-window path strides).
        let err = validate_segment_params(20, 5, 5).unwrap_err().to_string();
        assert!(err.contains("must be < segment_len"), "{err}");
        let err = validate_segment_params(20, 5, 9).unwrap_err().to_string();
        assert!(err.contains("must be < segment_len"), "{err}");
    }

    #[test]
    fn validate_segment_params_rejects_non_vae_aligned_len() {
        // segment_len must be 1 + 4k so the clean-history VAE encode aligns across segments.
        let err = validate_segment_params(20, 10, 2).unwrap_err().to_string();
        assert!(err.contains("1 + 4"), "{err}");
    }

    #[test]
    fn validate_segment_params_accepts_aligned_window() {
        // 9 = 1 + 4·2, overlap 4 < 9 — the realistic SCAIL-2 window.
        validate_segment_params(25, 9, 4).expect("aligned window is valid");
    }

    #[test]
    fn validate_segment_params_skips_guards_for_short_clips() {
        // F-096 regression: a clip that fits one window (`total <= segment_len`) takes the
        // single-window path, which never uses segment_len/overlap — a previously-working
        // short-clip job must not be newly rejected over fields it doesn't use.
        validate_segment_params(13, 81, 81).expect("single-window job ignores window params");
        validate_segment_params(10, 10, 3).expect("total == segment_len is single-window");
    }

    #[test]
    fn public_job_geometry_is_exact_or_rejected() {
        assert_eq!(
            validate_job_geometry(1280, 704).expect("on-grid geometry is exact"),
            (1280, 704)
        );
        for (width, height) in [(1280, 730), (730, 1280), (0, 704), (704, 0)] {
            let err = validate_job_geometry(width, height)
                .expect_err("the public low-level job must never be silently snapped")
                .to_string();
            assert!(
                err.contains("non-zero multiples of 32")
                    && err.contains(&format!("{width}×{height}")),
                "got: {err}"
            );
        }
    }

    #[test]
    fn public_generate_rejects_geometry_before_adapter_io() {
        let image = Image {
            width: 1,
            height: 1,
            pixels: vec![0; 3],
        };
        let frames = [image.clone()];
        let masks = [image.clone()];
        let job = Scail2Job {
            prompt: "p",
            negative_prompt: "",
            width: 1280,
            height: 730,
            reference: CharacterRef {
                image: &image,
                mask: &image,
            },
            additional: Vec::new(),
            driving_frames: &frames,
            driving_masks: &masks,
            replace_flag: false,
            seed: 0,
            steps: 1,
            shift: 5.0,
            guidance: 1.0,
            sampler: SolverKind::UniPC,
            fps: 16,
            segment_len: 81,
            segment_overlap: 5,
        };
        let inaccessible = AdapterSpec::new(
            std::path::PathBuf::from("/sc16198-missing/adapter.safetensors"),
            1.0,
            mlx_gen::AdapterKind::Lora,
        );
        let mut noop = |_: Progress| {};
        let err = generate(
            Path::new("/sc16198-missing/snapshot"),
            &Scail2Config::default(),
            &job,
            None,
            &[inaccessible],
            &CancelFlag::default(),
            &mut noop,
        )
        .expect_err("invalid public job geometry must fail before adapter or snapshot I/O")
        .to_string();
        assert!(
            err.contains("non-zero multiples of 32") && err.contains("1280×730"),
            "geometry must be the first error, got: {err}"
        );
    }

    /// sc-15445: SCAIL-2 shares Krea's half-tile quality policy, not Wan's restored product overlap.
    #[test]
    fn decode_tiling_retains_scail2s_half_tile_overlap() {
        std::env::set_var("WAN_VAE_BUDGET_GIB", "10");
        let cfg = decode_tiling(384, 640, 84)
            .unwrap()
            .expect("the measured SCAIL-2 row must tile at 10 GiB");
        std::env::remove_var("WAN_VAE_BUDGET_GIB");
        assert_eq!(
            cfg.temporal.map(|t| (t.tile_frames, t.overlap_frames)),
            Some((32, 16)),
        );
    }
}
