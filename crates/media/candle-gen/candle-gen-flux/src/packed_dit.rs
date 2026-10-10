//! Vendored **diffusers-layout** FLUX.1 MMDiT (`FluxTransformer2DModel`) with the shared packed-load
//! seam (sc-9407) — the candle twin of the flux2-dev vendored transformer (sc-9087) and the z-image
//! `packed_dit` (sc-9408).
//!
//! **Why a vendored diffusers DiT.** The stock txt2img path ([`crate::pipeline`]) uses
//! `candle-transformers`'s **BFL-layout** `flux::model::Flux` (`double_blocks`/`single_blocks`, fused
//! `img_attn.qkv`). The pre-quantized MLX tier (`SceneWorks/flux1-schnell-mlx`, epic 8506) ships the
//! **diffusers** `FluxTransformer2DModel` layout instead (`transformer_blocks`/`single_transformer_blocks`,
//! split `attn.to_q`/`to_k`/`to_v`, `norm1.linear` AdaLN-Zero, `ff.net.0.proj`) — the exact layout the
//! FLUX control branch already ports ([`crate::control`]). So the packed path vendors a minimal
//! diffusers DiT here, building every `Linear` through the packed-detecting [`crate::quant::QLinear`] so
//! q4/q8 load straight from the packed parts (no dense staging), while a dense diffusers snapshot (bf16,
//! no `.scales`) loads through the same code unchanged. Numerically this is the diffusers formulation of
//! the same FLUX.1 forward the stock BFL model computes (both consume the same VAE-packed latents / T5
//! context / CLIP pooled vector and emit the same velocity). Coverage for this vendored DiT is:
//! (a) the shared-module packed-vs-dense projection parity unit tests (the [`crate::quant`] `QLinear`
//! seam every `Linear` here is built through), (b) a coherent q4 GPU render end-to-end, plus the local
//! shape/finite forward smoke below, and (c) **a stock-vs-vendored DiT numeric parity test** (sc-9443):
//! `vendored_dit_matches_stock_bfl_dense` builds this DiT dense, remaps its diffusers weights into the
//! BFL key layout (split-QKV → fused-QKV concat, `to_out.0` → `proj`, per-embedder rename) and pins its
//! forward against the stock `candle-transformers` `Flux` at 1e-4 on shared weights — mirroring the
//! CLIP/T5 encoder parity tests in [`crate::packed_te`]. This anchors the vendored DiT's RoPE / QK-norm
//! / QKV-split / modulation-chunk ordering so a subtly-wrong-but-coherent port cannot escape CI.
//!
//! The RoPE / SDPA / timestep-embedding helpers are **reused** from [`crate::ip_dit`] (the same FLUX
//! RoPE the BFL model and the control branch use), so this file adds no numerics of its own beyond the
//! diffusers block wiring. The diffusers double block is structurally the [`crate::control::JointBlock`]
//! (AdaLN-Zero modulation, split-projection joint attention, gated FF); the single block + the AdaLN
//! output head are added here.

use candle_gen::candle_core::{DType, Device, Result, Tensor, D};
use candle_gen::candle_nn::{LayerNorm, Module, RmsNorm, VarBuilder};
use candle_gen::gen_core::attention_budget::{AttentionBudget, AttentionPlan};
use candle_gen::quant::PackedWeightSidecars;
use std::sync::Arc;

use crate::ip_adapter::FluxIpInjector;
use crate::ip_dit::{
    apply_rope, control_residual_interval, scaled_dot_product_attention_planned,
    timestep_embedding, Config, DitImageInjector, EmbedNd,
};
use crate::quant::QLinear;

struct StreamLoad<'a> {
    sidecars: &'a PackedWeightSidecars,
    prefix: String,
}

fn load_linear(
    in_dim: usize,
    out_dim: usize,
    vb: &VarBuilder,
    base: &str,
    bias: bool,
    stream: Option<&StreamLoad<'_>>,
) -> Result<QLinear> {
    let Some(stream) = stream else {
        return QLinear::linear_detect(in_dim, out_dim, vb, base, bias);
    };
    if !vb.contains_tensor(&format!("{base}.scales")) {
        return QLinear::linear_detect(in_dim, out_dim, vb, base, bias);
    }
    let sidecar_base = format!("{}.{}", stream.prefix, base);
    if !stream.sidecars.contains(&sidecar_base) {
        candle_gen::candle_core::bail!(
            "FLUX streamed packed projection `{sidecar_base}` has no prepared device-format sidecar"
        );
    }
    let dense_bias = bias
        .then(|| vb.get(out_dim, &format!("{base}.bias")))
        .transpose()?;
    let qtensor = stream.sidecars.load(&sidecar_base, vb.device())?;
    Ok(candle_gen::quant::AdaptLinear::from_packed(
        candle_gen::quant::QLinear::from_qtensor_dequant(Arc::new(qtensor), dense_bias),
        in_dim,
        out_dim,
    ))
}

/// diffusers FLUX LayerNorm / RMS epsilon.
const LN_EPS: f64 = 1e-6;
const RMS_EPS: f64 = 1e-6;
/// Pooled CLIP width / T5 context width / packed latent channels (the DiT's three input widths).
const POOLED_DIM: usize = 768;
const CONTEXT_DIM: usize = 4096;

/// The DiT structural dims derived from the shared FLUX [`Config`]: hidden 3072, heads 24, head_dim 128,
/// mlp 12288 (`mlp_ratio` 4.0). Shared with the BFL model via the reused config, so this fork cannot
/// drift on the FLUX hyperparameters.
#[derive(Clone, Copy, Debug)]
struct Dims {
    hidden: usize,
    heads: usize,
    head_dim: usize,
    mlp: usize,
}

impl Dims {
    fn from_config(cfg: &Config) -> Self {
        let hidden = cfg.hidden_size;
        let heads = cfg.num_heads;
        Self {
            hidden,
            heads,
            head_dim: hidden / heads,
            mlp: (hidden as f64 * cfg.mlp_ratio) as usize,
        }
    }
}

/// A parameter-free `LayerNorm` (elementwise-affine = False) — the diffusers AdaLN base norm.
fn layer_norm_no_affine(
    dim: usize,
    dtype: DType,
    device: &candle_gen::candle_core::Device,
) -> Result<LayerNorm> {
    let ws = Tensor::ones(dim, dtype, device)?;
    Ok(LayerNorm::new_no_bias(ws, LN_EPS))
}

/// `silu(emb) @ linear` → split into `chunks` modulation params — the diffusers `AdaLayerNormZero`
/// (6-chunk, double block) / `AdaLayerNormZeroSingle` (3-chunk, single block). The base LayerNorm is
/// parameter-free; the shift/scale/gate come from `emb`.
struct AdaLayerNormZero {
    linear: QLinear,
    norm: LayerNorm,
}

impl AdaLayerNormZero {
    fn new_with_stream(
        chunks: usize,
        d: Dims,
        vb: &VarBuilder,
        prefix: &str,
        stream: Option<&StreamLoad<'_>>,
    ) -> Result<Self> {
        let linear = load_linear(
            d.hidden,
            chunks * d.hidden,
            vb,
            &format!("{prefix}.linear"),
            true,
            stream,
        )?;
        Ok(Self {
            linear,
            norm: layer_norm_no_affine(d.hidden, vb.dtype(), vb.device())?,
        })
    }

    /// 6-chunk (double block): `(normed, gate_msa, shift_mlp, scale_mlp, gate_mlp)`.
    fn forward_six(
        &self,
        hidden: &Tensor,
        emb: &Tensor,
    ) -> Result<(Tensor, Tensor, Tensor, Tensor, Tensor)> {
        let p = self.linear.forward(&emb.silu()?)?.chunk(6, D::Minus1)?;
        let normed = self
            .norm
            .forward(hidden)?
            .broadcast_mul(&(p[1].unsqueeze(1)? + 1.0)?)?
            .broadcast_add(&p[0].unsqueeze(1)?)?;
        Ok((
            normed,
            p[2].clone(),
            p[3].clone(),
            p[4].clone(),
            p[5].clone(),
        ))
    }

    /// 3-chunk (single block): `(normed, gate)`.
    fn forward_three(&self, hidden: &Tensor, emb: &Tensor) -> Result<(Tensor, Tensor)> {
        let p = self.linear.forward(&emb.silu()?)?.chunk(3, D::Minus1)?;
        let normed = self
            .norm
            .forward(hidden)?
            .broadcast_mul(&(p[1].unsqueeze(1)? + 1.0)?)?
            .broadcast_add(&p[0].unsqueeze(1)?)?;
        Ok((normed, p[2].clone()))
    }
}

/// The diffusers joint (double-block) attention: split `to_q`/`to_k`/`to_v` + `to_out.0` for the image
/// stream, `add_{q,k,v}_proj` + `to_add_out` for the text stream, RMS-norm on q/k, joint RoPE over
/// `cat(txt, img)`. Structurally identical to [`crate::control::JointBlock`]'s attention but built with
/// the packed-detecting [`QLinear`].
struct JointAttention {
    to_q: QLinear,
    to_k: QLinear,
    to_v: QLinear,
    to_out: QLinear,
    add_q: QLinear,
    add_k: QLinear,
    add_v: QLinear,
    to_add_out: QLinear,
    norm_q: RmsNorm,
    norm_k: RmsNorm,
    norm_added_q: RmsNorm,
    norm_added_k: RmsNorm,
    heads: usize,
    head_dim: usize,
}

impl JointAttention {
    fn new_with_stream(d: Dims, vb: &VarBuilder, stream: Option<&StreamLoad<'_>>) -> Result<Self> {
        let lin = |n: &str| load_linear(d.hidden, d.hidden, vb, n, true, stream);
        let rms =
            |n: &str| -> Result<RmsNorm> { Ok(RmsNorm::new(vb.get(d.head_dim, n)?, RMS_EPS)) };
        Ok(Self {
            to_q: lin("to_q")?,
            to_k: lin("to_k")?,
            to_v: lin("to_v")?,
            // `to_out.0`: the packed `.scales`/`.biases` siblings sit under the full `to_out.0` prefix,
            // so pass that whole base to `linear_detect` (never `.pp("0")` past the sibling).
            to_out: load_linear(d.hidden, d.hidden, vb, "to_out.0", true, stream)?,
            add_q: lin("add_q_proj")?,
            add_k: lin("add_k_proj")?,
            add_v: lin("add_v_proj")?,
            to_add_out: lin("to_add_out")?,
            norm_q: rms("norm_q.weight")?,
            norm_k: rms("norm_k.weight")?,
            norm_added_q: rms("norm_added_q.weight")?,
            norm_added_k: rms("norm_added_k.weight")?,
            heads: d.heads,
            head_dim: d.head_dim,
        })
    }

    fn qkv(
        &self,
        x: &Tensor,
        q: &QLinear,
        k: &QLinear,
        v: &QLinear,
        nq: &RmsNorm,
        nk: &RmsNorm,
    ) -> Result<(Tensor, Tensor, Tensor)> {
        let (b, s, _) = x.dims3()?;
        let (heads, head_dim) = (self.heads, self.head_dim);
        let to_heads =
            |t: Tensor| -> Result<Tensor> { t.reshape((b, s, heads, head_dim))?.transpose(1, 2) };
        let q = to_heads(q.forward(x)?)?.apply(nq)?;
        let k = to_heads(k.forward(x)?)?.apply(nk)?;
        let v = to_heads(v.forward(x)?)?;
        Ok((q, k, v))
    }

    fn forward(
        &self,
        hidden: &Tensor,
        encoder: &Tensor,
        pe: &Tensor,
        ip: Option<(&FluxIpInjector<'_>, usize)>,
        attention_plan: AttentionPlan<'_>,
    ) -> candle_gen::Result<(Tensor, Tensor, Option<Tensor>)> {
        let (q, k, v) = self.qkv(
            hidden,
            &self.to_q,
            &self.to_k,
            &self.to_v,
            &self.norm_q,
            &self.norm_k,
        )?;
        // XLabs consumes the image query after QK norm but before joint concat/RoPE. Preserve that
        // exact seam for packed diffusers-layout checkpoints; the IP token keys are position-less.
        let ip_residual = match ip {
            Some((injector, block_idx)) => injector.double_block_residual(block_idx, &q)?,
            None => None,
        };
        let (eq, ek, ev) = self.qkv(
            encoder,
            &self.add_q,
            &self.add_k,
            &self.add_v,
            &self.norm_added_q,
            &self.norm_added_k,
        )?;
        let q = Tensor::cat(&[&eq, &q], 2)?;
        let k = Tensor::cat(&[&ek, &k], 2)?;
        let v = Tensor::cat(&[&ev, &v], 2)?;
        let q = apply_rope(&q, pe)?.contiguous()?;
        let k = apply_rope(&k, pe)?.contiguous()?;
        let out = scaled_dot_product_attention_planned(&q, &k, &v, attention_plan)?;
        let out = out.transpose(1, 2)?.flatten_from(2)?;
        let txt_seq = encoder.dim(1)?;
        let img_seq = hidden.dim(1)?;
        let attn_txt = self.to_add_out.forward(&out.narrow(1, 0, txt_seq)?)?;
        let attn_img = self.to_out.forward(&out.narrow(1, txt_seq, img_seq)?)?;
        Ok((attn_img, attn_txt, ip_residual))
    }
}

/// diffusers `FeedForward` (`net.0.proj` → activation → `net.2`). The image stream uses exact GELU
/// (`gelu_erf`), the context stream the tanh approximation (`gelu`) — mirroring the mlx port + control.
struct FeedForward {
    lin1: QLinear,
    lin2: QLinear,
    approx: bool,
}

impl FeedForward {
    fn new_with_stream(
        approx: bool,
        d: Dims,
        vb: &VarBuilder,
        stream: Option<&StreamLoad<'_>>,
    ) -> Result<Self> {
        let lin1 = load_linear(d.hidden, d.mlp, vb, "net.0.proj", true, stream)?;
        let lin2 = load_linear(d.mlp, d.hidden, vb, "net.2", true, stream)?;
        Ok(Self { lin1, lin2, approx })
    }

    fn forward(&self, x: &Tensor) -> Result<Tensor> {
        let x = self.lin1.forward(x)?;
        let x = if self.approx {
            x.gelu()?
        } else {
            x.gelu_erf()?
        };
        self.lin2.forward(&x)
    }

    fn visit_adaptable_mut(
        &mut self,
        prefix: &str,
        visitor: &mut dyn FnMut(&str, &mut candle_gen::quant::AdaptLinear) -> Result<()>,
    ) -> Result<()> {
        visitor(&format!("{prefix}.net.0.proj"), &mut self.lin1)?;
        visitor(&format!("{prefix}.net.2"), &mut self.lin2)
    }
}

/// One diffusers FLUX joint (double-stream) block (`transformer_blocks.{i}`).
struct JointBlock {
    norm1: AdaLayerNormZero,
    norm1_context: AdaLayerNormZero,
    attn: JointAttention,
    ff: FeedForward,
    ff_context: FeedForward,
    norm2: LayerNorm,
}

impl JointBlock {
    fn new(d: Dims, vb: &VarBuilder) -> Result<Self> {
        Self::new_with_sidecars(d, vb, None, "")
    }

    fn new_with_sidecars(
        d: Dims,
        vb: &VarBuilder,
        sidecars: Option<&PackedWeightSidecars>,
        prefix: &str,
    ) -> Result<Self> {
        let stream = sidecars.map(|sidecars| StreamLoad {
            sidecars,
            prefix: prefix.to_owned(),
        });
        let stream = stream.as_ref();
        Ok(Self {
            norm1: AdaLayerNormZero::new_with_stream(6, d, vb, "norm1", stream)?,
            norm1_context: AdaLayerNormZero::new_with_stream(6, d, vb, "norm1_context", stream)?,
            attn: JointAttention::new_with_stream(
                d,
                &vb.pp("attn"),
                stream
                    .map(|s| StreamLoad {
                        sidecars: s.sidecars,
                        prefix: format!("{}.attn", s.prefix),
                    })
                    .as_ref(),
            )?,
            ff: FeedForward::new_with_stream(
                false,
                d,
                &vb.pp("ff"),
                stream
                    .map(|s| StreamLoad {
                        sidecars: s.sidecars,
                        prefix: format!("{}.ff", s.prefix),
                    })
                    .as_ref(),
            )?,
            ff_context: FeedForward::new_with_stream(
                true,
                d,
                &vb.pp("ff_context"),
                stream
                    .map(|s| StreamLoad {
                        sidecars: s.sidecars,
                        prefix: format!("{}.ff_context", s.prefix),
                    })
                    .as_ref(),
            )?,
            norm2: layer_norm_no_affine(d.hidden, vb.dtype(), vb.device())?,
        })
    }

    /// `(hidden, encoder)` → `(hidden', encoder')`.
    fn forward(
        &self,
        hidden: &Tensor,
        encoder: &Tensor,
        emb: &Tensor,
        pe: &Tensor,
        ip: Option<(&FluxIpInjector<'_>, usize)>,
        attention_plan: AttentionPlan<'_>,
    ) -> candle_gen::Result<(Tensor, Tensor)> {
        let (norm_hidden, gate_msa, shift_mlp, scale_mlp, gate_mlp) =
            self.norm1.forward_six(hidden, emb)?;
        let (norm_encoder, c_gate_msa, c_shift_mlp, c_scale_mlp, c_gate_mlp) =
            self.norm1_context.forward_six(encoder, emb)?;
        let (attn_img, attn_txt, ip_residual) =
            self.attn
                .forward(&norm_hidden, &norm_encoder, pe, ip, attention_plan)?;
        let mut hidden = apply_norm_ff(
            hidden,
            &attn_img,
            &gate_msa,
            &shift_mlp,
            &scale_mlp,
            &gate_mlp,
            &self.ff,
            &self.norm2,
        )?;
        // XLabs adds the decoupled cross-attention residual raw after the gated FF, matching the
        // native BFL-layout seam and diffusers' FluxIPAdapterAttnProcessor.
        if let Some(residual) = ip_residual {
            hidden = (&hidden + residual.to_dtype(hidden.dtype())?)?;
        }
        let encoder = apply_norm_ff(
            encoder,
            &attn_txt,
            &c_gate_msa,
            &c_shift_mlp,
            &c_scale_mlp,
            &c_gate_mlp,
            &self.ff_context,
            &self.norm2,
        )?;
        Ok((hidden, encoder))
    }

    fn visit_adaptable_mut(
        &mut self,
        prefix: &str,
        visitor: &mut dyn FnMut(&str, &mut candle_gen::quant::AdaptLinear) -> Result<()>,
    ) -> Result<()> {
        visitor(&format!("{prefix}.norm1.linear"), &mut self.norm1.linear)?;
        visitor(
            &format!("{prefix}.norm1_context.linear"),
            &mut self.norm1_context.linear,
        )?;
        for (name, linear) in [
            ("to_q", &mut self.attn.to_q),
            ("to_k", &mut self.attn.to_k),
            ("to_v", &mut self.attn.to_v),
            ("to_out.0", &mut self.attn.to_out),
            ("add_q_proj", &mut self.attn.add_q),
            ("add_k_proj", &mut self.attn.add_k),
            ("add_v_proj", &mut self.attn.add_v),
            ("to_add_out", &mut self.attn.to_add_out),
        ] {
            visitor(&format!("{prefix}.attn.{name}"), linear)?;
        }
        self.ff
            .visit_adaptable_mut(&format!("{prefix}.ff"), visitor)?;
        self.ff_context
            .visit_adaptable_mut(&format!("{prefix}.ff_context"), visitor)
    }
}

/// The AdaLN-Zero post-attention residual + gated FF (shared by the image/text streams):
/// `h = h + gate_msa·attn; h = h + gate_mlp·ff(norm(h)·(1+scale_mlp)+shift_mlp)`.
#[allow(clippy::too_many_arguments)]
fn apply_norm_ff(
    hidden: &Tensor,
    attn: &Tensor,
    gate_msa: &Tensor,
    shift_mlp: &Tensor,
    scale_mlp: &Tensor,
    gate_mlp: &Tensor,
    ff: &FeedForward,
    norm: &LayerNorm,
) -> Result<Tensor> {
    let hidden = (hidden + attn.broadcast_mul(&gate_msa.unsqueeze(1)?)?)?;
    let normed = norm
        .forward(&hidden)?
        .broadcast_mul(&(scale_mlp.unsqueeze(1)? + 1.0)?)?
        .broadcast_add(&shift_mlp.unsqueeze(1)?)?;
    let ff_out = ff.forward(&normed)?;
    hidden.broadcast_add(&ff_out.broadcast_mul(&gate_mlp.unsqueeze(1)?)?)
}

/// One diffusers FLUX single-stream block (`single_transformer_blocks.{i}`): AdaLN-Zero-Single
/// modulation, split `attn.to_q`/`to_k`/`to_v` (+ RMS q/k norm), a parallel `proj_mlp` (hidden →
/// 4·hidden), and a fused `proj_out` (hidden + 4·hidden → hidden) over `cat(attn, gelu(mlp))`. The
/// single blocks operate on the concatenated `cat(txt, img)` stream (like the BFL single blocks).
struct SingleBlock {
    norm: AdaLayerNormZero,
    to_q: QLinear,
    to_k: QLinear,
    to_v: QLinear,
    norm_q: RmsNorm,
    norm_k: RmsNorm,
    proj_mlp: QLinear,
    proj_out: QLinear,
    heads: usize,
    head_dim: usize,
}

impl SingleBlock {
    fn new(d: Dims, vb: &VarBuilder) -> Result<Self> {
        Self::new_with_sidecars(d, vb, None, "")
    }

    fn new_with_sidecars(
        d: Dims,
        vb: &VarBuilder,
        sidecars: Option<&PackedWeightSidecars>,
        prefix: &str,
    ) -> Result<Self> {
        let attn = vb.pp("attn");
        let root = sidecars.map(|sidecars| StreamLoad {
            sidecars,
            prefix: prefix.to_owned(),
        });
        let attn_stream = root.as_ref().map(|stream| StreamLoad {
            sidecars: stream.sidecars,
            prefix: format!("{}.attn", stream.prefix),
        });
        Ok(Self {
            // `norm` here is AdaLayerNormZeroSingle: `norm.linear` emits 3·hidden.
            norm: AdaLayerNormZero::new_with_stream(3, d, vb, "norm", root.as_ref())?,
            to_q: load_linear(
                d.hidden,
                d.hidden,
                &attn,
                "to_q",
                true,
                attn_stream.as_ref(),
            )?,
            to_k: load_linear(
                d.hidden,
                d.hidden,
                &attn,
                "to_k",
                true,
                attn_stream.as_ref(),
            )?,
            to_v: load_linear(
                d.hidden,
                d.hidden,
                &attn,
                "to_v",
                true,
                attn_stream.as_ref(),
            )?,
            norm_q: RmsNorm::new(attn.get(d.head_dim, "norm_q.weight")?, RMS_EPS),
            norm_k: RmsNorm::new(attn.get(d.head_dim, "norm_k.weight")?, RMS_EPS),
            proj_mlp: load_linear(d.hidden, d.mlp, vb, "proj_mlp", true, root.as_ref())?,
            proj_out: load_linear(
                d.hidden + d.mlp,
                d.hidden,
                vb,
                "proj_out",
                true,
                root.as_ref(),
            )?,
            heads: d.heads,
            head_dim: d.head_dim,
        })
    }

    fn forward(
        &self,
        hidden: &Tensor,
        emb: &Tensor,
        pe: &Tensor,
        attention_plan: AttentionPlan<'_>,
    ) -> candle_gen::Result<Tensor> {
        let (norm_hidden, gate) = self.norm.forward_three(hidden, emb)?;
        let (b, s, _) = norm_hidden.dims3()?;
        let (heads, head_dim) = (self.heads, self.head_dim);
        let to_heads =
            |t: Tensor| -> Result<Tensor> { t.reshape((b, s, heads, head_dim))?.transpose(1, 2) };
        let q = to_heads(self.to_q.forward(&norm_hidden)?)?.apply(&self.norm_q)?;
        let k = to_heads(self.to_k.forward(&norm_hidden)?)?.apply(&self.norm_k)?;
        let v = to_heads(self.to_v.forward(&norm_hidden)?)?;
        let q = apply_rope(&q, pe)?.contiguous()?;
        let k = apply_rope(&k, pe)?.contiguous()?;
        let attn = scaled_dot_product_attention_planned(&q, &k, &v, attention_plan)?;
        let attn = attn.transpose(1, 2)?.flatten_from(2)?; // [b, s, hidden]
        let mlp = self.proj_mlp.forward(&norm_hidden)?.gelu()?;
        let out = self
            .proj_out
            .forward(&Tensor::cat(&[&attn, &mlp], D::Minus1)?)?;
        // Residual with the single-block gate.
        Ok(hidden.broadcast_add(&out.broadcast_mul(&gate.unsqueeze(1)?)?)?)
    }

    fn visit_adaptable_mut(
        &mut self,
        prefix: &str,
        visitor: &mut dyn FnMut(&str, &mut candle_gen::quant::AdaptLinear) -> Result<()>,
    ) -> Result<()> {
        visitor(&format!("{prefix}.norm.linear"), &mut self.norm.linear)?;
        visitor(&format!("{prefix}.attn.to_q"), &mut self.to_q)?;
        visitor(&format!("{prefix}.attn.to_k"), &mut self.to_k)?;
        visitor(&format!("{prefix}.attn.to_v"), &mut self.to_v)?;
        visitor(&format!("{prefix}.proj_mlp"), &mut self.proj_mlp)?;
        visitor(&format!("{prefix}.proj_out"), &mut self.proj_out)
    }
}

/// `silu → linear_1 → silu → linear_2` MLP (diffusers `TimestepEmbedding` / text projection).
struct MlpEmbedder {
    lin1: QLinear,
    lin2: QLinear,
}

impl MlpEmbedder {
    fn new(in_dim: usize, hidden: usize, vb: &VarBuilder) -> Result<Self> {
        Ok(Self {
            lin1: QLinear::linear_detect(in_dim, hidden, vb, "linear_1", true)?,
            lin2: QLinear::linear_detect(hidden, hidden, vb, "linear_2", true)?,
        })
    }

    fn forward(&self, x: &Tensor) -> Result<Tensor> {
        self.lin2.forward(&self.lin1.forward(x)?.silu()?)
    }

    fn visit_adaptable_mut(
        &mut self,
        prefix: &str,
        visitor: &mut dyn FnMut(&str, &mut candle_gen::quant::AdaptLinear) -> Result<()>,
    ) -> Result<()> {
        visitor(&format!("{prefix}.linear_1"), &mut self.lin1)?;
        visitor(&format!("{prefix}.linear_2"), &mut self.lin2)
    }
}

/// diffusers `CombinedTimestep(Guidance)TextEmbeddings`: sinusoidal time (+ optional guidance)
/// projection summed with the pooled-text projection. `time_text_embed.{timestep,guidance,text}_embedder`.
struct TimeTextEmbed {
    timestep: MlpEmbedder,
    text: MlpEmbedder,
    guidance: Option<MlpEmbedder>,
}

impl TimeTextEmbed {
    fn new(
        supports_guidance: bool,
        hidden: usize,
        pooled_dim: usize,
        vb: &VarBuilder,
    ) -> Result<Self> {
        Ok(Self {
            timestep: MlpEmbedder::new(256, hidden, &vb.pp("timestep_embedder"))?,
            text: MlpEmbedder::new(pooled_dim, hidden, &vb.pp("text_embedder"))?,
            guidance: if supports_guidance {
                Some(MlpEmbedder::new(256, hidden, &vb.pp("guidance_embedder"))?)
            } else {
                None
            },
        })
    }

    fn forward(
        &self,
        timestep: &Tensor,
        guidance: Option<&Tensor>,
        pooled: &Tensor,
    ) -> Result<Tensor> {
        let dtype = pooled.dtype();
        let mut out = self
            .timestep
            .forward(&timestep_embedding(timestep, 256, dtype)?)?;
        if let (Some(g_in), Some(g)) = (self.guidance.as_ref(), guidance) {
            out = (out + g_in.forward(&timestep_embedding(g, 256, dtype)?)?)?;
        }
        out = (out + self.text.forward(pooled)?)?;
        Ok(out)
    }

    fn visit_adaptable_mut(
        &mut self,
        visitor: &mut dyn FnMut(&str, &mut candle_gen::quant::AdaptLinear) -> Result<()>,
    ) -> Result<()> {
        self.timestep
            .visit_adaptable_mut("time_text_embed.timestep_embedder", visitor)?;
        self.text
            .visit_adaptable_mut("time_text_embed.text_embedder", visitor)?;
        if let Some(guidance) = &mut self.guidance {
            guidance.visit_adaptable_mut("time_text_embed.guidance_embedder", visitor)?;
        }
        Ok(())
    }
}

/// diffusers `AdaLayerNormContinuous` output head (`norm_out`): `silu(emb) @ linear` → `(scale, shift)`,
/// `norm(hidden)·(1+scale)+shift`, then the `proj_out` to the packed latent channels.
struct OutputHead {
    norm_linear: QLinear,
    norm: LayerNorm,
    proj_out: QLinear,
}

impl OutputHead {
    fn new(d: Dims, out_channels: usize, vb: &VarBuilder) -> Result<Self> {
        Ok(Self {
            norm_linear: QLinear::linear_detect(
                d.hidden,
                2 * d.hidden,
                vb,
                "norm_out.linear",
                true,
            )?,
            norm: layer_norm_no_affine(d.hidden, vb.dtype(), vb.device())?,
            proj_out: QLinear::linear_detect(d.hidden, out_channels, vb, "proj_out", true)?,
        })
    }

    fn forward(&self, hidden: &Tensor, emb: &Tensor) -> Result<Tensor> {
        // diffusers `AdaLayerNormContinuous` chunks the projection as (scale, shift) — **scale FIRST**
        // (`scale, shift = emb.chunk(2)`), unlike the 6-chunk `AdaLayerNormZero` (shift-first) the double/
        // single blocks use. So `p[0]` is the scale and `p[1]` is the shift. Reading them shift-first
        // swaps the multiplicative and additive modulation at the final layer — leaving composition intact
        // (the correct blocks) but corrupting every token's output latent into a fixed per-patch magenta
        // grid (sc-10914). This matches BFL's shift-first `final_layer.adaLN_modulation.1` only because the
        // diffusers→BFL conversion swaps the two halves (verified: the real `norm_out.linear` weight halves
        // are the byte-swapped BFL `adaLN_modulation.1` halves).
        let p = self
            .norm_linear
            .forward(&emb.silu()?)?
            .chunk(2, D::Minus1)?;
        let normed = self
            .norm
            .forward(hidden)?
            .broadcast_mul(&(p[0].unsqueeze(1)? + 1.0)?)?
            .broadcast_add(&p[1].unsqueeze(1)?)?;
        self.proj_out.forward(&normed)
    }
}

/// The vendored diffusers FLUX.1 MMDiT — 19 double `transformer_blocks` + 38 single
/// `single_transformer_blocks`, packed-detecting every `Linear` through [`QLinear`]. Consumes the same
/// packed VAE latents / T5 context / CLIP pooled vector as the stock BFL model and emits the same
/// `[B, img_seq, 64]` velocity.
pub struct PackedFluxDit {
    x_embedder: QLinear,
    context_embedder: QLinear,
    time_text_embed: TimeTextEmbed,
    blocks: PackedFluxBlocks,
    output: OutputHead,
    pe_embedder: EmbedNd,
    device: Device,
}

enum PackedFluxBlocks {
    Resident {
        double: Vec<JointBlock>,
        single: Vec<SingleBlock>,
    },
    Streamed {
        weights: VarBuilder<'static>,
        config: Config,
        num_double: usize,
        num_single: usize,
        double_sidecars: Option<Arc<PackedWeightSidecars>>,
        single_sidecars: Option<Arc<PackedWeightSidecars>>,
    },
}

impl PackedFluxDit {
    fn num_double_blocks(&self) -> usize {
        match &self.blocks {
            PackedFluxBlocks::Resident { double, .. } => double.len(),
            PackedFluxBlocks::Streamed { num_double, .. } => *num_double,
        }
    }

    pub fn visit_adaptable_mut(
        &mut self,
        visitor: &mut dyn FnMut(&str, &mut candle_gen::quant::AdaptLinear) -> Result<()>,
    ) -> Result<()> {
        visitor("x_embedder", &mut self.x_embedder)?;
        visitor("context_embedder", &mut self.context_embedder)?;
        self.time_text_embed.visit_adaptable_mut(visitor)?;
        match &mut self.blocks {
            PackedFluxBlocks::Resident { double, single } => {
                for (index, block) in double.iter_mut().enumerate() {
                    block.visit_adaptable_mut(&format!("transformer_blocks.{index}"), visitor)?;
                }
                for (index, block) in single.iter_mut().enumerate() {
                    block.visit_adaptable_mut(
                        &format!("single_transformer_blocks.{index}"),
                        visitor,
                    )?;
                }
            }
            PackedFluxBlocks::Streamed { .. } => {
                candle_gen::candle_core::bail!(
                    "FLUX adapters require resident transformer blocks; disable block streaming"
                )
            }
        }
        visitor("norm_out.linear", &mut self.output.norm_linear)?;
        visitor("proj_out", &mut self.output.proj_out)
    }

    /// Load the diffusers FLUX DiT from `vb` (rooted at the `transformer/` component). `cfg` is the
    /// shared FLUX [`Config`] (`Config::schnell()` / `Config::dev()`); `num_double`/`num_single` come
    /// from the component `config.json` (`num_layers` / `num_single_layers` = 19 / 38 for FLUX.1).
    pub fn new(cfg: &Config, num_double: usize, num_single: usize, vb: VarBuilder) -> Result<Self> {
        let d = Dims::from_config(cfg);
        let device = vb.device().clone();
        let x_embedder =
            QLinear::linear_detect(cfg.in_channels, d.hidden, &vb, "x_embedder", true)?;
        let context_embedder =
            QLinear::linear_detect(CONTEXT_DIM, d.hidden, &vb, "context_embedder", true)?;
        let time_text_embed = TimeTextEmbed::new(
            cfg.guidance_embed,
            d.hidden,
            POOLED_DIM,
            &vb.pp("time_text_embed"),
        )?;
        let mut double = Vec::with_capacity(num_double);
        let vb_d = vb.pp("transformer_blocks");
        for i in 0..num_double {
            double.push(JointBlock::new(d, &vb_d.pp(i))?);
        }
        let mut single = Vec::with_capacity(num_single);
        let vb_s = vb.pp("single_transformer_blocks");
        for i in 0..num_single {
            single.push(SingleBlock::new(d, &vb_s.pp(i))?);
        }
        Ok(Self {
            x_embedder,
            context_embedder,
            time_text_embed,
            blocks: PackedFluxBlocks::Resident { double, single },
            output: OutputHead::new(d, cfg.in_channels, &vb)?,
            pe_embedder: EmbedNd::new(d.head_dim, cfg.theta, cfg.axes_dim.clone()),
            device,
        })
    }

    pub fn new_block_streamed(
        cfg: &Config,
        num_double: usize,
        num_single: usize,
        vb: VarBuilder<'static>,
    ) -> Result<Self> {
        Self::new_streamed_impl(cfg, num_double, num_single, vb, None, None)
    }

    pub fn new_block_streamed_with_sidecars(
        cfg: &Config,
        num_double: usize,
        num_single: usize,
        vb: VarBuilder<'static>,
        double_sidecars: Arc<PackedWeightSidecars>,
        single_sidecars: Arc<PackedWeightSidecars>,
    ) -> Result<Self> {
        Self::new_streamed_impl(
            cfg,
            num_double,
            num_single,
            vb,
            Some(double_sidecars),
            Some(single_sidecars),
        )
    }

    fn new_streamed_impl(
        cfg: &Config,
        num_double: usize,
        num_single: usize,
        vb: VarBuilder<'static>,
        double_sidecars: Option<Arc<PackedWeightSidecars>>,
        single_sidecars: Option<Arc<PackedWeightSidecars>>,
    ) -> Result<Self> {
        let d = Dims::from_config(cfg);
        let device = vb.device().clone();
        let x_embedder =
            QLinear::linear_detect(cfg.in_channels, d.hidden, &vb, "x_embedder", true)?;
        let context_embedder =
            QLinear::linear_detect(CONTEXT_DIM, d.hidden, &vb, "context_embedder", true)?;
        let time_text_embed = TimeTextEmbed::new(
            cfg.guidance_embed,
            d.hidden,
            POOLED_DIM,
            &vb.pp("time_text_embed"),
        )?;
        let blocks = PackedFluxBlocks::Streamed {
            weights: vb.clone(),
            config: cfg.clone(),
            num_double,
            num_single,
            double_sidecars,
            single_sidecars,
        };
        let output = OutputHead::new(d, cfg.in_channels, &vb)?;
        let pe_embedder = EmbedNd::new(d.head_dim, cfg.theta, cfg.axes_dim.clone());
        Ok(Self {
            x_embedder,
            context_embedder,
            time_text_embed,
            blocks,
            output,
            pe_embedder,
            device,
        })
    }

    /// FLUX velocity forward. `img`: packed latents `[B, img_seq, 64]`. `txt`: T5 context
    /// `[B, txt_seq, 4096]`. `pooled`: CLIP pooled `[B, 768]`. `timesteps`: `[B]` raw σ (the sinusoid
    /// embedder scales ×1000). `guidance`: `[B]` embedded guidance (dev only). `img_ids`/`txt_ids`:
    /// `[B, seq, 3]` FLUX position ids. Returns `[B, img_seq, 64]`.
    ///
    /// A thin wrapper over [`forward_injected`](Self::forward_injected) with `injector = None`, so it is
    /// byte-identical to the pre-seam body (the txt2img packed path, [`crate::pipeline`]).
    #[allow(clippy::too_many_arguments)]
    #[allow(dead_code)]
    pub fn forward(
        &self,
        img: &Tensor,
        img_ids: &Tensor,
        txt: &Tensor,
        txt_ids: &Tensor,
        timesteps: &Tensor,
        pooled: &Tensor,
        guidance: Option<&Tensor>,
    ) -> Result<Tensor> {
        self.forward_injected(
            img, img_ids, txt, txt_ids, timesteps, pooled, guidance, None,
        )
    }

    /// FLUX velocity forward plus the generic **post-block** image-stream residual injector — the
    /// diffusers-layout twin of [`crate::ip_dit::IpFlux::forward_injected`], so the PuLID-FLUX id
    /// cross-attn (`candle-gen-pulid`, sc-5492) drives the SAME [`DitImageInjector`] seam on a packed
    /// (or dense diffusers) tier that it drives on the BFL-layout `IpFlux`. The injector is consulted
    /// after every double block (on the image stream `hidden`) and after the single blocks it opts into
    /// (on the image-token tail of the joint `cat(encoder, hidden)` stream), matching the reference
    /// PuLID injection points. `injector = None` is byte-identical to [`forward`](Self::forward) — the
    /// no-id ablation (`id_weight = 0` ⇒ every residual `None`) carries zero overhead.
    ///
    /// The injector block indices are layout-agnostic (the diffusers `transformer_blocks` /
    /// `single_transformer_blocks` are the SAME 19 double / 38 single blocks as the BFL
    /// `double_blocks` / `single_blocks`), so a [`crate::ip_dit::DitImageInjector`] built for the BFL
    /// model injects at the identical points here.
    #[allow(clippy::too_many_arguments)]
    pub fn forward_injected(
        &self,
        img: &Tensor,
        img_ids: &Tensor,
        txt: &Tensor,
        txt_ids: &Tensor,
        timesteps: &Tensor,
        pooled: &Tensor,
        guidance: Option<&Tensor>,
        injector: Option<&dyn DitImageInjector>,
    ) -> Result<Tensor> {
        self.forward_core(
            img,
            img_ids,
            txt,
            txt_ids,
            timesteps,
            pooled,
            guidance,
            None,
            injector,
            None,
            AttentionPlan::budgeted(AttentionBudget::from_score_elements(
                candle_gen::ATTN_SCORES_BUDGET as u64,
                false,
            )),
            usize::MAX,
            &candle_gen::gen_core::CancelFlag::default(),
        )
        .map_err(|error| match error {
            candle_gen::CandleError::Candle(error) => error,
            other => candle_gen::candle_core::Error::Msg(other.to_string()),
        })
    }

    #[allow(clippy::too_many_arguments)]
    pub(crate) fn forward_injected_with_memory(
        &self,
        img: &Tensor,
        img_ids: &Tensor,
        txt: &Tensor,
        txt_ids: &Tensor,
        timesteps: &Tensor,
        pooled: &Tensor,
        guidance: Option<&Tensor>,
        injector: Option<&dyn DitImageInjector>,
        attention_plan: AttentionPlan<'_>,
        transformer_window: usize,
        cancel: &candle_gen::gen_core::CancelFlag,
    ) -> candle_gen::Result<Tensor> {
        self.forward_core(
            img,
            img_ids,
            txt,
            txt_ids,
            timesteps,
            pooled,
            guidance,
            None,
            injector,
            None,
            attention_plan,
            transformer_window,
            cancel,
        )
    }

    /// Packed diffusers-layout XLabs IP-Adapter forward. Unlike the generic post-block injector used
    /// by PuLID, XLabs consumes each double block's post-QKNorm, pre-RoPE image query and adds its
    /// residual raw after that block's gated feed-forward path.
    #[allow(clippy::too_many_arguments)]
    pub(crate) fn forward_ip_with_memory(
        &self,
        img: &Tensor,
        img_ids: &Tensor,
        txt: &Tensor,
        txt_ids: &Tensor,
        timesteps: &Tensor,
        pooled: &Tensor,
        guidance: Option<&Tensor>,
        ip: &FluxIpInjector<'_>,
        attention_plan: AttentionPlan<'_>,
        transformer_window: usize,
        cancel: &candle_gen::gen_core::CancelFlag,
    ) -> candle_gen::Result<Tensor> {
        self.forward_core(
            img,
            img_ids,
            txt,
            txt_ids,
            timesteps,
            pooled,
            guidance,
            Some(ip),
            None,
            None,
            attention_plan,
            transformer_window,
            cancel,
        )
    }

    /// Packed diffusers-layout control forward. The optional generic identity injector is applied
    /// first, then the indexed control residual, matching the native BFL-layout composition order.
    #[allow(clippy::too_many_arguments)]
    pub(crate) fn forward_control_with_memory(
        &self,
        img: &Tensor,
        img_ids: &Tensor,
        txt: &Tensor,
        txt_ids: &Tensor,
        timesteps: &Tensor,
        pooled: &Tensor,
        guidance: Option<&Tensor>,
        injector: Option<&dyn DitImageInjector>,
        control: Option<(&[Tensor], f64)>,
        attention_plan: AttentionPlan<'_>,
        transformer_window: usize,
        cancel: &candle_gen::gen_core::CancelFlag,
    ) -> candle_gen::Result<Tensor> {
        self.forward_core(
            img,
            img_ids,
            txt,
            txt_ids,
            timesteps,
            pooled,
            guidance,
            None,
            injector,
            control,
            attention_plan,
            transformer_window,
            cancel,
        )
    }

    #[allow(clippy::too_many_arguments)]
    pub(crate) fn forward_with_memory(
        &self,
        img: &Tensor,
        img_ids: &Tensor,
        txt: &Tensor,
        txt_ids: &Tensor,
        timesteps: &Tensor,
        pooled: &Tensor,
        guidance: Option<&Tensor>,
        attention_plan: AttentionPlan<'_>,
        transformer_window: usize,
        cancel: &candle_gen::gen_core::CancelFlag,
    ) -> candle_gen::Result<Tensor> {
        self.forward_core(
            img,
            img_ids,
            txt,
            txt_ids,
            timesteps,
            pooled,
            guidance,
            None,
            None,
            None,
            attention_plan,
            transformer_window,
            cancel,
        )
    }

    #[allow(clippy::too_many_arguments)]
    fn forward_core(
        &self,
        img: &Tensor,
        img_ids: &Tensor,
        txt: &Tensor,
        txt_ids: &Tensor,
        timesteps: &Tensor,
        pooled: &Tensor,
        guidance: Option<&Tensor>,
        ip: Option<&FluxIpInjector<'_>>,
        injector: Option<&dyn DitImageInjector>,
        control: Option<(&[Tensor], f64)>,
        attention_plan: AttentionPlan<'_>,
        transformer_window: usize,
        cancel: &candle_gen::gen_core::CancelFlag,
    ) -> candle_gen::Result<Tensor> {
        let mut hidden = self.x_embedder.forward(img)?;
        let mut encoder = self.context_embedder.forward(txt)?;
        let emb = self.time_text_embed.forward(timesteps, guidance, pooled)?;
        let pe = Tensor::cat(&[txt_ids, img_ids], 1)?.apply(&self.pe_embedder)?;
        let control = control.filter(|(residuals, _)| !residuals.is_empty());
        let scaled_control = match control {
            Some((residuals, scale)) => {
                let interval = control_residual_interval(self.num_double_blocks(), residuals.len());
                let dtype = hidden.dtype();
                let residuals = residuals
                    .iter()
                    .map(|residual| residual.to_dtype(dtype)? * scale)
                    .collect::<Result<Vec<_>>>()?;
                Some((residuals, interval))
            }
            None => None,
        };

        if let PackedFluxBlocks::Streamed {
            weights,
            config,
            num_double,
            num_single,
            double_sidecars,
            single_sidecars,
        } = &self.blocks
        {
            let d = Dims::from_config(config);
            let window = transformer_window.max(1);
            let double_plan = candle_gen::block_window::BlockPlan::new(*num_double, window)?;
            let (stream_hidden, stream_encoder) = candle_gen::block_window::run_windowed(
                &self.device,
                &double_plan,
                cancel,
                (hidden, encoder),
                || Ok(weights.clone()),
                |(mut hidden, mut encoder), view, range| {
                    let blocks = range
                        .map(|index| {
                            JointBlock::new_with_sidecars(
                                d,
                                &view.pp("transformer_blocks").pp(index),
                                double_sidecars.as_deref(),
                                &format!("transformer_blocks.{index}"),
                            )
                            .map(|block| (index, block))
                            .map_err(candle_gen::CandleError::from)
                        })
                        .collect::<candle_gen::Result<Vec<_>>>()?;
                    for (index, block) in &blocks {
                        candle_gen::check_cancel(cancel)?;
                        (hidden, encoder) = block.forward(
                            &hidden,
                            &encoder,
                            &emb,
                            &pe,
                            ip.map(|injector| (injector, *index)),
                            attention_plan,
                        )?;
                        if let Some(inj) = injector {
                            if let Some(r) = inj.after_double(*index, &hidden)? {
                                hidden = (&hidden + r.to_dtype(hidden.dtype())?)?;
                            }
                        }
                        if let Some((residuals, interval)) = &scaled_control {
                            let control_idx = (*index / interval).min(residuals.len() - 1);
                            hidden = (&hidden + &residuals[control_idx])?;
                        }
                    }
                    Ok((hidden, encoder))
                },
            )?;
            let txt_seq = stream_encoder.dim(1)?;
            let img_seq = stream_hidden.dim(1)?;
            let joint = Tensor::cat(&[&stream_encoder, &stream_hidden], 1)?;
            let single_plan = candle_gen::block_window::BlockPlan::new(*num_single, window)?;
            let joint = candle_gen::block_window::run_windowed(
                &self.device,
                &single_plan,
                cancel,
                joint,
                || Ok(weights.clone()),
                |mut joint, view, range| {
                    let blocks = range
                        .map(|index| {
                            SingleBlock::new_with_sidecars(
                                d,
                                &view.pp("single_transformer_blocks").pp(index),
                                single_sidecars.as_deref(),
                                &format!("single_transformer_blocks.{index}"),
                            )
                            .map(|block| (index, block))
                            .map_err(candle_gen::CandleError::from)
                        })
                        .collect::<candle_gen::Result<Vec<_>>>()?;
                    for (index, block) in &blocks {
                        candle_gen::check_cancel(cancel)?;
                        joint = block.forward(&joint, &emb, &pe, attention_plan)?;
                        if let Some(inj) = injector {
                            if inj.injects_after_single(*index) {
                                let seq = joint.dim(1)?;
                                let img_part = joint.narrow(1, txt_seq, seq - txt_seq)?;
                                if let Some(r) = inj.after_single(*index, &img_part)? {
                                    let added = (img_part + r.to_dtype(joint.dtype())?)?;
                                    let txt_part = joint.narrow(1, 0, txt_seq)?;
                                    joint = Tensor::cat(&[&txt_part, &added], 1)?;
                                }
                            }
                        }
                    }
                    Ok(joint)
                },
            )?;
            let hidden = joint.narrow(1, txt_seq, img_seq)?;
            return Ok(self.output.forward(&hidden, &emb)?);
        }
        let PackedFluxBlocks::Resident { double, single } = &self.blocks else {
            unreachable!("streamed FLUX packed blocks returned above")
        };

        for (i, block) in double.iter().enumerate() {
            candle_gen::check_cancel(cancel)?;
            let (h, e) = block.forward(
                &hidden,
                &encoder,
                &emb,
                &pe,
                ip.map(|injector| (injector, i)),
                attention_plan,
            )?;
            hidden = h;
            encoder = e;
            // Post-block identity injector (PuLID): add its residual to the image stream. Inert when
            // `injector = None` or the block index yields no residual.
            if let Some(inj) = injector {
                if let Some(r) = inj.after_double(i, &hidden)? {
                    hidden = (&hidden + r.to_dtype(hidden.dtype())?)?;
                }
            }
            if let Some((residuals, interval)) = &scaled_control {
                let control_idx = (i / interval).min(residuals.len() - 1);
                hidden = (&hidden + &residuals[control_idx])?;
            }
        }

        // The single blocks run on the concatenated `cat(txt, img)` stream (`txt_seq` unchanged by them,
        // so the image tail always starts at `txt_seq`). The injector's `after_single` residual is added
        // to the image-token tail (and written back) after the single blocks it opts into.
        let txt_seq = encoder.dim(1)?;
        let img_seq = hidden.dim(1)?;
        let mut joint = Tensor::cat(&[&encoder, &hidden], 1)?;
        for (i, block) in single.iter().enumerate() {
            candle_gen::check_cancel(cancel)?;
            joint = block.forward(&joint, &emb, &pe, attention_plan)?;
            if let Some(inj) = injector {
                if inj.injects_after_single(i) {
                    let seq = joint.dim(1)?;
                    let img_part = joint.narrow(1, txt_seq, seq - txt_seq)?;
                    if let Some(r) = inj.after_single(i, &img_part)? {
                        let added = (img_part + r.to_dtype(joint.dtype())?)?;
                        let txt_part = joint.narrow(1, 0, txt_seq)?;
                        joint = Tensor::cat(&[&txt_part, &added], 1)?;
                    }
                }
            }
        }
        let hidden = joint.narrow(1, txt_seq, img_seq)?;

        Ok(self.output.forward(&hidden, &emb)?)
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use candle_gen::candle_core::Device;
    use candle_gen::candle_nn::VarMap;
    use std::cell::RefCell;

    /// A tiny FLUX [`Config`] for the GPU-free DiT smoke test: inner 16 (heads 2 · head_dim 8),
    /// `axes_dim` summing to 8, real input widths (in 64 / context 4096 / pooled 768).
    fn tiny_cfg(guidance: bool) -> Config {
        Config {
            in_channels: 64,
            vec_in_dim: 768,
            context_in_dim: 4096,
            hidden_size: 16,
            mlp_ratio: 4.0,
            num_heads: 2,
            depth: 0,
            depth_single_blocks: 0,
            axes_dim: vec![2, 2, 4],
            theta: 10_000,
            qkv_bias: true,
            guidance_embed: guidance,
        }
    }

    /// The vendored diffusers DiT loads (dense, no `.scales`) and forwards to the FLUX velocity shape
    /// `[B, img_seq, 64]` with finite values — exercising the double/single/output-head wiring and the
    /// `cat(txt,img)` single-block plumbing end-to-end. `guidance_embed = true` also exercises the dev
    /// guidance-embedder path. A 2-double / 2-single tiny config keeps it GPU-free.
    #[test]
    fn packed_dit_dense_forward_shape_and_finite() -> Result<()> {
        let dev = Device::Cpu;
        let cfg = tiny_cfg(true);
        let vm = VarMap::new();
        let vb = VarBuilder::from_varmap(&vm, DType::F32, &dev);
        let dit = PackedFluxDit::new(&cfg, 2, 2, vb)?;

        let (b, img_seq, txt_seq) = (1usize, 4usize, 3usize);
        let img = Tensor::randn(0f32, 1f32, (b, img_seq, 64), &dev)?;
        let txt = Tensor::randn(0f32, 1f32, (b, txt_seq, 4096), &dev)?;
        let pooled = Tensor::randn(0f32, 1f32, (b, 768), &dev)?;
        let img_ids = Tensor::zeros((b, img_seq, 3), DType::F32, &dev)?;
        let txt_ids = Tensor::zeros((b, txt_seq, 3), DType::F32, &dev)?;
        let ts = Tensor::full(0.5f32, b, &dev)?;
        let g = Tensor::full(3.5f32, b, &dev)?;

        let out = dit.forward(&img, &img_ids, &txt, &txt_ids, &ts, &pooled, Some(&g))?;
        assert_eq!(out.dims(), &[b, img_seq, 64]);
        let max = out.abs()?.max_all()?.to_scalar::<f32>()?;
        assert!(max.is_finite(), "DiT output must be finite, got max {max}");
        Ok(())
    }

    #[test]
    fn dense_streamed_blocks_match_resident_window_one() -> Result<()> {
        let dev = Device::Cpu;
        let cfg = tiny_cfg(true);
        let vm = VarMap::new();
        let vb = VarBuilder::from_varmap(&vm, DType::F32, &dev);
        let resident = PackedFluxDit::new(&cfg, 2, 2, vb.clone())?;
        let streamed = PackedFluxDit::new_block_streamed(&cfg, 2, 2, vb)?;
        let (b, img_seq, txt_seq) = (1usize, 4usize, 3usize);
        let img = Tensor::randn(0f32, 1f32, (b, img_seq, 64), &dev)?;
        let txt = Tensor::randn(0f32, 1f32, (b, txt_seq, 4096), &dev)?;
        let pooled = Tensor::randn(0f32, 1f32, (b, 768), &dev)?;
        let ts = Tensor::full(0.5f32, b, &dev)?;
        let guidance = Tensor::full(3.5f32, b, &dev)?;
        let img_ids = Tensor::zeros((b, img_seq, 3), DType::F32, &dev)?;
        let txt_ids = Tensor::zeros((b, txt_seq, 3), DType::F32, &dev)?;
        let expected = resident.forward(
            &img,
            &img_ids,
            &txt,
            &txt_ids,
            &ts,
            &pooled,
            Some(&guidance),
        )?;
        let actual = streamed
            .forward_with_memory(
                &img,
                &img_ids,
                &txt,
                &txt_ids,
                &ts,
                &pooled,
                Some(&guidance),
                AttentionPlan::budgeted(AttentionBudget::from_score_elements(u64::MAX, false)),
                1,
                &candle_gen::gen_core::CancelFlag::default(),
            )
            .map_err(|error| candle_gen::candle_core::Error::Msg(error.to_string()))?;
        assert_eq!(expected.to_vec3::<f32>()?, actual.to_vec3::<f32>()?);
        Ok(())
    }

    /// A test [`DitImageInjector`] that adds a constant residual to the image stream after one double
    /// block and one single block, so the effect of the seam is observable (the candle twin of the
    /// PuLID CA modules, without the identity math).
    struct StubInjector {
        after_double_idx: usize,
        after_single_idx: usize,
        value: f64,
    }

    impl StubInjector {
        /// A **channel-varying** residual (a per-channel ramp, broadcast over batch/tokens). A constant
        /// or pure-scalar-multiple residual would be normalized away by the output-head LayerNorm
        /// (shift/scale-invariant per token) after passing near-unchanged through the residual single
        /// blocks — so it could not be observed. The real PuLID CA residual likewise varies per channel.
        fn residual(&self, like: &Tensor) -> Result<Tensor> {
            let (b, s, c) = like.dims3()?;
            let ramp = Tensor::arange(0u32, c as u32, like.device())?
                .to_dtype(like.dtype())?
                .affine(self.value / c as f64, self.value)?;
            ramp.reshape((1, 1, c))?
                .broadcast_as((b, s, c))?
                .contiguous()
        }
    }

    impl DitImageInjector for StubInjector {
        fn after_double(&self, block_idx: usize, img_hidden: &Tensor) -> Result<Option<Tensor>> {
            if block_idx == self.after_double_idx {
                Ok(Some(self.residual(img_hidden)?))
            } else {
                Ok(None)
            }
        }
        fn injects_after_single(&self, block_idx: usize) -> bool {
            block_idx == self.after_single_idx
        }
        fn after_single(&self, block_idx: usize, img_tokens: &Tensor) -> Result<Option<Tensor>> {
            if block_idx == self.after_single_idx {
                Ok(Some(self.residual(img_tokens)?))
            } else {
                Ok(None)
            }
        }
    }

    /// Build a tiny dense diffusers DiT with deterministically-randomized weights. A zero-init VarMap
    /// (as in the finite-shape smoke above) makes the forward degenerate — the output-head LayerNorm
    /// normalizes away a constant residual and the zero `proj_out` maps everything to 0 — so an injected
    /// residual could not be observed. Randomizing every parameter (mirrors `ip_dit::tests::tiny_ipflux`)
    /// makes the forward a non-degenerate function of the injector.
    fn randomized_tiny_dit(dev: &Device) -> Result<PackedFluxDit> {
        Ok(randomized_tiny_dit_pair(dev)?.0)
    }

    fn randomized_tiny_dit_pair(dev: &Device) -> Result<(PackedFluxDit, PackedFluxDit)> {
        let cfg = tiny_cfg(true);
        let vm = VarMap::new();
        let vb = VarBuilder::from_varmap(&vm, DType::F32, dev);
        let resident = PackedFluxDit::new(&cfg, 2, 2, vb.clone())?;
        let streamed = PackedFluxDit::new_block_streamed(&cfg, 2, 2, vb)?;
        let mut seed = 0x9E3779B97F4A7C15u64;
        for var in vm.data().lock().unwrap().values() {
            let n = var.shape().elem_count();
            let data: Vec<f32> = (0..n)
                .map(|_| {
                    // xorshift64* — deterministic, self-contained (no rand dep in this crate's tests).
                    seed ^= seed >> 12;
                    seed ^= seed << 25;
                    seed ^= seed >> 27;
                    let u =
                        (seed.wrapping_mul(0x2545F4914F6CDD1D) >> 11) as f64 / (1u64 << 53) as f64;
                    ((u as f32) - 0.5) * 0.1
                })
                .collect();
            var.set(&Tensor::from_vec(data, var.shape(), dev)?)?;
        }
        Ok((resident, streamed))
    }

    #[test]
    fn streamed_injected_window_one_matches_resident_across_both_namespaces() -> Result<()> {
        let dev = Device::Cpu;
        let (resident, streamed) = randomized_tiny_dit_pair(&dev)?;
        let (b, img_seq, txt_seq) = (1usize, 4usize, 3usize);
        let img = Tensor::randn(0f32, 1f32, (b, img_seq, 64), &dev)?;
        let txt = Tensor::randn(0f32, 1f32, (b, txt_seq, 4096), &dev)?;
        let pooled = Tensor::randn(0f32, 1f32, (b, 768), &dev)?;
        let img_ids = Tensor::zeros((b, img_seq, 3), DType::F32, &dev)?;
        let txt_ids = Tensor::zeros((b, txt_seq, 3), DType::F32, &dev)?;
        let ts = Tensor::full(0.5f32, b, &dev)?;
        let guidance = Tensor::full(3.5f32, b, &dev)?;
        let injector = StubInjector {
            after_double_idx: 1,
            after_single_idx: 0,
            value: 0.5,
        };
        let plan =
            || AttentionPlan::budgeted(AttentionBudget::from_score_elements(u64::MAX, false));
        let cancel = candle_gen::gen_core::CancelFlag::default();
        let expected = resident
            .forward_injected_with_memory(
                &img,
                &img_ids,
                &txt,
                &txt_ids,
                &ts,
                &pooled,
                Some(&guidance),
                Some(&injector),
                plan(),
                1,
                &cancel,
            )
            .map_err(|error| candle_gen::candle_core::Error::Msg(error.to_string()))?;
        let actual = streamed
            .forward_injected_with_memory(
                &img,
                &img_ids,
                &txt,
                &txt_ids,
                &ts,
                &pooled,
                Some(&guidance),
                Some(&injector),
                plan(),
                1,
                &cancel,
            )
            .map_err(|error| candle_gen::candle_core::Error::Msg(error.to_string()))?;
        assert_eq!(expected.to_vec3::<f32>()?, actual.to_vec3::<f32>()?);
        Ok(())
    }

    /// The packed XLabs seam uses the double block's post-QKNorm, pre-RoPE image query (not the
    /// generic post-block injector). Window-one streaming must preserve its absolute block index and
    /// populate exactly one cached image-token K/V pair per adapted block.
    #[test]
    fn streamed_xlabs_window_one_matches_resident_and_populates_each_block_cache() -> Result<()> {
        let dev = Device::Cpu;
        let (resident, streamed) = randomized_tiny_dit_pair(&dev)?;
        let (b, img_seq, txt_seq) = (1usize, 4usize, 3usize);
        let img = Tensor::randn(0f32, 1f32, (b, img_seq, 64), &dev)?;
        let txt = Tensor::randn(0f32, 1f32, (b, txt_seq, 4096), &dev)?;
        let pooled = Tensor::randn(0f32, 1f32, (b, 768), &dev)?;
        let img_ids = Tensor::zeros((b, img_seq, 3), DType::F32, &dev)?;
        let txt_ids = Tensor::zeros((b, txt_seq, 3), DType::F32, &dev)?;
        let ts = Tensor::full(0.5f32, b, &dev)?;
        let guidance = Tensor::full(3.5f32, b, &dev)?;
        let adapter = crate::ip_adapter::FluxIpAdapter::synthetic_for_hidden(2, 4096, 16, &dev)?;
        let token_data = (0..4 * 4096)
            .map(|index| (index as f32 * 0.019).sin() * 0.1)
            .collect::<Vec<_>>();
        let tokens = Tensor::from_vec(token_data, (1, 4, 4096), &dev)?;
        let resident_injector = FluxIpInjector::new(&adapter, tokens.clone(), 0.7);
        let streamed_injector = FluxIpInjector::new(&adapter, tokens, 0.7);
        let plan =
            || AttentionPlan::budgeted(AttentionBudget::from_score_elements(u64::MAX, false));
        let cancel = candle_gen::gen_core::CancelFlag::default();

        let expected = resident
            .forward_ip_with_memory(
                &img,
                &img_ids,
                &txt,
                &txt_ids,
                &ts,
                &pooled,
                Some(&guidance),
                &resident_injector,
                plan(),
                1,
                &cancel,
            )
            .map_err(|error| candle_gen::candle_core::Error::Msg(error.to_string()))?;
        let actual = streamed
            .forward_ip_with_memory(
                &img,
                &img_ids,
                &txt,
                &txt_ids,
                &ts,
                &pooled,
                Some(&guidance),
                &streamed_injector,
                plan(),
                1,
                &cancel,
            )
            .map_err(|error| candle_gen::candle_core::Error::Msg(error.to_string()))?;
        assert_eq!(expected.to_vec3::<f32>()?, actual.to_vec3::<f32>()?);
        assert_eq!(resident_injector.cached_block_count(), 2);
        assert_eq!(streamed_injector.cached_block_count(), 2);

        let baseline = resident.forward(
            &img,
            &img_ids,
            &txt,
            &txt_ids,
            &ts,
            &pooled,
            Some(&guidance),
        )?;
        assert!(
            max_abs_diff(&baseline, &expected) > 1e-6,
            "nonzero XLabs residual must affect the packed DiT output"
        );
        Ok(())
    }

    #[test]
    fn streamed_control_window_one_matches_resident_with_absolute_residual_indices() -> Result<()> {
        let dev = Device::Cpu;
        let (resident, streamed) = randomized_tiny_dit_pair(&dev)?;
        let (b, img_seq, txt_seq) = (1usize, 4usize, 3usize);
        let img = Tensor::randn(0f32, 1f32, (b, img_seq, 64), &dev)?;
        let txt = Tensor::randn(0f32, 1f32, (b, txt_seq, 4096), &dev)?;
        let pooled = Tensor::randn(0f32, 1f32, (b, 768), &dev)?;
        let img_ids = Tensor::zeros((b, img_seq, 3), DType::F32, &dev)?;
        let txt_ids = Tensor::zeros((b, txt_seq, 3), DType::F32, &dev)?;
        let ts = Tensor::full(0.5f32, b, &dev)?;
        let guidance = Tensor::full(3.5f32, b, &dev)?;
        let ramp = Tensor::arange(0f32, 16f32, &dev)?
            .reshape((1, 1, 16))?
            .broadcast_as((b, img_seq, 16))?
            .contiguous()?;
        let residuals = vec![ramp.affine(0.025, 0.1)?, ramp.affine(-0.05, -0.2)?];
        let plan =
            || AttentionPlan::budgeted(AttentionBudget::from_score_elements(u64::MAX, false));
        let cancel = candle_gen::gen_core::CancelFlag::default();
        let expected = resident
            .forward_control_with_memory(
                &img,
                &img_ids,
                &txt,
                &txt_ids,
                &ts,
                &pooled,
                Some(&guidance),
                None,
                Some((&residuals, 0.7)),
                plan(),
                1,
                &cancel,
            )
            .map_err(|error| candle_gen::candle_core::Error::Msg(error.to_string()))?;
        let actual = streamed
            .forward_control_with_memory(
                &img,
                &img_ids,
                &txt,
                &txt_ids,
                &ts,
                &pooled,
                Some(&guidance),
                None,
                Some((&residuals, 0.7)),
                plan(),
                1,
                &cancel,
            )
            .map_err(|error| candle_gen::candle_core::Error::Msg(error.to_string()))?;
        assert_eq!(expected.to_vec3::<f32>()?, actual.to_vec3::<f32>()?);
        let baseline = resident.forward(
            &img,
            &img_ids,
            &txt,
            &txt_ids,
            &ts,
            &pooled,
            Some(&guidance),
        )?;
        assert!(max_abs_diff(&baseline, &expected) > 1e-6);
        Ok(())
    }

    #[test]
    fn streamed_window_one_observes_cancel_before_next_block_materialization() -> Result<()> {
        struct CancelAfterFirst<'a> {
            cancel: &'a candle_gen::gen_core::CancelFlag,
            visited: RefCell<Vec<usize>>,
        }
        impl DitImageInjector for CancelAfterFirst<'_> {
            fn after_double(&self, block_idx: usize, _hidden: &Tensor) -> Result<Option<Tensor>> {
                self.visited.borrow_mut().push(block_idx);
                if block_idx == 0 {
                    self.cancel.cancel();
                }
                Ok(None)
            }

            fn injects_after_single(&self, _block_idx: usize) -> bool {
                false
            }

            fn after_single(
                &self,
                _block_idx: usize,
                _img_tokens: &Tensor,
            ) -> Result<Option<Tensor>> {
                Ok(None)
            }
        }

        let dev = Device::Cpu;
        let (_, streamed) = randomized_tiny_dit_pair(&dev)?;
        let (b, img_seq, txt_seq) = (1usize, 4usize, 3usize);
        let img = Tensor::zeros((b, img_seq, 64), DType::F32, &dev)?;
        let txt = Tensor::zeros((b, txt_seq, 4096), DType::F32, &dev)?;
        let pooled = Tensor::zeros((b, 768), DType::F32, &dev)?;
        let img_ids = Tensor::zeros((b, img_seq, 3), DType::F32, &dev)?;
        let txt_ids = Tensor::zeros((b, txt_seq, 3), DType::F32, &dev)?;
        let ts = Tensor::full(0.5f32, b, &dev)?;
        let guidance = Tensor::full(3.5f32, b, &dev)?;
        let cancel = candle_gen::gen_core::CancelFlag::default();
        let injector = CancelAfterFirst {
            cancel: &cancel,
            visited: RefCell::new(Vec::new()),
        };
        let error = streamed
            .forward_injected_with_memory(
                &img,
                &img_ids,
                &txt,
                &txt_ids,
                &ts,
                &pooled,
                Some(&guidance),
                Some(&injector),
                AttentionPlan::budgeted(AttentionBudget::from_score_elements(u64::MAX, false)),
                1,
                &cancel,
            )
            .expect_err("cancel after block zero must stop the next window");
        assert!(matches!(error, candle_gen::CandleError::Canceled));
        assert_eq!(&*injector.visited.borrow(), &[0]);
        Ok(())
    }

    /// `forward_injected(.., None)` is byte-identical to `forward(..)` — the seam is inert with no
    /// injector, so the txt2img packed path is unperturbed (mirrors the BFL `IpFlux` invariant).
    #[test]
    fn forward_injected_none_matches_forward() -> Result<()> {
        let dev = Device::Cpu;
        let dit = randomized_tiny_dit(&dev)?;
        let (b, img_seq, txt_seq) = (1usize, 4usize, 3usize);
        let img = Tensor::randn(0f32, 1f32, (b, img_seq, 64), &dev)?;
        let txt = Tensor::randn(0f32, 1f32, (b, txt_seq, 4096), &dev)?;
        let pooled = Tensor::randn(0f32, 1f32, (b, 768), &dev)?;
        let img_ids = Tensor::zeros((b, img_seq, 3), DType::F32, &dev)?;
        let txt_ids = Tensor::zeros((b, txt_seq, 3), DType::F32, &dev)?;
        let ts = Tensor::full(0.5f32, b, &dev)?;
        let g = Tensor::full(3.5f32, b, &dev)?;

        let base = dit.forward(&img, &img_ids, &txt, &txt_ids, &ts, &pooled, Some(&g))?;
        let injected =
            dit.forward_injected(&img, &img_ids, &txt, &txt_ids, &ts, &pooled, Some(&g), None)?;
        assert_eq!(
            max_abs_diff(&base, &injected),
            0.0,
            "None injector must be a no-op"
        );
        Ok(())
    }

    /// A nonzero injected residual (after a double block AND a single block) changes the output — the
    /// seam is actually wired into both block loops, not silently dropped.
    #[test]
    fn forward_injected_residual_changes_output() -> Result<()> {
        let dev = Device::Cpu;
        let dit = randomized_tiny_dit(&dev)?;
        let (b, img_seq, txt_seq) = (1usize, 4usize, 3usize);
        let img = Tensor::randn(0f32, 1f32, (b, img_seq, 64), &dev)?;
        let txt = Tensor::randn(0f32, 1f32, (b, txt_seq, 4096), &dev)?;
        let pooled = Tensor::randn(0f32, 1f32, (b, 768), &dev)?;
        let img_ids = Tensor::zeros((b, img_seq, 3), DType::F32, &dev)?;
        let txt_ids = Tensor::zeros((b, txt_seq, 3), DType::F32, &dev)?;
        let ts = Tensor::full(0.5f32, b, &dev)?;
        let g = Tensor::full(3.5f32, b, &dev)?;

        let base = dit.forward(&img, &img_ids, &txt, &txt_ids, &ts, &pooled, Some(&g))?;
        // Inject after double block 1 and single block 0 (both must be in-range for the tiny 2/2 DiT).
        let inj = StubInjector {
            after_double_idx: 1,
            after_single_idx: 0,
            value: 0.5,
        };
        let out = dit.forward_injected(
            &img,
            &img_ids,
            &txt,
            &txt_ids,
            &ts,
            &pooled,
            Some(&g),
            Some(&inj),
        )?;
        let d = max_abs_diff(&base, &out);
        assert!(
            d > 1e-4,
            "a nonzero injected residual must change the output: max|Δ| = {d}"
        );
        Ok(())
    }

    // ========================================================================================
    // Stock-vs-vendored DiT numeric parity (sc-9443).
    //
    // The vendored DiT above is the **diffusers**-layout FLUX.1 MMDiT (split `attn.to_q`/`to_k`/`to_v`,
    // `transformer_blocks`/`single_transformer_blocks`, `norm1.linear` AdaLN-Zero). The stock
    // `candle_transformers::models::flux::model::Flux` is the **BFL** layout (fused `img_attn.qkv`,
    // `double_blocks`/`single_blocks`, `img_mod.lin` modulation). They compute the same FLUX velocity —
    // so a dense build of the vendored DiT, its diffusers weights remapped into the BFL key layout, must
    // match the stock `Flux` forward at ~1e-4 on shared weights. This anchors the vendored DiT's RoPE /
    // QK-norm / QKV-split / modulation-chunk ordering against the reference (mirrors the CLIP/T5 encoder
    // parity tests in [`crate::packed_te`]). The remap (below) is the load-time transform the packed tier
    // implies: diffusers split-QKV → BFL fused-QKV, `to_out.0` → `proj`, per-embedder rename.
    // ========================================================================================

    use candle_gen::candle_core::Var;
    use std::collections::HashMap;

    fn max_abs_diff(a: &Tensor, b: &Tensor) -> f32 {
        a.to_dtype(DType::F32)
            .unwrap()
            .sub(&b.to_dtype(DType::F32).unwrap())
            .unwrap()
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap()
    }

    /// A tiny parity [`Config`]: heads 2 · head_dim 8 = hidden 16, `axes_dim` summing to 8.
    /// `context_in_dim`/`vec_in_dim` MUST be the real FLUX widths (4096 T5 / 768 pooled) because the
    /// vendored `context_embedder`/`text_embedder` are built at the module constants [`CONTEXT_DIM`] /
    /// [`POOLED_DIM`], not from the cfg — the stock `Flux` reads them from cfg, so pinning cfg to those
    /// constants keeps the two input projections shape-matched. Only the tiny seq lengths / hidden width
    /// keep it GPU-free (the two input `Linear`s are the cost, but a 3-token / 5-token forward is cheap).
    /// `guidance_embed` toggles the dev guidance-embedder path.
    fn parity_cfg(guidance: bool) -> Config {
        Config {
            in_channels: 32,
            vec_in_dim: POOLED_DIM,
            context_in_dim: CONTEXT_DIM,
            hidden_size: 16,
            mlp_ratio: 4.0,
            num_heads: 2,
            depth: 2,
            depth_single_blocks: 2,
            axes_dim: vec![2, 2, 4],
            theta: 10_000,
            qkv_bias: true,
            guidance_embed: guidance,
        }
    }

    /// Make the QK-RMSNorm scales **Q/K-asymmetric** so the parity anchors actually discriminate a
    /// Q↔K transposition in the QKV split (sc-9443, review). QK-RMSNorm + a tiny head_dim (8) +
    /// statistically-symmetric random-init `to_q`/`to_k` weights make Q and K interchangeable at this
    /// config's scale: swapping which projection feeds Q vs K leaves `softmax(QKᵀ)` unchanged to well
    /// inside 1e-4, so a wrong-QKV-split port would escape CI. The learned RMSNorm scale vectors are the
    /// one per-channel signal that survives the (scale-invariant) RMS normalization, so we overwrite them
    /// in the shared `VarMap` — *before* both the vendored and stock models read them — with distinct,
    /// deterministic per-channel patterns for the query vs key norms. Correct remap still matches exactly
    /// (both sides read the same asymmetric scales); a Q↔K swap now mismatches the channel weighting of
    /// the attention score and diverges by O(1), tripping the tight 1e-4 anchor.
    ///
    /// Query norm gets an ascending ramp `1.0 + 0.5·c/(D-1)` (∈[1.0, 1.5]); key norm gets a *descending*,
    /// sign-alternating pattern `-(1.5 - 0.5·c/(D-1))` — different magnitude curve AND different sign per
    /// channel, so the two are not related by any permutation/scale and the swap cannot cancel out.
    fn make_qk_asymmetric(
        vm: &mut VarMap,
        num_double: usize,
        num_single: usize,
        head_dim: usize,
        dev: &Device,
    ) -> Result<()> {
        let d = head_dim;
        let q_scale: Vec<f32> = (0..d)
            .map(|c| 1.0 + 0.5 * (c as f32) / ((d - 1).max(1) as f32))
            .collect();
        let k_scale: Vec<f32> = (0..d)
            .map(|c| {
                let m = 1.5 - 0.5 * (c as f32) / ((d - 1).max(1) as f32);
                if c % 2 == 0 {
                    -m
                } else {
                    m
                }
            })
            .collect();
        let q = Tensor::from_vec(q_scale, d, dev)?;
        let k = Tensor::from_vec(k_scale, d, dev)?;
        let mut set = |name: String, v: &Tensor| vm.set_one(name, v);
        for i in 0..num_double {
            let s = format!("transformer_blocks.{i}.attn");
            set(format!("{s}.norm_q.weight"), &q)?;
            set(format!("{s}.norm_k.weight"), &k)?;
            // The text stream carries its own QK-norm; make it asymmetric too so a Q↔K swap in the
            // `add_q_proj`/`add_k_proj` concat is likewise caught.
            set(format!("{s}.norm_added_q.weight"), &q)?;
            set(format!("{s}.norm_added_k.weight"), &k)?;
        }
        for i in 0..num_single {
            let s = format!("single_transformer_blocks.{i}.attn");
            set(format!("{s}.norm_q.weight"), &q)?;
            set(format!("{s}.norm_k.weight"), &k)?;
        }
        Ok(())
    }

    /// Swap the two halves of a tensor along dim 0 — the (scale, shift) → (shift, scale) re-ordering the
    /// diffusers→BFL output-head conversion needs (`norm_out.linear` is scale-first `AdaLayerNormContinuous`,
    /// BFL `adaLN_modulation.1` is shift-first). Applies to the `[2·hidden, hidden]` weight and `[2·hidden]`
    /// bias alike (sc-10914).
    fn swap_halves(x: &Tensor) -> Tensor {
        let h = x.dim(0).unwrap() / 2;
        let lo = x.narrow(0, 0, h).unwrap();
        let hi = x.narrow(0, h, h).unwrap();
        Tensor::cat(&[&hi, &lo], 0).unwrap()
    }

    /// Read a vendored tensor out of the populated `VarMap` by its diffusers key.
    fn t(map: &HashMap<String, Var>, key: &str) -> Tensor {
        map.get(key)
            .unwrap_or_else(|| panic!("missing vendored key {key}"))
            .as_tensor()
            .clone()
    }

    /// Remap the vendored **diffusers** DiT weights (already materialized in `vm`) into the **BFL** key
    /// layout the stock `candle_transformers` `Flux` reads, performing the split-QKV → fused-QKV
    /// concatenation the packed tier's layout difference requires. Returns a `HashMap` ready for
    /// `VarBuilder::from_tensors`.
    fn remap_to_bfl(
        vm: &VarMap,
        num_double: usize,
        num_single: usize,
        guidance: bool,
    ) -> HashMap<String, Tensor> {
        let src = vm.data().lock().unwrap();
        let src: HashMap<String, Var> = src.clone();
        let mut out: HashMap<String, Tensor> = HashMap::new();
        let mut put = |k: String, v: Tensor| {
            out.insert(k, v);
        };
        let g = |k: &str| t(&src, k);

        // Input projections + per-embedder rename.
        for wb in ["weight", "bias"] {
            put(format!("img_in.{wb}"), g(&format!("x_embedder.{wb}")));
            put(format!("txt_in.{wb}"), g(&format!("context_embedder.{wb}")));
            put(
                format!("time_in.in_layer.{wb}"),
                g(&format!("time_text_embed.timestep_embedder.linear_1.{wb}")),
            );
            put(
                format!("time_in.out_layer.{wb}"),
                g(&format!("time_text_embed.timestep_embedder.linear_2.{wb}")),
            );
            put(
                format!("vector_in.in_layer.{wb}"),
                g(&format!("time_text_embed.text_embedder.linear_1.{wb}")),
            );
            put(
                format!("vector_in.out_layer.{wb}"),
                g(&format!("time_text_embed.text_embedder.linear_2.{wb}")),
            );
            if guidance {
                put(
                    format!("guidance_in.in_layer.{wb}"),
                    g(&format!("time_text_embed.guidance_embedder.linear_1.{wb}")),
                );
                put(
                    format!("guidance_in.out_layer.{wb}"),
                    g(&format!("time_text_embed.guidance_embedder.linear_2.{wb}")),
                );
            }
            // Output head: diffusers `norm_out.linear` is (scale, shift) — **scale-first**
            // (`AdaLayerNormContinuous`) — whereas BFL `final_layer.adaLN_modulation.1` is (shift, scale)
            // shift-first. So the conversion **swaps the two halves** (verified against the real checkpoint:
            // the diffusers `norm_out.linear` halves are the byte-swapped BFL halves). `proj_out` ≡ BFL
            // `final_layer.linear`. (sc-10914 — swapping here is what anchors the corrected scale-first
            // `OutputHead` chunk order against stock; a straight copy would re-hide the original bug.)
            put(
                format!("final_layer.adaLN_modulation.1.{wb}"),
                swap_halves(&g(&format!("norm_out.linear.{wb}"))),
            );
            put(
                format!("final_layer.linear.{wb}"),
                g(&format!("proj_out.{wb}")),
            );
        }

        // Double blocks: `transformer_blocks.{i}` → `double_blocks.{i}`.
        for i in 0..num_double {
            let s = format!("transformer_blocks.{i}");
            let d = format!("double_blocks.{i}");
            // Modulation: diffusers chunk order [shift_msa, scale_msa, gate_msa, shift_mlp, scale_mlp,
            // gate_mlp] matches BFL Modulation2's (mod1=shift,scale,gate ; mod2=shift,scale,gate) — a
            // straight rename of `norm1.linear` → `img_mod.lin`, `norm1_context.linear` → `txt_mod.lin`.
            for wb in ["weight", "bias"] {
                put(
                    format!("{d}.img_mod.lin.{wb}"),
                    g(&format!("{s}.norm1.linear.{wb}")),
                );
                put(
                    format!("{d}.txt_mod.lin.{wb}"),
                    g(&format!("{s}.norm1_context.linear.{wb}")),
                );
            }
            // Fused QKV (image stream): concat split `to_q`/`to_k`/`to_v` on the output rows (dim 0).
            for wb in ["weight", "bias"] {
                let qkv = Tensor::cat(
                    &[
                        &g(&format!("{s}.attn.to_q.{wb}")),
                        &g(&format!("{s}.attn.to_k.{wb}")),
                        &g(&format!("{s}.attn.to_v.{wb}")),
                    ],
                    0,
                )
                .unwrap();
                put(format!("{d}.img_attn.qkv.{wb}"), qkv);
                let add_qkv = Tensor::cat(
                    &[
                        &g(&format!("{s}.attn.add_q_proj.{wb}")),
                        &g(&format!("{s}.attn.add_k_proj.{wb}")),
                        &g(&format!("{s}.attn.add_v_proj.{wb}")),
                    ],
                    0,
                )
                .unwrap();
                put(format!("{d}.txt_attn.qkv.{wb}"), add_qkv);
                // Attn output proj: diffusers `to_out.0` → BFL `img_attn.proj`; `to_add_out` → `txt_attn.proj`.
                put(
                    format!("{d}.img_attn.proj.{wb}"),
                    g(&format!("{s}.attn.to_out.0.{wb}")),
                );
                put(
                    format!("{d}.txt_attn.proj.{wb}"),
                    g(&format!("{s}.attn.to_add_out.{wb}")),
                );
                // FF: diffusers `net.0.proj`/`net.2` → BFL Mlp `0`/`2` (image = img_mlp, context = txt_mlp).
                put(
                    format!("{d}.img_mlp.0.{wb}"),
                    g(&format!("{s}.ff.net.0.proj.{wb}")),
                );
                put(
                    format!("{d}.img_mlp.2.{wb}"),
                    g(&format!("{s}.ff.net.2.{wb}")),
                );
                put(
                    format!("{d}.txt_mlp.0.{wb}"),
                    g(&format!("{s}.ff_context.net.0.proj.{wb}")),
                );
                put(
                    format!("{d}.txt_mlp.2.{wb}"),
                    g(&format!("{s}.ff_context.net.2.{wb}")),
                );
            }
            // QK RMSNorm scales: diffusers `.weight` → BFL `.scale`.
            put(
                format!("{d}.img_attn.norm.query_norm.scale"),
                g(&format!("{s}.attn.norm_q.weight")),
            );
            put(
                format!("{d}.img_attn.norm.key_norm.scale"),
                g(&format!("{s}.attn.norm_k.weight")),
            );
            put(
                format!("{d}.txt_attn.norm.query_norm.scale"),
                g(&format!("{s}.attn.norm_added_q.weight")),
            );
            put(
                format!("{d}.txt_attn.norm.key_norm.scale"),
                g(&format!("{s}.attn.norm_added_k.weight")),
            );
        }

        // Single blocks: `single_transformer_blocks.{i}` → `single_blocks.{i}`.
        for i in 0..num_single {
            let s = format!("single_transformer_blocks.{i}");
            let d = format!("single_blocks.{i}");
            for wb in ["weight", "bias"] {
                // Modulation (3-chunk shift,scale,gate) → BFL Modulation1.
                put(
                    format!("{d}.modulation.lin.{wb}"),
                    g(&format!("{s}.norm.linear.{wb}")),
                );
                // linear1 = concat[to_q; to_k; to_v; proj_mlp] on output rows (BFL packs qkv then mlp).
                let l1 = Tensor::cat(
                    &[
                        &g(&format!("{s}.attn.to_q.{wb}")),
                        &g(&format!("{s}.attn.to_k.{wb}")),
                        &g(&format!("{s}.attn.to_v.{wb}")),
                        &g(&format!("{s}.proj_mlp.{wb}")),
                    ],
                    0,
                )
                .unwrap();
                put(format!("{d}.linear1.{wb}"), l1);
                // linear2 = diffusers `proj_out`.
                put(
                    format!("{d}.linear2.{wb}"),
                    g(&format!("{s}.proj_out.{wb}")),
                );
            }
            put(
                format!("{d}.norm.query_norm.scale"),
                g(&format!("{s}.attn.norm_q.weight")),
            );
            put(
                format!("{d}.norm.key_norm.scale"),
                g(&format!("{s}.attn.norm_k.weight")),
            );
        }

        out
    }

    /// **Vendored diffusers FLUX DiT ≡ stock candle-transformers BFL `Flux` (dense, 1e-4).** The
    /// vendored DiT is built dense into a `VarMap`; its diffusers weights are then remapped into the BFL
    /// key layout (split-QKV → fused-QKV concat, `to_out.0` → `proj`, per-embedder rename) and loaded
    /// into the stock `Flux`. Feeding both the same FLUX inputs, the velocity outputs must agree at
    /// against the reference model (sc-9443). A tiny config keeps it GPU-free.
    ///
    /// **One documented reference divergence.** The diffusers image-stream FF activation is *exact*
    /// GELU (`gelu_erf`) — the vendored DiT reproduces that ([`FeedForward::forward`], `approx=false`
    /// for `ff`) — whereas the stock BFL `Mlp` uses the *tanh-approx* GELU (`candle .gelu()`) on **both**
    /// streams. So a full double-block network differs by the compounded `gelu_erf` vs `gelu_tanh` gap
    /// (~5e-4 per element; ~1e-3 at the DiT output) — a genuine formulation difference between the two
    /// reference impls, not a port bug. Everything else (input/output projections, RoPE, QK-norm, joint
    /// attention, single blocks whose MLP uses the same tanh-GELU on both sides, the AdaLN output head)
    /// is bit-exact. So the test pins **two** anchors on the SAME shared weights:
    ///  - a **tight 1e-4** anchor with `depth = 0` (no double blocks) — the single-block + IO + output-
    ///    head path, which uses the same tanh-GELU on both sides, must match exactly (this is where the
    ///    single-block QKV split→fuse remap, the joint RoPE, and the AdaLN head are pinned);
    ///  - a **full-network** anchor (2 double + 2 single) bounded at 5e-3 — loose enough to absorb the
    ///    documented image-FF GELU gap yet far tighter than any structural bug (a wrong RoPE / QKV split
    ///    / modulation-chunk order diverges by O(1)), so it still guards the double-block wiring.
    ///
    /// **Discriminating the QKV split (sc-9443, review).** QK-RMSNorm + a tiny head_dim (8) + symmetric
    /// random-init `to_q`/`to_k` weights would make Q and K interchangeable at this scale — a Q↔K swap in
    /// the split→fuse concat leaves the output unchanged to inside 1e-4, so the anchor would *not* catch a
    /// transposed QKV split. To close that hole, [`make_qk_asymmetric`] overwrites the shared QK-norm
    /// scales with distinct per-channel patterns for the query vs key norms before either model reads them
    /// (correct remap still matches exactly; a Q↔K swap now diverges by O(1) — verified ~2.9 on the tight
    /// anchor). See that fn for the mechanism.
    fn run_parity(num_double: usize, num_single: usize, guidance: bool, tol: f32) -> Result<f32> {
        run_parity_cfg(parity_cfg(guidance), num_double, num_single, guidance, tol)
    }

    /// As [`run_parity`] but with a caller-supplied base [`Config`] — so a test can pin the vendored DiT
    /// against stock at the **real** FLUX.1 hyperparameters (head_dim 128, `axes_dim` [16,56,56], packed
    /// `in_channels` 64) rather than only the tiny parity config. The tiny config's `axes_dim` [2,2,4]
    /// and head_dim 8 cannot exercise a RoPE / attention-reshape bug that only manifests at the real
    /// per-axis rope widths.
    fn run_parity_cfg(
        base: Config,
        num_double: usize,
        num_single: usize,
        guidance: bool,
        tol: f32,
    ) -> Result<f32> {
        use candle_transformers::models::flux::model::{Config as StockConfig, Flux};
        use candle_transformers::models::flux::WithForward;

        let dev = Device::Cpu;
        let mut cfg = base;
        cfg.guidance_embed = guidance;
        cfg.depth = num_double;
        cfg.depth_single_blocks = num_single;

        // Build the vendored diffusers DiT — this populates the VarMap with diffusers-keyed weights.
        let mut vm = VarMap::new();
        let vb = VarBuilder::from_varmap(&vm, DType::F32, &dev);
        let vendored = PackedFluxDit::new(&cfg, num_double, num_single, vb)?;

        // Make the shared QK-norm scales Q/K-asymmetric so the parity anchors actually catch a Q↔K
        // transposition in the QKV split (sc-9443); both models read these mutated scales, so a correct
        // remap still matches exactly. Must run before `remap_to_bfl` snapshots the VarMap.
        let head_dim = Dims::from_config(&cfg).head_dim;
        make_qk_asymmetric(&mut vm, num_double, num_single, head_dim, &dev)?;

        // Remap into the BFL layout and build the stock model from those exact weights.
        let bfl = remap_to_bfl(&vm, num_double, num_single, guidance);
        let stock_cfg = StockConfig {
            in_channels: cfg.in_channels,
            vec_in_dim: cfg.vec_in_dim,
            context_in_dim: cfg.context_in_dim,
            hidden_size: cfg.hidden_size,
            mlp_ratio: cfg.mlp_ratio,
            num_heads: cfg.num_heads,
            depth: cfg.depth,
            depth_single_blocks: cfg.depth_single_blocks,
            axes_dim: cfg.axes_dim.clone(),
            theta: cfg.theta,
            qkv_bias: cfg.qkv_bias,
            guidance_embed: cfg.guidance_embed,
        };
        let vb_stock = VarBuilder::from_tensors(bfl, DType::F32, &dev);
        let stock = Flux::new(&stock_cfg, vb_stock)?;

        // Shared FLUX inputs.
        let (b, img_seq, txt_seq) = (1usize, 5usize, 3usize);
        let img = Tensor::randn(0f32, 1f32, (b, img_seq, cfg.in_channels), &dev)?;
        let txt = Tensor::randn(0f32, 1f32, (b, txt_seq, cfg.context_in_dim), &dev)?;
        let pooled = Tensor::randn(0f32, 1f32, (b, cfg.vec_in_dim), &dev)?;
        // Non-trivial position ids (rows differ) so RoPE is actually exercised.
        let mk_ids = |n: usize| -> Result<Tensor> {
            let mut v = Vec::with_capacity(n * 3);
            for r in 0..n {
                v.push(r as f32);
                v.push((r % 2) as f32);
                v.push((r % 3) as f32);
            }
            Tensor::from_vec(v, (b, n, 3), &dev)
        };
        let img_ids = mk_ids(img_seq)?;
        let txt_ids = mk_ids(txt_seq)?;
        let ts = Tensor::full(0.37f32, b, &dev)?;
        let guid = if guidance {
            Some(Tensor::full(3.5f32, b, &dev)?)
        } else {
            None
        };

        let v = vendored.forward(&img, &img_ids, &txt, &txt_ids, &ts, &pooled, guid.as_ref())?;
        let s = stock.forward(&img, &img_ids, &txt, &txt_ids, &ts, &pooled, guid.as_ref())?;
        assert_eq!(v.dims(), s.dims());
        let d = max_abs_diff(&v, &s);
        assert!(
            d < tol,
            "vendored diffusers DiT vs stock BFL Flux (double={num_double} single={num_single} \
             guidance={guidance}) max|Δ| = {d} (tol {tol})"
        );
        Ok(d)
    }

    /// Tight anchor: single-block + IO + output-head path is bit-exact against stock (no image-FF GELU
    /// divergence, since `depth = 0`). Runs both the schnell (no guidance) and dev (guidance) heads.
    #[test]
    fn vendored_dit_single_and_io_matches_stock_bfl_dense() -> Result<()> {
        for guidance in [false, true] {
            let d = run_parity(0, 2, guidance, 1e-4)?;
            assert!(d < 1e-4, "single-block/IO parity max|Δ| = {d}");
        }
        Ok(())
    }

    /// Full-network anchor: 2 double + 2 single blocks, bounded at 5e-3 (absorbs only the documented
    /// image-FF `gelu_erf` vs stock `gelu_tanh` gap; a structural bug would diverge by O(1)).
    #[test]
    fn vendored_dit_full_network_close_to_stock_bfl_dense() -> Result<()> {
        for guidance in [false, true] {
            let d = run_parity(2, 2, guidance, 5e-3)?;
            // Sanity: the divergence must be well within the documented GELU-variant band, not O(1).
            assert!(d < 5e-3, "full-network parity max|Δ| = {d}");
        }
        Ok(())
    }

    /// The **real** FLUX.1 hyperparameters (sc-10914 investigation): head_dim 128, `axes_dim` [16,56,56],
    /// packed `in_channels` 64, hidden 3072/24 heads. Only the tiny seq lengths keep it GPU-free. This
    /// exercises the RoPE per-axis rope widths + the attention reshape at the widths the shipping tiers
    /// actually use — which the tiny [`parity_cfg`] ([2,2,4], head_dim 8) cannot.
    fn real_cfg() -> Config {
        Config {
            in_channels: 64,
            vec_in_dim: POOLED_DIM,
            context_in_dim: CONTEXT_DIM,
            hidden_size: 3072,
            mlp_ratio: 4.0,
            num_heads: 24,
            depth: 0,
            depth_single_blocks: 0,
            axes_dim: vec![16, 56, 56],
            theta: 10_000,
            qkv_bias: true,
            guidance_embed: true,
        }
    }

    /// Real-dims single-block + IO + **output-head** path must be bit-exact against stock. This is the
    /// anchor for the scale-first `OutputHead` chunk order at the real `axes_dim`/head_dim/64-channel
    /// widths the shipping tiers use — paired with the half-swap in [`remap_to_bfl`], reverting the
    /// output head to shift-first breaks it (sc-10914). One double block is already covered by the tiny
    /// [`vendored_dit_full_network_close_to_stock_bfl_dense`]; kept to depth=0 here to bound CI cost.
    #[test]
    fn vendored_dit_real_config_matches_stock_bfl_dense() -> Result<()> {
        let d = run_parity_cfg(real_cfg(), 0, 1, true, 1e-4)?;
        assert!(d < 1e-4, "real-config single/IO parity max|Δ| = {d}");
        Ok(())
    }
}
