//! The trainable LoRA/LoKr adapter seam (sc-5165).
//!
//! [`LoraLinear`] is the candle analog of a PEFT-wrapped `nn::Linear`: a **frozen** base `Linear`
//! plus an optional low-rank (LoRA) or Kronecker (LoKr) residual added *in the forward*. The residual
//! factors are held as `Var`-backed [`Tensor`]s — storage-sharing clones of the trainer's `Var`s — so:
//!
//!  * the optimizer's `Var::set` mutates that storage in place, and the **next forward reads the new
//!    values** with no re-install and no model rebuild (candle is eager: each forward re-reads the
//!    factor storage at matmul time); and
//!  * the clones keep the `Var`'s tensor-id and variable flag, so `loss.backward()` records them as
//!    leaves and `GradStore::get(var)` returns the factor gradient.
//!
//! Factors are **f32** regardless of the train dtype (master-weights pattern, per the gen-core
//! `TrainingConfig` contract); the forward casts them to the activation dtype for the matmul (a
//! differentiable cast, so grads flow back to the f32 `Var`s). The LoKr residual is reconstructed the
//! same way the inference loader does — `ΔW = (alpha/rank)·kron(w1, w2)` at f32 — so a trained adapter
//! round-trips exactly (mirrors mlx-gen's `reconstruct_lokr_delta`, SDXL f32 path).
//!
//! A model exposes its adaptable projections by implementing [`LoraHost`]; [`build_lora_targets`] /
//! [`build_lokr_targets`] then walk the host, size + initialize the factors per target, install them,
//! and return a [`LoraSet`] (the flat `Var` list for the optimizer + the per-target metadata for
//! checkpoint save). This keeps the harness model-agnostic — SDXL, Z-Image, and Wan reuse it.

use std::collections::{BTreeMap, HashMap};
use std::path::Path;

use candle_core::{DType, Device, Tensor, Var};
use candle_nn::{Linear, Module, VarBuilder};
use rand::distr::Uniform;
use rand::{rngs::StdRng, SeedableRng};
use rand_distr::Distribution;

use crate::quant::{AdaptLinear, LokrFactors, QLinear};
use crate::{CandleError, Result};

/// PEFT gaussian-init standard deviation for the **LoRA** `A` factor (diffusers/PEFT
/// `init_lora_weights="gaussian"` uses 0.02); the LoRA `B` leg starts at zero, so the LoRA is the
/// identity at step 0. (LoKr no longer uses this — sc-5179 moved its init to PEFT's zero-`w1` /
/// kaiming-`w2` `reset_adapter_parameters`; see [`build_lokr_targets`].)
const INIT_STD: f32 = 0.02;

/// The SDXL default LoRA target suffixes — the attention projections (matches the torch
/// `DEFAULT_LORA_TARGET_MODULES` and the MLX trainer). `to_out.0` is the first element of diffusers'
/// `to_out` `ModuleList`, so its path segment literally contains the `.0`.
pub const SDXL_ATTN_TARGETS: [&str; 4] = ["to_q", "to_k", "to_v", "to_out.0"];

/// The PEFT key prefix SDXL writes (what `peft.save_pretrained()` emits and the SDXL loader's PEFT
/// classifier expects). The DiT families use `""` (bare dotted paths).
pub const SDXL_PEFT_PREFIX: &str = "base_model.model.unet.";

/// Which adapter parameterization a [`LoraSet`] carries.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum AdapterKind {
    /// Standard low-rank `B·A` residual.
    Lora,
    /// LyCORIS Kronecker-product residual.
    Lokr,
}

impl AdapterKind {
    /// The `networkType` metadata string written into the adapter `.safetensors`.
    pub fn network_type(self) -> &'static str {
        match self {
            AdapterKind::Lora => "lora",
            AdapterKind::Lokr => "lokr",
        }
    }
}

/// The trainable second Kronecker leg of a LoKr residual: either a full `[out_b, in_b]` matrix or a
/// low-rank product `w2_a[out_b, rank] · w2_b[rank, in_b]`.
#[derive(Debug, Clone)]
enum LokrW2 {
    Full(Tensor),
    LowRank { a: Tensor, b: Tensor },
}

/// The trainable residual spliced into a [`LoraLinear`]'s forward. Holds storage-sharing clones of
/// the trainer's `Var`s (see the module docs) — never owned weight copies.
#[derive(Debug, Clone)]
enum Adapter {
    /// `down`: `A` `[rank, in]`; `up`: `B` `[out, rank]`; residual = `scale · (x·Aᵀ)·Bᵀ`.
    Lora {
        down: Tensor,
        up: Tensor,
        scale: f64,
    },
    /// `w1` `[out_a, in_a]`, `w2` (full/low-rank) reconstructing `[out_b, in_b]`; residual =
    /// `x · ΔWᵀ` with `ΔW = scale · kron(w1, w2)` reshaped to `[out, in]`.
    Lokr {
        w1: Tensor,
        w2: LokrW2,
        out_f: usize,
        in_f: usize,
        scale: f64,
    },
}

/// A **forward-time additive (unmerged) inference residual** stacked onto a [`LoraLinear`] — the
/// packed-tier analog of the trainable [`Adapter`] (sc-11103, epic 10765). Unlike [`Adapter`] (a single
/// `Var`-backed trainable residual that a **dense** base folds at merge time), these are frozen f32
/// factors added *at forward* and valid on **any** base including an MLX-**packed** [`QLinear`] — the
/// base weight is never dequantized or mutated, so a q4/q8 SDXL tier keeps its footprint while a distill
/// LoRA rides on top. This is the SDXL adoption of the shared additive path
/// ([`crate::quant::AdaptLinear`], sc-11091): the LoRA arm is the same two-small-matmul residual, and
/// the LoKr arm delegates to the shared allocation-free [`LokrFactors`] vec-trick (no `[out,in]` delta,
/// so a LoKr stays packed too). Multiple residuals stack, applied in push order after the base.
#[derive(Debug, Clone)]
enum AdditiveResidual {
    /// `scale·((x·a)·b)`: `a` `[in, rank]` (= `downᵀ`), `b` `[rank, out]` (= `upᵀ` with `alpha/rank`
    /// folded in). The deferred two-matmul form — never the `[out,in]` product — so it stays memory-free
    /// on a packed base. Mirrors [`crate::quant::AdaptLinear`]'s `Lora` arm exactly.
    Lora { a: Tensor, b: Tensor, scale: f64 },
    /// The structured LoKr residual via the shared Kronecker vec-trick; the full `(alpha/rank)·strength`
    /// scale is baked into the [`LokrFactors`], so `[out,in]` is never formed.
    LokrStructured { factors: LokrFactors },
}

impl AdditiveResidual {
    /// A zero user strength is an exact disabled adapter. Check it before evaluating the factors so
    /// unused non-finite data cannot contaminate the host output.
    fn is_zero(&self) -> bool {
        match self {
            AdditiveResidual::Lora { scale, .. } => *scale == 0.0,
            AdditiveResidual::LokrStructured { factors } => factors.scale == 0.0,
        }
    }

    /// The residual this adapter contributes, in the activation dtype of `x` (factors are held f32 and
    /// cast per forward — they are tiny). Identical to [`crate::quant::AdaptLinear`]'s residual so the
    /// packed-additive SDXL path and the dense-fold path agree to f32 tolerance.
    fn residual(&self, x: &Tensor) -> candle_core::Result<Tensor> {
        match self {
            AdditiveResidual::Lora { a, b, scale } => {
                let xd = x.dtype();
                let r = x
                    .broadcast_matmul(&a.to_dtype(xd)?)?
                    .broadcast_matmul(&b.to_dtype(xd)?)?;
                r * *scale
            }
            AdditiveResidual::LokrStructured { factors } => factors.residual(x),
        }
    }
}

/// 2-D Kronecker product `kron(a[m,n], b[p,q]) = [m·p, n·q]` via broadcast — differentiable, so grads
/// flow to `a`/`b`. `out[i·p+k, j·q+l] = a[i,j]·b[k,l]`.
fn kron2d(a: &Tensor, b: &Tensor) -> candle_core::Result<Tensor> {
    let (m, n) = a.dims2()?;
    let (p, q) = b.dims2()?;
    let a4 = a.reshape((m, 1, n, 1))?;
    let b4 = b.reshape((1, p, 1, q))?;
    a4.broadcast_mul(&b4)?.reshape((m * p, n * q))
}

/// The frozen base projection behind a [`LoraLinear`] — a plain dense `Linear` (the training default,
/// byte-identical to pre-sc-9416) or a **GGUF-quantized** [`QLinear`] loaded straight from a
/// pre-quantized MLX tier (sc-9416, the candle SDXL packed-load). Both compute `x·Wᵀ + b`; the packed
/// arm dequantizes-on-forward into a dense matmul (sc-7702). The packed base remains frozen, but an
/// independent trainable LoRA residual may be installed over it (the LTX q4 trainer path).
#[derive(Clone)]
enum LoraBase {
    Dense(Linear),
    Packed(QLinear),
}

// `QLinear` holds a `QMatMul`/`QTensor` that are not `Debug`; `LoraLinear` derives `Debug` (it drops
// into `#[derive(Debug)]` vendored modules), so summarize the base rather than recurse into the weight.
impl std::fmt::Debug for LoraBase {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        match self {
            Self::Dense(l) => f.debug_tuple("Dense").field(l).finish(),
            Self::Packed(_) => f.write_str("Packed(QLinear)"),
        }
    }
}

impl LoraBase {
    fn forward(&self, x: &Tensor) -> candle_core::Result<Tensor> {
        match self {
            Self::Dense(l) => l.forward(x),
            Self::Packed(q) => q.forward(x),
        }
    }

    fn is_packed(&self) -> bool {
        matches!(self, Self::Packed(_))
    }
}

/// A frozen base projection (dense or packed — `LoraBase`) with an optional trainable LoRA/LoKr
/// residual. Implements [`Module`] so it drops into a vendored model exactly where an
/// `nn::Linear` was, and carries its own PEFT-style `path` (captured from the `VarBuilder` prefix at
/// construction) so a [`LoraHost`] visitor can route adapters without threading prefixes through the
/// module tree.
#[derive(Debug, Clone)]
pub struct LoraLinear {
    base: LoraBase,
    in_features: usize,
    out_features: usize,
    path: String,
    adapter: Option<Adapter>,
    /// While a preview render is in flight ([`freeze_adapter`](Self::freeze_adapter)), the live
    /// `Var`-backed adapter is parked here and `adapter` holds a detached snapshot, so the inference
    /// forward builds no autograd graph. [`thaw_adapter`](Self::thaw_adapter) restores it.
    frozen: Option<Adapter>,
    /// Forward-time additive **inference** residuals (sc-11103), applied in push order AFTER the base
    /// (and after any trainable `adapter`). Empty on the plain / trainable path ⇒ forward is byte-
    /// identical to before. Valid on a **packed** base — the SDXL packed-tier distill-LoRA path pushes
    /// these instead of dequant-folding, so the q4/q8 footprint survives.
    additive: Vec<AdditiveResidual>,
}

impl LoraLinear {
    /// Wrap an already-built frozen base `Linear` known to map `in_features -> out_features`, at the
    /// given PEFT module `path`.
    pub fn from_linear(
        base: Linear,
        in_features: usize,
        out_features: usize,
        path: String,
    ) -> Self {
        Self {
            base: LoraBase::Dense(base),
            in_features,
            out_features,
            path,
            adapter: None,
            frozen: None,
            additive: Vec::new(),
        }
    }

    /// Wrap an already-built **packed** [`QLinear`] base (sc-9416) — the frozen base for
    /// a pre-quantized MLX tier. `in_features`/`out_features` are the logical projection dims; `path`
    /// is the PEFT module path. The packed weights are never trained; a LoRA can still be trained as an
    /// independent additive residual. With no adapter the forward is exactly the packed base's `x·Wᵀ + b`.
    pub fn from_qlinear(
        base: QLinear,
        in_features: usize,
        out_features: usize,
        path: String,
    ) -> Self {
        Self {
            base: LoraBase::Packed(base),
            in_features,
            out_features,
            path,
            adapter: None,
            frozen: None,
            additive: Vec::new(),
        }
    }

    /// Whether the frozen base is a packed (GGUF-quantized) [`QLinear`] rather than a dense `Linear`
    /// (sc-9416).
    pub fn is_packed(&self) -> bool {
        self.base.is_packed()
    }

    /// The PEFT module path (e.g. `down_blocks.0.attentions.0.transformer_blocks.0.attn1.to_q`),
    /// captured from the `VarBuilder` prefix at construction. Drives target matching + save keys.
    pub fn path(&self) -> &str {
        &self.path
    }

    pub fn in_features(&self) -> usize {
        self.in_features
    }

    pub fn out_features(&self) -> usize {
        self.out_features
    }

    /// Whether a trainable residual is currently installed.
    pub fn is_adapted(&self) -> bool {
        self.adapter.is_some()
    }

    /// Whether the live `Var`-backed adapter is currently parked behind a detached preview snapshot
    /// ([`freeze_adapter`](Self::freeze_adapter)). `false` once [`thaw_adapter`](Self::thaw_adapter)
    /// has restored it — i.e. the adapter is back in its gradient-tracking (training) state. Lets the
    /// harness assert the freeze/thaw restore invariant around preview rendering (F-035, sc-9019).
    pub fn is_frozen(&self) -> bool {
        self.frozen.is_some()
    }

    /// Install a LoRA residual. `down`/`up` are expected to be `Var`-backed (storage-sharing) f32
    /// tensors of shape `[rank, in]` / `[out, rank]`; `scale = alpha / rank`.
    ///
    /// The frozen base may be dense or packed. Adapter factors are independent f32 `Var`s, so a
    /// quantized base remains immutable while gradients flow through the residual.
    pub fn install_lora(&mut self, down: Tensor, up: Tensor, scale: f64) {
        self.adapter = Some(Adapter::Lora { down, up, scale });
    }

    /// Drop any installed residual (back to the frozen base — the inference path with no adapter).
    pub fn clear(&mut self) {
        self.adapter = None;
    }

    /// Attach a forward-time **additive LoRA** inference residual `scale·((x·a)·b)` (sc-11103): `a`
    /// `[in, rank]` (= `downᵀ`), `b` `[rank, out]` (= `upᵀ` with `alpha/rank` folded in), `scale` the
    /// per-adapter user strength. Unlike [`install_lora`](Self::install_lora) (trainable),
    /// this is valid on **any** base including a **packed** [`QLinear`] — the base weight is never
    /// dequantized, so a q4/q8 tier keeps its footprint. Multiple pushes stack (applied in push order).
    pub fn push_additive_lora(&mut self, a: Tensor, b: Tensor, scale: f64) {
        self.additive.push(AdditiveResidual::Lora { a, b, scale });
    }

    /// Attach a forward-time **additive structured LoKr** inference residual via the shared Kronecker
    /// vec-trick (sc-11103): the full `(alpha/rank)·strength` scale is baked into `factors`, so the
    /// `[out,in]` delta is never formed and the residual is memory-free on a packed base. Valid on any
    /// base; multiple pushes stack and mix freely with additive LoRA residuals (push order).
    pub fn push_additive_lokr(&mut self, factors: LokrFactors) {
        self.additive
            .push(AdditiveResidual::LokrStructured { factors });
    }

    /// Whether any forward-time additive inference residual is attached (sc-11103) — distinct from
    /// [`is_adapted`](Self::is_adapted), which reports the single *trainable* adapter.
    pub fn has_additive(&self) -> bool {
        !self.additive.is_empty()
    }

    fn install_lokr(&mut self, w1: Tensor, w2: LokrW2, scale: f64) {
        debug_assert!(
            !self.base.is_packed(),
            "cannot install a LoKr residual on a packed (quantized) base"
        );
        self.adapter = Some(Adapter::Lokr {
            w1,
            w2,
            out_f: self.out_features,
            in_f: self.in_features,
            scale,
        });
    }

    /// Park the live `Var`-backed adapter and install a **detached snapshot** in its place, so an
    /// inference forward (a preview render, sc-8650) builds NO autograd graph — the snapshot's factors
    /// are non-variable, so candle frees each layer's activations instead of retaining them for a
    /// backward that never comes. Without this the full-resolution preview OOMs (it retains a whole
    /// training-style graph of the 28-step denoise). Idempotent; pair with [`thaw_adapter`](Self::thaw_adapter).
    pub fn freeze_adapter(&mut self) {
        if self.frozen.is_none() {
            if let Some(original) = self.adapter.take() {
                self.adapter = Some(original.detached());
                self.frozen = Some(original);
            }
        }
    }

    /// Restore the live `Var`-backed adapter parked by [`freeze_adapter`](Self::freeze_adapter) so
    /// training resumes tracking gradients. Idempotent (no-op if not frozen).
    pub fn thaw_adapter(&mut self) {
        if let Some(original) = self.frozen.take() {
            self.adapter = Some(original);
        }
    }
}

impl Adapter {
    /// A graph-free copy: every `Var`-backed factor replaced by a [`Tensor::detach`]ed (non-variable)
    /// tensor sharing the same storage. A forward through it reads the current factor values but builds
    /// no autograd graph (sc-8650 preview rendering).
    fn detached(&self) -> Adapter {
        match self {
            Adapter::Lora { down, up, scale } => Adapter::Lora {
                down: down.detach(),
                up: up.detach(),
                scale: *scale,
            },
            Adapter::Lokr {
                w1,
                w2,
                out_f,
                in_f,
                scale,
            } => Adapter::Lokr {
                w1: w1.detach(),
                w2: match w2 {
                    LokrW2::Full(w) => LokrW2::Full(w.detach()),
                    LokrW2::LowRank { a, b } => LokrW2::LowRank {
                        a: a.detach(),
                        b: b.detach(),
                    },
                },
                out_f: *out_f,
                in_f: *in_f,
                scale: *scale,
            },
        }
    }
}

impl Module for LoraLinear {
    fn forward(&self, x: &Tensor) -> candle_core::Result<Tensor> {
        let y = self.base.forward(x)?;
        let mut y = match &self.adapter {
            None => y,
            Some(Adapter::Lora { scale, .. }) if *scale == 0.0 => y,
            // Factors are f32; cast to the activation dtype for the matmul. The cast is
            // differentiable, so grads flow back to the f32 `Var`s (master-weights). The factor
            // tensors share storage with those `Var`s, so this reads the current optimizer-updated value.
            Some(Adapter::Lora { down, up, scale }) => {
                let xd = x.dtype();
                let down = down.to_dtype(xd)?;
                let up = up.to_dtype(xd)?;
                let lora = x.broadcast_matmul(&down.t()?)?.broadcast_matmul(&up.t()?)?;
                let residual = (lora * *scale)?.to_dtype(y.dtype())?;
                (y + residual)?
            }
            Some(Adapter::Lokr { scale, .. }) if *scale == 0.0 => y,
            Some(Adapter::Lokr {
                w1,
                w2,
                out_f,
                in_f,
                scale,
            }) => {
                let factor2 = match w2 {
                    LokrW2::Full(w) => w.clone(),
                    LokrW2::LowRank { a, b } => a.matmul(b)?, // [out_b, rank] · [rank, in_b]
                };
                // ΔW = scale · kron(w1, w2) at f32, reshaped to [out, in] (kron already yields that
                // shape for the linear case; the reshape is a safety no-op). Cast to the activation
                // dtype for the residual matmul x·ΔWᵀ.
                let delta = kron2d(w1, &factor2)?.reshape((*out_f, *in_f))?;
                let delta = (delta * *scale)?.to_dtype(x.dtype())?;
                let residual = x.broadcast_matmul(&delta.t()?)?.to_dtype(y.dtype())?;
                (y + residual)?
            }
        };
        // Forward-time additive inference residuals (sc-11103), applied in push order after the base +
        // trainable adapter. Disabled residuals are skipped; live residuals retain their x-dtype math
        // and cast only to the current host output dtype at the add. Empty on the plain / trainable
        // path, so this loop is a no-op there.
        for ar in &self.additive {
            if ar.is_zero() {
                continue;
            }
            let residual = ar.residual(x)?.to_dtype(y.dtype())?;
            y = (y + residual)?;
        }
        Ok(y)
    }
}

/// Build a frozen base `Linear` (no bias) and wrap it as a [`LoraLinear`], recording the
/// `VarBuilder`'s current prefix as the PEFT path. Drop-in replacement for `candle_nn::linear_no_bias`
/// inside a vendored, trainable model.
pub fn lora_linear_no_bias(
    in_f: usize,
    out_f: usize,
    vs: VarBuilder,
) -> candle_core::Result<LoraLinear> {
    let path = vs.prefix();
    let base = candle_nn::linear_no_bias(in_f, out_f, vs)?;
    Ok(LoraLinear::from_linear(base, in_f, out_f, path))
}

/// Build a frozen base `Linear` (with bias) and wrap it as a [`LoraLinear`]. Drop-in replacement for
/// `candle_nn::linear`. The adapter residual adapts only the weight; the base bias is frozen.
pub fn lora_linear(in_f: usize, out_f: usize, vs: VarBuilder) -> candle_core::Result<LoraLinear> {
    let path = vs.prefix();
    let base = candle_nn::linear(in_f, out_f, vs)?;
    Ok(LoraLinear::from_linear(base, in_f, out_f, path))
}

/// **Packed-detecting** biased [`LoraLinear`] (sc-9416): if `{base_key}.scales` is present in `vs` (a
/// pre-quantized MLX tier) the frozen base is a quantized [`QLinear`] built straight from the packed
/// parts at `group_size` (no dense weight materialized); otherwise it is the plain dense `Linear`,
/// byte-identical to [`lora_linear`]. `base_key` is the full dotted prefix (e.g. `attn2.to_out.0`), so
/// the `.scales`/`.biases` siblings survive the `to_out.0` nesting — the `linear_detect` contract. The
/// A packed base can host an independent trainable LoRA residual. Used by the candle SDXL packed
/// txt2img load and the LTX q4 trainer.
pub fn lora_linear_detect(
    in_f: usize,
    out_f: usize,
    vs: &VarBuilder,
    base_key: &str,
    group_size: usize,
) -> candle_core::Result<LoraLinear> {
    let path = vs.pp(base_key).prefix();
    let q = crate::quant::lin_gs(vs, base_key, in_f, out_f, true, group_size)?;
    if q.is_quantized() {
        Ok(LoraLinear::from_qlinear(q, in_f, out_f, path))
    } else {
        Ok(LoraLinear::from_linear(
            candle_nn::linear(in_f, out_f, vs.pp(base_key))?,
            in_f,
            out_f,
            path,
        ))
    }
}

/// **Packed-detecting** bias-free [`LoraLinear`] (sc-9416) — the `no_bias` analogue of
/// [`lora_linear_detect`]. The SDXL attention `to_q`/`to_k`/`to_v` projections are bias-free.
pub fn lora_linear_no_bias_detect(
    in_f: usize,
    out_f: usize,
    vs: &VarBuilder,
    base_key: &str,
    group_size: usize,
) -> candle_core::Result<LoraLinear> {
    let path = vs.pp(base_key).prefix();
    let q = crate::quant::lin_gs(vs, base_key, in_f, out_f, false, group_size)?;
    if q.is_quantized() {
        Ok(LoraLinear::from_qlinear(q, in_f, out_f, path))
    } else {
        Ok(LoraLinear::from_linear(
            candle_nn::linear_no_bias(in_f, out_f, vs.pp(base_key))?,
            in_f,
            out_f,
            path,
        ))
    }
}

/// A model that exposes its adaptable [`LoraLinear`]s for the harness to install adapters into. The
/// candle analog of the MLX `AdaptableHost`. Implementors recurse their module tree, invoking `f` once
/// per adaptable projection; each `LoraLinear` already carries its PEFT `path`, so no prefix threading
/// is needed.
pub trait LoraHost {
    fn visit_lora_mut(&mut self, f: &mut dyn FnMut(&mut LoraLinear) -> Result<()>) -> Result<()>;
}

/// A model whose inference projections already use [`AdaptLinear`]. This parallel host seam lets a
/// trainer attach live `Var`-backed LoRA/LoKr factors without duplicating the model into a second
/// `LoraLinear`-only implementation. Paths are supplied by the host because `AdaptLinear` deliberately
/// carries no model-specific naming.
pub trait AdaptLoraHost {
    fn visit_adapt_lora_mut(
        &mut self,
        f: &mut dyn FnMut(&str, &mut AdaptLinear) -> Result<()>,
    ) -> Result<()>;
}

/// One installed target: its PEFT path plus the trainer-owned factor `Var`s keyed by their save-key
/// suffix (e.g. `("lora_A.weight", a)` / `("lokr_w1", w1)`). The same `Var`s are flattened into
/// [`LoraSet::vars`] for the optimizer; here they carry the suffix the checkpoint writer needs.
#[derive(Debug, Clone)]
pub struct AdapterTarget {
    pub path: String,
    factors: Vec<(&'static str, Var)>,
}

/// The result of installing adapters onto a host: the flat `Var` list to optimize, the per-target
/// metadata to save, and the network descriptors echoed into the adapter metadata.
#[derive(Debug, Clone)]
pub struct LoraSet {
    pub kind: AdapterKind,
    pub rank: u32,
    pub alpha: f32,
    /// LoKr block-split factor (`-1` = auto); unused for plain LoRA.
    pub decompose_factor: i32,
    /// Every trainable factor, for the optimizer.
    pub vars: Vec<Var>,
    targets: Vec<AdapterTarget>,
}

impl LoraSet {
    /// `scale = alpha / rank` (the residual multiplier).
    pub fn scale(&self) -> f64 {
        self.alpha as f64 / self.rank.max(1) as f64
    }

    /// Number of adapted projections.
    pub fn len(&self) -> usize {
        self.targets.len()
    }

    pub fn is_empty(&self) -> bool {
        self.targets.is_empty()
    }

    /// Stable, fully-qualified trainable surface used by resume snapshots. The names are the same
    /// bare PEFT keys written to the final adapter.
    pub fn named_vars(&self) -> Vec<(String, Var)> {
        self.targets
            .iter()
            .flat_map(|target| {
                target
                    .factors
                    .iter()
                    .map(move |(suffix, var)| (format!("{}.{}", target.path, suffix), var.clone()))
            })
            .collect()
    }

    /// Restore trainable factors from a resume tensor map, rejecting any missing, extra, or
    /// shape-incompatible key so a changed target-module config cannot resume an inert surface.
    pub fn restore_named(&self, saved: &HashMap<String, Tensor>) -> Result<()> {
        let named = self.named_vars();
        let expected: std::collections::HashSet<&str> =
            named.iter().map(|(name, _)| name.as_str()).collect();
        let actual: std::collections::HashSet<&str> = saved.keys().map(String::as_str).collect();
        if expected != actual {
            let missing: Vec<_> = expected.difference(&actual).copied().collect();
            let extra: Vec<_> = actual.difference(&expected).copied().collect();
            return Err(CandleError::Msg(format!(
                "resume: adapter target surface differs (missing={missing:?}, extra={extra:?})"
            )));
        }
        for (name, var) in named {
            let value = &saved[&name];
            if value.dims() != var.dims() {
                return Err(CandleError::Msg(format!(
                    "resume: factor {name:?} shape {:?} does not match {:?}",
                    value.dims(),
                    var.dims()
                )));
            }
            var.set(&value.to_dtype(var.dtype())?.to_device(var.device())?)?;
        }
        Ok(())
    }
}

/// PEFT suffix match: `suffix` matches a module `path` iff the path equals it or ends with `.{suffix}`
/// (so `to_q` matches `…attn1.to_q` but not `…attn1.to_qx`, and `to_out.0` matches `…attn1.to_out.0`).
fn path_matches(path: &str, suffix: &str) -> bool {
    path == suffix || path.ends_with(&format!(".{suffix}"))
}

/// LyCORIS dimension factorization: split `dimension` into `(a, b)` with `a·b == dimension` and
/// `a ≤ b`. `factor > 0` requests a block size (the pair containing `factor`, smaller-first); `-1`
/// (auto) picks the most balanced divisor pair. Faithful port of the MLX/LyCORIS `factorization`.
pub fn factorization(dimension: usize, factor: i32) -> (usize, usize) {
    if factor > 0 {
        let f = factor as usize;
        if dimension.is_multiple_of(f) {
            let n = dimension / f;
            return if f > n { (n, f) } else { (f, n) };
        }
    }
    // auto (or a `factor` that doesn't divide): climb to the most balanced divisor pair, bounded by
    // `factor` (= dimension when auto).
    let cap = if factor < 0 {
        dimension
    } else {
        factor as usize
    };
    let (mut m, mut n) = (1usize, dimension);
    let mut length = m + n;
    while m < n {
        let mut new_m = m + 1;
        while !dimension.is_multiple_of(new_m) {
            new_m += 1;
        }
        let new_n = dimension / new_m;
        if new_m + new_n > length || new_m > cap {
            break;
        }
        m = new_m;
        n = new_n;
        length = m + n;
    }
    if m > n {
        (n, m)
    } else {
        (m, n)
    }
}

/// Deterministic, launch-portable factor init: draw `rows·cols` `N(0, std²)` values from a seeded CPU
/// `StdRng` (NOT candle's device RNG — same reasoning as the sc-3673 initial-noise path), build the
/// tensor on CPU, and move it to `device`. Returned as a trainable f32 `Var`.
fn gaussian_var(
    rows: usize,
    cols: usize,
    std: f32,
    rng: &mut StdRng,
    device: &Device,
) -> Result<Var> {
    // Draw the raw unit-normal sequence via the shared primitive (identical draw order/salt), then
    // scale each sample by `std` — `N(0, std²)`.
    let data: Vec<f32> = crate::seeded_normal_vec(rng, rows * cols)
        .into_iter()
        .map(|z| std * z)
        .collect();
    let t = Tensor::from_vec(data, (rows, cols), &Device::Cpu)?.to_device(device)?;
    Ok(Var::from_tensor(&t)?)
}

fn zero_var(rows: usize, cols: usize, device: &Device) -> Result<Var> {
    Ok(Var::from_tensor(&Tensor::zeros(
        (rows, cols),
        DType::F32,
        device,
    )?)?)
}

/// Deterministic kaiming-uniform factor init matching `torch.nn.init.kaiming_uniform_(a=√5)`:
/// `U(±1/√fan_in)` with `fan_in = cols` (gain `√(2/(1+5)) = 1/√3`, bound `√3·gain/√fan_in = 1/√fan_in`).
/// Same seeded-CPU-`StdRng` portability as [`gaussian_var`] (sc-5179, the LoKr second-factor init).
fn kaiming_uniform_var(rows: usize, cols: usize, rng: &mut StdRng, device: &Device) -> Result<Var> {
    let bound = 1.0f32 / (cols as f32).sqrt();
    // `bound > 0` always (cols ≥ 1), so the range is well-formed; `new_inclusive` only errs on an
    // empty/NaN range.
    let dist = Uniform::new_inclusive(-bound, bound).expect("valid kaiming-uniform bounds");
    let data: Vec<f32> = (0..rows * cols).map(|_| dist.sample(rng)).collect();
    let t = Tensor::from_vec(data, (rows, cols), &Device::Cpu)?.to_device(device)?;
    Ok(Var::from_tensor(&t)?)
}

/// Install LoRA adapters on `host` for every adaptable projection whose path matches one of
/// `target_suffixes`. `A ~ N(0, 0.02²)` `[rank, in]`, `B = 0` `[out, rank]` (identity at step 0).
/// Factors are f32 on `device`; init is seeded by `seed` for reproducibility.
pub fn build_lora_targets(
    host: &mut dyn LoraHost,
    target_suffixes: &[String],
    rank: u32,
    alpha: f32,
    seed: u64,
    device: &Device,
) -> Result<LoraSet> {
    if rank == 0 {
        return Err(CandleError::Msg("lora rank must be >= 1".into()));
    }
    let r = rank as usize;
    let scale = alpha as f64 / r as f64;
    let mut rng = StdRng::seed_from_u64(seed);
    let mut vars: Vec<Var> = Vec::new();
    let mut targets: Vec<AdapterTarget> = Vec::new();

    host.visit_lora_mut(&mut |lin: &mut LoraLinear| {
        if !target_suffixes.iter().any(|s| path_matches(lin.path(), s)) {
            return Ok(());
        }
        let (in_f, out_f) = (lin.in_features(), lin.out_features());
        let down = gaussian_var(r, in_f, INIT_STD, &mut rng, device)?; // A [rank, in]
        let up = zero_var(out_f, r, device)?; // B [out, rank]
        lin.install_lora(down.as_tensor().clone(), up.as_tensor().clone(), scale);
        vars.push(down.clone());
        vars.push(up.clone());
        targets.push(AdapterTarget {
            path: lin.path().to_string(),
            factors: vec![("lora_A.weight", down), ("lora_B.weight", up)],
        });
        Ok(())
    })?;

    if targets.is_empty() {
        return Err(CandleError::Msg(format!(
            "no LoRA targets matched suffixes {target_suffixes:?} on the host"
        )));
    }
    Ok(LoraSet {
        kind: AdapterKind::Lora,
        rank,
        alpha,
        decompose_factor: -1,
        vars,
        targets,
    })
}

/// Install LoKr adapters on `host` for every matching projection, matching **PEFT
/// `LoKrConfig(init_weights=True)`'s `reset_adapter_parameters`** (sc-5179) so a Python LoKr learning
/// rate transfers. The weight `[out,in]` factors as `kron(w1[out_a,in_a], w2[out_b,in_b])`; `w2` is
/// low-ranked to `rank` when `rank < max(out_b,in_b)/2` (PEFT's `use_w2`). The **first** factor `w1` is
/// **zero-init**; the **second** factor `w2` (full, or both `w2_a`/`w2_b` low-rank) is **kaiming-uniform
/// `a=√5`** ⇒ `U(±1/√fan_in)`. The zeroed factor is `w1`, so the initial delta `kron(0, w2)·scale = 0`.
/// `decompose_factor` (`-1` = auto) is the block-split knob. Mirrors the MLX `build_lokr_targets`
/// (sc-5179); the residual is reconstructed at f32 (SDXL path). NOTE: replaced the prior `w1 ~ N(0,0.02)`
/// / zeroed-`w2` init (opposite zeroed factor + a fixed ~4-5× smaller scale), which forced a ~10× higher,
/// non-transferable LoKr lr; the save/round-trip format is unchanged so prior adapters still load.
pub fn build_lokr_targets(
    host: &mut dyn LoraHost,
    target_suffixes: &[String],
    rank: u32,
    alpha: f32,
    decompose_factor: i32,
    seed: u64,
    device: &Device,
) -> Result<LoraSet> {
    if rank == 0 {
        return Err(CandleError::Msg("lokr rank must be >= 1".into()));
    }
    let r = rank as usize;
    let scale = alpha as f64 / r as f64;
    let mut rng = StdRng::seed_from_u64(seed);
    let mut vars: Vec<Var> = Vec::new();
    let mut targets: Vec<AdapterTarget> = Vec::new();

    host.visit_lora_mut(&mut |lin: &mut LoraLinear| {
        if !target_suffixes.iter().any(|s| path_matches(lin.path(), s)) {
            return Ok(());
        }
        let (in_f, out_f) = (lin.in_features(), lin.out_features());
        let (out_a, out_b) = factorization(out_f, decompose_factor);
        let (in_a, in_b) = factorization(in_f, decompose_factor);

        // w1 = zeros [out_a, in_a] — the zeroed factor, so the initial delta is exactly 0 (PEFT).
        let w1 = zero_var(out_a, in_a, device)?;
        vars.push(w1.clone());
        let mut factors: Vec<(&'static str, Var)> = vec![("lokr_w1", w1.clone())];

        // PEFT `use_w2 = not(r < max(out_b,in_b)/2)`: low-rank w2 = w2_a @ w2_b only below half the
        // larger factor dim, else a full w2. Both factors are kaiming-init (the delta is held at 0 by w1).
        let runtime_w2 = if (r as f32) < (out_b.max(in_b) as f32) / 2.0 {
            let w2a = kaiming_uniform_var(out_b, r, &mut rng, device)?; // fan_in = r
            let w2b = kaiming_uniform_var(r, in_b, &mut rng, device)?; // fan_in = in_b
            vars.push(w2a.clone());
            vars.push(w2b.clone());
            factors.push(("lokr_w2_a", w2a.clone()));
            factors.push(("lokr_w2_b", w2b.clone()));
            LokrW2::LowRank {
                a: w2a.as_tensor().clone(),
                b: w2b.as_tensor().clone(),
            }
        } else {
            let w2 = kaiming_uniform_var(out_b, in_b, &mut rng, device)?; // fan_in = in_b
            vars.push(w2.clone());
            factors.push(("lokr_w2", w2.clone()));
            LokrW2::Full(w2.as_tensor().clone())
        };
        lin.install_lokr(w1.as_tensor().clone(), runtime_w2, scale);
        targets.push(AdapterTarget {
            path: lin.path().to_string(),
            factors,
        });
        Ok(())
    })?;

    if targets.is_empty() {
        return Err(CandleError::Msg(format!(
            "no LoKr targets matched suffixes {target_suffixes:?} on the host"
        )));
    }
    Ok(LoraSet {
        kind: AdapterKind::Lokr,
        rank,
        alpha,
        decompose_factor,
        vars,
        targets,
    })
}

/// Reconstruct the LoRA weight delta `ΔW = (alpha/rank)·scale·(B·A)` as an `[out, in]` **f32** tensor
/// — the inference-side **merge** counterpart to [`LoraLinear`]'s training **forward**, which adds the
/// mathematically-identical residual `scale·(x·Aᵀ)·Bᵀ` with the install `scale = alpha/rank`. `down`
/// is `A` `[rank, in]`, `up` is `B` `[out, rank]`; `scale` is the caller's per-adapter strength
/// (`gen_core::AdapterSpec::scale`, `1.0` reconstructs the trained delta verbatim). Computed in f32 so
/// a candle-trained adapter round-trips through inference exactly.
///
/// SDXL merges this into the dense UNet weight (`W += ΔW`) rather than adding it live: the ancestral
/// sampler is chaos-sensitive and the merged forward `(W+ΔW)·x` differs from the residual form
/// `W·x + ΔW·x` by ~1 ULP, which cascades to a visibly different image (see `candle-gen-sdxl`'s
/// adapter merge). Holding both forms to the same f32 reconstruction keeps train and infer in lockstep.
/// Install trainable LoRA factors on an [`AdaptLoraHost`]. The saved factor convention is identical
/// to [`build_lora_targets`]; only the host projection type differs.
pub fn build_adapt_lora_targets(
    host: &mut dyn AdaptLoraHost,
    target_suffixes: &[String],
    rank: u32,
    alpha: f32,
    seed: u64,
    device: &Device,
) -> Result<LoraSet> {
    if rank == 0 {
        return Err(CandleError::Msg("lora rank must be >= 1".into()));
    }
    let r = rank as usize;
    let scale = alpha as f64 / r as f64;
    let mut rng = StdRng::seed_from_u64(seed);
    let mut vars = Vec::new();
    let mut targets = Vec::new();
    host.visit_adapt_lora_mut(&mut |path, lin| {
        if !target_suffixes.is_empty()
            && !target_suffixes
                .iter()
                .any(|suffix| path_matches(path, suffix))
        {
            return Ok(());
        }
        let (out_f, in_f) = lin.base_shape();
        let down = gaussian_var(r, in_f, INIT_STD, &mut rng, device)?;
        let up = zero_var(out_f, r, device)?;
        lin.push_trainable_lora(down.as_tensor().clone(), up.as_tensor().clone(), scale);
        vars.push(down.clone());
        vars.push(up.clone());
        targets.push(AdapterTarget {
            path: path.to_string(),
            factors: vec![("lora_A.weight", down), ("lora_B.weight", up)],
        });
        Ok(())
    })?;
    if targets.is_empty() {
        return Err(CandleError::Msg(format!(
            "no LoRA targets matched suffixes {target_suffixes:?} on the host"
        )));
    }
    Ok(LoraSet {
        kind: AdapterKind::Lora,
        rank,
        alpha,
        decompose_factor: -1,
        vars,
        targets,
    })
}

/// Install trainable full-factor LoKr residuals on an [`AdaptLoraHost`]. Keeping `w2` full avoids
/// caching a stale eager `w2_a·w2_b` product between optimizer steps while preserving the standard
/// LyCORIS `w1`/`w2` checkpoint format consumed by inference mergers.
pub fn build_adapt_lokr_targets(
    host: &mut dyn AdaptLoraHost,
    target_suffixes: &[String],
    rank: u32,
    alpha: f32,
    decompose_factor: i32,
    seed: u64,
    device: &Device,
) -> Result<LoraSet> {
    if rank == 0 {
        return Err(CandleError::Msg("lokr rank must be >= 1".into()));
    }
    let scale = alpha as f64 / rank as f64;
    let mut rng = StdRng::seed_from_u64(seed);
    let mut vars = Vec::new();
    let mut targets = Vec::new();
    host.visit_adapt_lora_mut(&mut |path, lin| {
        if !target_suffixes.is_empty()
            && !target_suffixes
                .iter()
                .any(|suffix| path_matches(path, suffix))
        {
            return Ok(());
        }
        let (out_f, in_f) = lin.base_shape();
        let (out_a, out_b) = factorization(out_f, decompose_factor);
        let (in_a, in_b) = factorization(in_f, decompose_factor);
        let w1 = zero_var(out_a, in_a, device)?;
        let w2 = kaiming_uniform_var(out_b, in_b, &mut rng, device)?;
        lin.push_trainable_lokr(w1.as_tensor().clone(), w2.as_tensor().clone(), scale);
        vars.push(w1.clone());
        vars.push(w2.clone());
        targets.push(AdapterTarget {
            path: path.to_string(),
            factors: vec![("lokr_w1", w1), ("lokr_w2", w2)],
        });
        Ok(())
    })?;
    if targets.is_empty() {
        return Err(CandleError::Msg(format!(
            "no LoKr targets matched suffixes {target_suffixes:?} on the host"
        )));
    }
    Ok(LoraSet {
        kind: AdapterKind::Lokr,
        rank,
        alpha,
        decompose_factor,
        vars,
        targets,
    })
}

pub fn reconstruct_lora_delta(
    down: &Tensor,
    up: &Tensor,
    alpha: f32,
    rank: f32,
    scale: f32,
) -> Result<Tensor> {
    let down = down.to_dtype(DType::F32)?;
    let up = up.to_dtype(DType::F32)?;
    let ba = up.matmul(&down)?; // [out, rank] · [rank, in] → [out, in]
    let eff = (alpha as f64 / rank as f64) * scale as f64;
    Ok((ba * eff)?)
}

/// Parse PEFT LoKr `rank`/`alpha` metadata without collapsing a present malformed value to a default.
/// Missing rank defaults to 1 and missing alpha defaults to rank; present values must match the same
/// finite, positive-rank contract enforced by [`reconstruct_lokr_delta`].
pub fn parse_lokr_metadata(rank: Option<&str>, alpha: Option<&str>) -> Result<(f32, f32)> {
    let parse = |field: &str, raw: &str| {
        raw.trim().parse::<f32>().map_err(|_| {
            CandleError::Msg(format!(
                "LoKr adapter metadata `{field}` = `{raw}` is not a valid number"
            ))
        })
    };
    let rank = match rank {
        Some(raw) => parse("rank", raw)?,
        None => 1.0,
    };
    let alpha = match alpha {
        Some(raw) => parse("alpha", raw)?,
        None => rank,
    };
    if !rank.is_finite() || rank <= 0.0 || !alpha.is_finite() {
        return Err(CandleError::Msg(format!(
            "LoKr: invalid metadata scale (rank = {rank}, alpha = {alpha}); rank must be finite and \
             > 0 and alpha must be finite"
        )));
    }
    Ok((rank, alpha))
}

/// Reconstruct the LoKr weight delta `ΔW = (alpha/rank)·scale·kron(w1, w2)` reshaped to `base_shape`
/// (`[out, in]`), as **f32** — the inference-side merge counterpart to [`LoraLinear`]'s LoKr forward,
/// using the *same* `kron2d` reconstruction. Each Kronecker leg is either a full factor (`w1`/`w2`)
/// or a low-rank product (`w1_a·w1_b` / `w2_a·w2_b`, e.g. the trainer's zero-init `w2_a`/`w2_b` form).
/// Errors if a leg is missing or if metadata/user scaling is invalid. Linear-only: pass 2-D factors
/// (the SDXL trainer adapts Linears; Tucker / conv reconstruction is not handled here).
#[allow(clippy::too_many_arguments)]
pub fn reconstruct_lokr_delta(
    w1: Option<&Tensor>,
    w1_a: Option<&Tensor>,
    w1_b: Option<&Tensor>,
    w2: Option<&Tensor>,
    w2_a: Option<&Tensor>,
    w2_b: Option<&Tensor>,
    alpha: f32,
    rank: f32,
    scale: f32,
    base_shape: (usize, usize),
) -> Result<Tensor> {
    if !scale.is_finite() {
        return Err(CandleError::Msg(format!(
            "LoKr: adapter scale must be finite (got {scale})"
        )));
    }
    if !rank.is_finite() || rank <= 0.0 || !alpha.is_finite() {
        return Err(CandleError::Msg(format!(
            "LoKr: invalid metadata scale (rank = {rank}, alpha = {alpha}); rank must be finite and \
             > 0 and alpha must be finite"
        )));
    }
    let eff = (alpha as f64 / rank as f64) * scale as f64;
    if !eff.is_finite() {
        return Err(CandleError::Msg(format!(
            "LoKr: derived (alpha/rank) * adapter scale must be finite (got {eff})"
        )));
    }
    let f32d = |t: &Tensor| t.to_dtype(DType::F32);
    let factor1 = match (w1, w1_a, w1_b) {
        (Some(w), _, _) => f32d(w)?,
        (_, Some(a), Some(b)) => f32d(a)?.matmul(&f32d(b)?)?,
        _ => {
            return Err(CandleError::Msg(
                "lokr: w1 missing (need full lokr_w1 or lokr_w1_a·lokr_w1_b)".into(),
            ))
        }
    };
    let factor2 = match (w2, w2_a, w2_b) {
        (Some(w), _, _) => f32d(w)?,
        (_, Some(a), Some(b)) => f32d(a)?.matmul(&f32d(b)?)?,
        _ => {
            return Err(CandleError::Msg(
                "lokr: w2 missing (need full lokr_w2 or lokr_w2_a·lokr_w2_b)".into(),
            ))
        }
    };
    let (out_f, in_f) = base_shape;
    let delta = kron2d(&factor1, &factor2)?.reshape((out_f, in_f))?;
    Ok((delta * eff)?)
}

/// Fuse a **conv-layer** LoRA pair into a single conv-weight delta in the trained-file **NCHW**
/// `[out, in, kH, kW]` layout (sc-5225) — the conv analog of [`reconstruct_lora_delta`]. Community SDXL
/// LoRAs adapt convs (resnet `conv1`/`conv2`/`conv_shortcut`, the down/up-samplers, `conv_in`/`conv_out`)
/// by decomposing a conv into a spatial `down` (`lora_down`, `[rank, in, kH, kW]`) followed by a 1×1
/// `up` (`lora_up`, `[out, rank, 1, 1]`); the fused weight is the composition of those two convs:
///   `δ[o, i, y, x] = Σ_r up[o, r] · down[r, i, y, x]`,
/// which is exactly `up[out, rank] · down[rank, in·kH·kW]` reshaped back to `[out, in, kH, kW]` —
/// bit-identical to PEFT/diffusers' `Conv2d` LoRA fusion, uniform across 1×1 and k×k kernels — then
/// scaled by `(alpha/rank)·scale`. Computed in **f32** (the candle SDXL merge path is f32-everywhere,
/// matching [`reconstruct_lora_delta`]); the caller folds it into the conv weight (`W += δ`).
///
/// Unlike mlx-gen's `conv_lora_delta` (which returns NCHW and transposes to NHWC at the merge site,
/// because mlx stores conv weights NHWC), candle convs are already NCHW (`candle_nn::Conv2d`), so the
/// returned delta merges into the diffusers `{path}.weight` tensor with no transpose. A non-4-D factor
/// (a malformed conv LoRA) is a typed error rather than a panic on the kernel-dim reshape.
pub fn conv_lora_delta(
    down: &Tensor,
    up: &Tensor,
    alpha: f32,
    rank: f32,
    scale: f32,
) -> Result<Tensor> {
    let (ds, us) = (down.dims(), up.dims());
    if ds.len() != 4 || us.len() != 4 {
        return Err(CandleError::Msg(format!(
            "conv LoRA: expected 4-D factors (down [rank,in,kH,kW], up [out,rank,1,1]), got down \
             {ds:?} up {us:?}"
        )));
    }
    if us[1] != ds[0] {
        return Err(CandleError::Msg(format!(
            "conv LoRA: rank mismatch between factors — down[0]={} but up[1]={} (down {ds:?} up {us:?})",
            ds[0], us[1]
        )));
    }
    let (r, cin, kh, kw) = (ds[0], ds[1], ds[2], ds[3]);
    let out = us[0];
    let down2 = down.to_dtype(DType::F32)?.reshape((r, cin * kh * kw))?; // [rank, in·kH·kW]
    let up2 = up.to_dtype(DType::F32)?.reshape((out, r))?; // [out, rank]
    let ba = up2.matmul(&down2)?; // [out, in·kH·kW]
    let eff = (alpha as f64 / rank as f64) * scale as f64;
    Ok((ba * eff)?.reshape((out, cin, kh, kw))?)
}

/// Reconstruct a **LoHa** (LyCORIS Hadamard-product) weight delta `ΔW = scale · ((w1_a·w1_b) ⊙
/// (w2_a·w2_b))` as an `[out, in]` **f32** tensor (sc-5225). Third-party LoHa decomposes a delta as the
/// elementwise product of TWO low-rank products (vs LoKr's Kronecker). `w1_a`/`w2_a` are `[out, rank]`,
/// `w1_b`/`w2_b` are `[rank, in]`; `scale` is the fully-effective multiplier (the lycoris `alpha/rank`
/// times the caller's per-adapter strength). Mirrors LyCORIS `LohaModule.get_weight` / `HadaWeight`
/// (`w1d=hada_w1_b, w1u=hada_w1_a`, so the product is `(hada_w1_a·hada_w1_b) ⊙ (hada_w2_a·hada_w2_b)`).
///
/// **Linear-only**: pass 2-D factors. The conv/tucker LoHa form (lycoris `use_cp`, `hada_t1`/`hada_t2`)
/// is out of the candle SDXL adapter surface — like third-party LoKr, LoHa merges only into the
/// attention/proj Linears (the conv surface is LoRA-only), so a conv-shaped LoHa is surfaced as skipped.
pub fn reconstruct_loha_delta(
    w1_a: &Tensor,
    w1_b: &Tensor,
    w2_a: &Tensor,
    w2_b: &Tensor,
    scale: f32,
    base_shape: (usize, usize),
) -> Result<Tensor> {
    let f32d = |t: &Tensor| t.to_dtype(DType::F32);
    let m1 = f32d(w1_a)?.matmul(&f32d(w1_b)?)?; // [out, rank]·[rank, in] → [out, in]
    let m2 = f32d(w2_a)?.matmul(&f32d(w2_b)?)?;
    let (out_f, in_f) = base_shape;
    let delta = (m1 * m2)?.reshape((out_f, in_f))?;
    Ok((delta * scale as f64)?)
}

/// Parsed view of the PEFT / diffusers `lora_adapter_metadata` config blob (sc-5374).
///
/// `peft.save_pretrained()` and diffusers `save_lora_adapter` do NOT write a per-target `.alpha`
/// tensor (the kohya / candle-trainer convention the merge reads first). They store the LoRA scaling
/// inside the safetensors header `__metadata__["lora_adapter_metadata"]` — a JSON blob carrying
/// `lora_alpha`, `r`, and the optional per-module `alpha_pattern` / `rank_pattern` overrides. With no
/// `.alpha` tensor the inference merge would otherwise fall back to `alpha = rank` (scale 1.0) and
/// apply such a file at the WRONG strength whenever `lora_alpha ≠ r` (the common `alpha = 2r` / `r/2` /
/// fixed-16 cases). Parsing this blob lets the merge recover the true `(alpha/rank)` scaling.
///
/// Scope is the **LoRA** path: LoKr carries its `rank`/`alpha` as top-level `__metadata__` strings the
/// LoKr merge already reads, so it is unaffected. The candle trainer's own PEFT output writes a
/// per-target `.alpha` tensor (and top-level `rank`/`alpha`, not this blob), so its round-trip is also
/// unaffected — this is purely external/community adapter coverage (same flavor as sc-5225).
#[derive(Debug, Default, Clone)]
pub struct LoraAdapterMeta {
    lora_alpha: Option<f32>,
    r: Option<f32>,
    alpha_pattern: BTreeMap<String, f32>,
    rank_pattern: BTreeMap<String, f32>,
}

impl LoraAdapterMeta {
    /// Parse the `lora_adapter_metadata` JSON blob out of a safetensors `__metadata__` map. Returns
    /// `None` when the blob is absent (kohya / candle-trainer files, which carry a per-target `.alpha`
    /// tensor instead) or unparseable — treated as absent so a malformed blob can never poison the
    /// merge (the caller then keeps today's `alpha = rank` default).
    pub fn from_file_metadata(meta: &HashMap<String, String>) -> Option<Self> {
        let blob = meta.get("lora_adapter_metadata")?;
        let v: serde_json::Value = serde_json::from_str(blob).ok()?;
        let num = |x: &serde_json::Value| x.as_f64().map(|f| f as f32);
        // A `{module: number}` JSON object → `BTreeMap`, skipping any non-numeric entry.
        let pattern = |x: Option<&serde_json::Value>| -> BTreeMap<String, f32> {
            x.and_then(|v| v.as_object())
                .map(|o| {
                    o.iter()
                        .filter_map(|(k, val)| val.as_f64().map(|f| (k.clone(), f as f32)))
                        .collect()
                })
                .unwrap_or_default()
        };
        Some(Self {
            lora_alpha: v.get("lora_alpha").and_then(num),
            r: v.get("r").and_then(num),
            alpha_pattern: pattern(v.get("alpha_pattern")),
            rank_pattern: pattern(v.get("rank_pattern")),
        })
    }

    /// PEFT per-module override resolution. A single `target_name_key` is the first pattern key (across
    /// `rank_pattern` ∪ `alpha_pattern`) that equals `module_path` or that `module_path` ends with as
    /// `.{key}` — PEFT's `re.match(r".*\.{key}$")` in `LoraModel._create_and_replace`. Deterministic on
    /// overlap (`BTreeMap` key order). `None` ⇒ no per-module override, use the globals.
    fn target_name_key(&self, module_path: &str) -> Option<&str> {
        self.rank_pattern
            .keys()
            .chain(self.alpha_pattern.keys())
            .map(String::as_str)
            .find(|&k| module_path == k || module_path.ends_with(&format!(".{k}")))
    }

    /// The effective `(alpha, rank)` for `module_path`: `alpha_pattern[key] → lora_alpha` and
    /// `rank_pattern[key] → r`, each `None` when unset. The caller uses `alpha` (falling back to the
    /// factor rank) as the numerator; `rank` is honored as the scaling denominator (a well-formed PEFT
    /// file stores `A` as `[r, in]`, so the factor's leading dim already equals this — the metadata
    /// value is used for faithfulness and as the source of truth PEFT itself scales by).
    pub fn effective(&self, module_path: &str) -> (Option<f32>, Option<f32>) {
        let key = self.target_name_key(module_path);
        let alpha = key
            .and_then(|k| self.alpha_pattern.get(k))
            .copied()
            .or(self.lora_alpha);
        let rank = key
            .and_then(|k| self.rank_pattern.get(k))
            .copied()
            .or(self.r);
        (alpha, rank)
    }
}

/// Collect a target's factor tensors as CPU/f32 `(key, tensor)` save entries under `prefix`.
fn factor_entries(set: &LoraSet, prefix: &str) -> Result<Vec<(String, Tensor)>> {
    let mut out = Vec::with_capacity(set.targets.len() * 3);
    for t in &set.targets {
        for (suffix, var) in &t.factors {
            let v = var
                .as_tensor()
                .to_device(&Device::Cpu)?
                .to_dtype(DType::F32)?
                .contiguous()?;
            out.push((format!("{prefix}{}.{suffix}", t.path), v));
        }
    }
    Ok(out)
}

fn write_safetensors(
    tensors: Vec<(String, Tensor)>,
    meta: HashMap<String, String>,
    path: &Path,
) -> Result<()> {
    safetensors::serialize_to_file(tensors, Some(meta), path)
        .map_err(|e| CandleError::Msg(format!("save adapter {}: {e}", path.display())))?;
    Ok(())
}

/// Write a LoRA [`LoraSet`] as a PEFT-format `.safetensors`: keys `{prefix}{path}.lora_A.weight`
/// (`[rank, in]`), `{prefix}{path}.lora_B.weight` (`[out, rank]`), and a per-target scalar
/// `{prefix}{path}.alpha`, plus `networkType`/`rank`/`alpha` metadata (the candle save path that
/// candle-core's own `save` cannot produce — it passes `None` for metadata). `prefix` is
/// [`SDXL_PEFT_PREFIX`] for SDXL, `""` for the DiT families. Matches the MLX `save_lora_peft`.
pub fn save_lora_peft(
    set: &LoraSet,
    prefix: &str,
    extra_meta: &HashMap<String, String>,
    path: &Path,
) -> Result<()> {
    if set.kind != AdapterKind::Lora {
        return Err(CandleError::Msg(
            "save_lora_peft called on a non-LoRA set".into(),
        ));
    }
    let mut tensors = factor_entries(set, prefix)?;
    // Per-target scalar `.alpha` (PEFT reload contract).
    for t in &set.targets {
        tensors.push((
            format!("{prefix}{}.alpha", t.path),
            Tensor::from_vec(vec![set.alpha], (1,), &Device::Cpu)?,
        ));
    }
    let mut meta: HashMap<String, String> = HashMap::new();
    meta.insert("networkType".into(), set.kind.network_type().into());
    meta.insert("rank".into(), set.rank.to_string());
    meta.insert("alpha".into(), set.alpha.to_string());
    for (k, v) in extra_meta {
        meta.entry(k.clone()).or_insert_with(|| v.clone());
    }
    write_safetensors(tensors, meta, path)
}

/// Write a LoKr [`LoraSet`] as `.safetensors`: bare keys `{path}.lokr_w1` + (`lokr_w2` |
/// `lokr_w2_a`/`lokr_w2_b`), with `networkType`/`rank`/`alpha`/`decomposeFactor` metadata. No key
/// prefix (the SDXL LoKr loader accepts a `base_model.model.unet.` prefix but bare keys resolve for
/// every family). Matches the MLX `save_lokr` (integer rank/alpha rendering).
pub fn save_lokr(set: &LoraSet, extra_meta: &HashMap<String, String>, path: &Path) -> Result<()> {
    if set.kind != AdapterKind::Lokr {
        return Err(CandleError::Msg(
            "save_lokr called on a non-LoKr set".into(),
        ));
    }
    let tensors = factor_entries(set, "")?;
    let mut meta: HashMap<String, String> = HashMap::new();
    meta.insert("networkType".into(), set.kind.network_type().into());
    meta.insert("rank".into(), (set.rank as i64).to_string());
    meta.insert("alpha".into(), (set.alpha as i64).to_string());
    meta.insert("decomposeFactor".into(), set.decompose_factor.to_string());
    for (k, v) in extra_meta {
        meta.entry(k.clone()).or_insert_with(|| v.clone());
    }
    write_safetensors(tensors, meta, path)
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::quant::DenseLinear;
    use crate::train::optim::TrainOptimizer;
    use candle_core::IndexOp;
    use gen_core::Quant;

    fn fixed_linear(weight: &[f32], out_f: usize, in_f: usize) -> LoraLinear {
        let w = Tensor::from_vec(weight.to_vec(), (out_f, in_f), &Device::Cpu).unwrap();
        LoraLinear::from_linear(Linear::new(w, None), in_f, out_f, "test.to_q".into())
    }

    struct OneAdaptHost {
        lin: AdaptLinear,
    }

    impl AdaptLoraHost for OneAdaptHost {
        fn visit_adapt_lora_mut(
            &mut self,
            f: &mut dyn FnMut(&str, &mut AdaptLinear) -> Result<()>,
        ) -> Result<()> {
            f("block.to_q", &mut self.lin)
        }
    }

    /// Standard LoRA initialization has B=0: the first loss must still build a graph to B, then an
    /// optimizer update to B must make the next loss reach A. This pins the distinction between the
    /// inference residual fast path and the trainable `AdaptLinear` residual seam.
    #[test]
    fn adapt_linear_zero_init_lora_trains_across_optimizer_steps() {
        let device = Device::Cpu;
        let base = Linear::new(Tensor::zeros((3, 4), DType::F32, &device).unwrap(), None);
        let mut host = OneAdaptHost {
            lin: AdaptLinear::from_dense(base, 4, 3),
        };
        let set =
            build_adapt_lora_targets(&mut host, &["to_q".to_string()], 2, 2.0, 7, &device).unwrap();
        let x = Tensor::from_vec(
            vec![1.0f32, -2.0, 0.5, 3.0, -1.0, 0.25, 2.0, 1.5],
            (2, 4),
            &device,
        )
        .unwrap();
        let target = Tensor::ones((2, 3), DType::F32, &device).unwrap();

        let loss1 = (host.lin.forward(&x).unwrap() - &target)
            .unwrap()
            .sqr()
            .unwrap()
            .mean_all()
            .unwrap();
        let grads1 = loss1.backward().unwrap();
        let up_grad = grads1
            .get(set.vars[1].as_tensor())
            .expect("zero-initialized B must receive the first-step gradient");
        assert!(
            up_grad
                .abs()
                .unwrap()
                .max_all()
                .unwrap()
                .to_scalar::<f32>()
                .unwrap()
                > 0.0
        );

        let mut optimizer =
            TrainOptimizer::from_config("adam", set.vars.clone(), 0.05, 0.0).unwrap();
        optimizer.step(&grads1).unwrap();
        assert!(
            set.vars[1]
                .as_tensor()
                .abs()
                .unwrap()
                .max_all()
                .unwrap()
                .to_scalar::<f32>()
                .unwrap()
                > 0.0,
            "the optimizer must move B off zero"
        );

        let loss2 = (host.lin.forward(&x).unwrap() - target)
            .unwrap()
            .sqr()
            .unwrap()
            .mean_all()
            .unwrap();
        let grads2 = loss2.backward().unwrap();
        let down_grad = grads2
            .get(set.vars[0].as_tensor())
            .expect("A must receive a gradient once B is nonzero");
        assert!(
            down_grad
                .abs()
                .unwrap()
                .max_all()
                .unwrap()
                .to_scalar::<f32>()
                .unwrap()
                > 0.0
        );
    }

    fn deterministic_lora_weight(out_f: usize, in_f: usize) -> Tensor {
        let values: Vec<f32> = (0..out_f * in_f)
            .map(|i| ((i % 17) as f32 - 8.0) / 16.0)
            .collect();
        Tensor::from_vec(values, (out_f, in_f), &Device::Cpu).unwrap()
    }

    fn deterministic_lora_input(rows: usize, in_f: usize, dtype: DType) -> Tensor {
        let values: Vec<f32> = (0..rows * in_f)
            .map(|i| ((i % 11) as f32 + 1.0) / 8.0)
            .collect();
        Tensor::from_vec(values, (rows, in_f), &Device::Cpu)
            .unwrap()
            .to_dtype(dtype)
            .unwrap()
    }

    fn int8_fast_lora(quant: Quant, out_f: usize, in_f: usize) -> LoraLinear {
        let mut base = QLinear::from_dense(DenseLinear::Linear(Linear::new(
            deterministic_lora_weight(out_f, in_f),
            None,
        )));
        base.quantize_int8_fast(quant, false, false, false).unwrap();
        LoraLinear::from_qlinear(base, in_f, out_f, "test.to_q".into())
    }

    fn exact_lora_values(t: &Tensor) -> Vec<Vec<f32>> {
        t.to_dtype(DType::F32).unwrap().to_vec2::<f32>().unwrap()
    }

    fn assert_lora_tensor_exact(actual: &Tensor, expected: &Tensor, context: &str) {
        assert_eq!(actual.dtype(), expected.dtype(), "{context}: dtype differs");
        assert_eq!(
            exact_lora_values(actual),
            exact_lora_values(expected),
            "{context}: element values differ"
        );
    }

    /// sc-15444 bypass audit: `LoraLinear` is the only Candle adapter host that hand-rolls the
    /// residual addition instead of delegating to `AdaptLinear`. Both its trainable and inference
    /// additive LoRA arms must skip a zero-strength residual without evaluating poisoned factors.
    #[test]
    fn lora_linear_scale_zero_skips_trainable_and_additive_residuals_exactly() {
        let (out_f, in_f, rank) = (16usize, 32usize, 2usize);
        let x = deterministic_lora_input(2, in_f, DType::F32);
        let base = LoraLinear::from_linear(
            Linear::new(deterministic_lora_weight(out_f, in_f), None),
            in_f,
            out_f,
            "test.to_q".into(),
        );
        let expected = base.forward(&x).unwrap();

        let poison_down =
            Tensor::from_vec(vec![f32::INFINITY; rank * in_f], (rank, in_f), &Device::Cpu).unwrap();
        let poison_up = Tensor::ones((out_f, rank), DType::F32, &Device::Cpu).unwrap();
        let mut trainable = LoraLinear::from_linear(
            Linear::new(deterministic_lora_weight(out_f, in_f), None),
            in_f,
            out_f,
            "test.to_q".into(),
        );
        trainable.install_lora(poison_down, poison_up, 0.0);
        assert_lora_tensor_exact(
            &trainable.forward(&x).unwrap(),
            &expected,
            "trainable scale=0",
        );

        let poison_a =
            Tensor::from_vec(vec![f32::INFINITY; in_f * rank], (in_f, rank), &Device::Cpu).unwrap();
        let poison_b = Tensor::ones((rank, out_f), DType::F32, &Device::Cpu).unwrap();
        let mut additive = LoraLinear::from_linear(
            Linear::new(deterministic_lora_weight(out_f, in_f), None),
            in_f,
            out_f,
            "test.to_q".into(),
        );
        additive.push_additive_lora(poison_a, poison_b, 0.0);
        assert_lora_tensor_exact(
            &additive.forward(&x).unwrap(),
            &expected,
            "additive scale=0",
        );

        let poison_w1 = Tensor::from_vec(vec![f32::INFINITY; 4 * 4], (4, 4), &Device::Cpu).unwrap();
        let poison_w2 = Tensor::ones((4, 8), DType::F32, &Device::Cpu).unwrap();
        let mut trainable_lokr = LoraLinear::from_linear(
            Linear::new(deterministic_lora_weight(out_f, in_f), None),
            in_f,
            out_f,
            "test.to_q".into(),
        );
        trainable_lokr.install_lokr(poison_w1.clone(), LokrW2::Full(poison_w2.clone()), 0.0);
        assert_lora_tensor_exact(
            &trainable_lokr.forward(&x).unwrap(),
            &expected,
            "trainable LoKr scale=0",
        );

        let factors = LokrFactors::build(
            0.0,
            (out_f, in_f),
            Some(&poison_w1),
            None,
            None,
            Some(&poison_w2),
            None,
            None,
            None,
        )
        .unwrap()
        .unwrap();
        let mut additive_lokr = LoraLinear::from_linear(
            Linear::new(deterministic_lora_weight(out_f, in_f), None),
            in_f,
            out_f,
            "test.to_q".into(),
        );
        additive_lokr.push_additive_lokr(factors);
        assert_lora_tensor_exact(
            &additive_lokr.forward(&x).unwrap(),
            &expected,
            "additive structured LoKr scale=0",
        );
    }

    /// sc-15444 bypass audit: the SDXL `LoraLinear` path must follow its quantized host's f32 output
    /// dtype rather than the activation dtype when adding either residual form. f64 is the CPU-executable
    /// proxy for production bf16 input because Candle CPU has no bf16 matmul.
    #[test]
    fn lora_linear_quantized_hosts_cast_live_residuals_to_output_dtype_exactly() {
        let (out_f, in_f, rank) = (32usize, 32usize, 2usize);
        let x = deterministic_lora_input(2, in_f, DType::F64);
        let down = Tensor::ones((rank, in_f), DType::F32, &Device::Cpu).unwrap();
        let up = Tensor::ones((out_f, rank), DType::F32, &Device::Cpu).unwrap();
        let a = down.t().unwrap().contiguous().unwrap();
        let b = up.t().unwrap().contiguous().unwrap();
        let residual = ((x
            .broadcast_matmul(&a.to_dtype(DType::F64).unwrap())
            .unwrap()
            .broadcast_matmul(&b.to_dtype(DType::F64).unwrap())
            .unwrap())
            * 0.5)
            .unwrap()
            .to_dtype(DType::F32)
            .unwrap();

        for quant in [Quant::Q8, Quant::Q4] {
            let bare = int8_fast_lora(quant, out_f, in_f);
            let base_y = bare.forward(&x).unwrap();
            assert_eq!(base_y.dtype(), DType::F32);
            let expected = (&base_y + &residual).unwrap();

            let mut trainable = int8_fast_lora(quant, out_f, in_f);
            trainable.install_lora(down.clone(), up.clone(), 0.5);
            assert_lora_tensor_exact(
                &trainable.forward(&x).unwrap(),
                &expected,
                "quantized trainable live adapter",
            );

            let mut additive = int8_fast_lora(quant, out_f, in_f);
            additive.push_additive_lora(a.clone(), b.clone(), 0.5);
            assert_lora_tensor_exact(
                &additive.forward(&x).unwrap(),
                &expected,
                "quantized additive live adapter",
            );
        }
    }

    // ---- packed base (sc-9416) ---------------------------------------------------------------

    /// Build a real MLX Q4 packed triple for an `[out, in]` weight (group 64), same construction as the
    /// `quant` module's fixtures: LSB-first nibble packing + per-group affine scales/biases.
    fn q4_packed_triple(out_f: usize, in_f: usize) -> (Tensor, Tensor, Tensor) {
        let dev = Device::Cpu;
        let gs = crate::quant::MLX_GROUP_SIZE;
        let codes: Vec<u8> = (0..out_f * in_f)
            .map(|i| ((i * 7 + i / 13) % 16) as u8)
            .collect();
        let words: Vec<u32> = codes
            .chunks_exact(8)
            .map(|c| {
                c.iter()
                    .enumerate()
                    .fold(0u32, |acc, (i, &q)| acc | ((q as u32 & 0xF) << (4 * i)))
            })
            .collect();
        let groups = out_f * in_f / gs;
        let scales: Vec<f32> = (0..groups).map(|g| 0.0625 * (g as f32 + 1.0)).collect();
        let biases: Vec<f32> = (0..groups).map(|g| -0.5 - 0.25 * g as f32).collect();
        let gpr = in_f / gs;
        (
            Tensor::from_vec(words, (out_f, in_f / 8), &dev).unwrap(),
            Tensor::from_vec(scales, (out_f, gpr), &dev).unwrap(),
            Tensor::from_vec(biases, (out_f, gpr), &dev).unwrap(),
        )
    }

    /// A `LoraLinear` wrapping a **packed** `QLinear` base (sc-9416) reports `is_packed()`, and with no
    /// adapter its forward is exactly the packed base's — the inference path a packed SDXL tier takes.
    #[test]
    fn packed_base_forwards_as_qlinear() {
        let dev = Device::Cpu;
        let (out_f, in_f) = (64usize, 128usize);
        let (wq, s, b) = q4_packed_triple(out_f, in_f);
        let q = QLinear::from_packed(&wq, &s, &b, None, &dev).unwrap();
        let ll = LoraLinear::from_qlinear(q.clone(), in_f, out_f, "attn2.to_out.0".into());
        assert!(ll.is_packed());
        assert!(!ll.is_adapted());

        let x = Tensor::randn(0f32, 1f32, (4, in_f), &dev).unwrap();
        let a = ll.forward(&x).unwrap();
        let bff = q.forward(&x).unwrap();
        let dmax = (a - bff)
            .unwrap()
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        assert_eq!(
            dmax, 0.0,
            "packed LoraLinear base must equal its QLinear forward"
        );
    }

    /// A dense base reports `!is_packed()` (the training default) — the byte-identical pre-sc-9416 path.
    #[test]
    fn dense_base_is_not_packed() {
        let ll = fixed_linear(&[1.0; 8], 2, 4);
        assert!(!ll.is_packed());
    }

    /// sc-11103: a forward-time **additive** LoRA residual on a **packed** `LoraLinear` base shifts the
    /// output by exactly `scale·((x·a)·b)` (isolated by cancelling the bit-identical packed base), keeps
    /// the base **packed** (no dense weight materialized — the packed footprint survives), and a scale-0
    /// residual is an exact no-op. This is the SDXL packed-tier distill-LoRA path's core property — the
    /// additive residual is added *over* the packed weight, never folded into a re-quantized dense one.
    #[test]
    fn additive_lora_on_packed_base_adds_exact_residual_and_scale0_noop() {
        let dev = Device::Cpu;
        let (out_f, in_f, rank) = (64usize, 128usize, 4usize);
        let (wq, s, b) = q4_packed_triple(out_f, in_f);
        let q = QLinear::from_packed(&wq, &s, &b, None, &dev).unwrap();
        // Two bit-identical packed bases: one bare (reference), one adapted.
        let base = LoraLinear::from_qlinear(q.clone(), in_f, out_f, "attn1.to_q".into());
        let mut adapted = LoraLinear::from_qlinear(q, in_f, out_f, "attn1.to_q".into());
        let a = (Tensor::randn(0f32, 1f32, (in_f, rank), &dev).unwrap() * 0.1).unwrap();
        let bfac = (Tensor::randn(0f32, 1f32, (rank, out_f), &dev).unwrap() * 0.1).unwrap();
        let scale = 0.7f64;
        adapted.push_additive_lora(a.clone(), bfac.clone(), scale);
        assert!(
            adapted.is_packed(),
            "the additive residual must not un-pack the base"
        );
        assert!(adapted.has_additive());
        assert!(
            !adapted.is_adapted(),
            "additive is not the trainable adapter"
        );

        let x = Tensor::randn(0f32, 1f32, (4usize, in_f), &dev).unwrap();
        // adapted − base cancels the identical packed base (quant error included) → the pure residual.
        let residual_actual = (adapted.forward(&x).unwrap() - base.forward(&x).unwrap()).unwrap();
        let residual_expected = ((x.matmul(&a).unwrap().matmul(&bfac).unwrap()) * scale).unwrap();
        let dmax = (residual_actual - residual_expected)
            .unwrap()
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        // 1e-4, not 1e-5: this synthetic packed grid is large-magnitude, so `(base + residual) − base`
        // loses a few ULPs to f32 cancellation. The residual itself is exact; the bound guards its value.
        assert!(
            dmax < 1e-4,
            "packed additive residual != scale·(x·a)·b ({dmax})"
        );

        // scale 0 ⇒ exact no-op vs the un-adapted packed base.
        let (wq, s, b) = q4_packed_triple(out_f, in_f);
        let q2 = QLinear::from_packed(&wq, &s, &b, None, &dev).unwrap();
        let mut zero = LoraLinear::from_qlinear(q2, in_f, out_f, "attn1.to_q".into());
        zero.push_additive_lora(a, bfac, 0.0);
        let zero_dev = (zero.forward(&x).unwrap() - base.forward(&x).unwrap())
            .unwrap()
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        assert_eq!(
            zero_dev, 0.0,
            "a scale-0 additive residual must be an exact no-op"
        );
    }

    /// sc-11103: the additive residual `scale·((x·a)·b)` reproduces the **folded** `x·(W + δ)ᵀ` with
    /// `δ = (alpha/rank)·scale·(up·down)` on a **dense** base — the additive == folded identity (tight in
    /// f32). This is the acceptance parity the packed path relies on: pushing the residual equals what the
    /// dense tier folds, so a distill LoRA renders the same on q4/q8 (up to the base's own quant error).
    #[test]
    fn additive_lora_matches_dense_fold() {
        let dev = Device::Cpu;
        let (out_f, in_f, rank) = (48usize, 64usize, 4usize);
        let w = Tensor::randn(0f32, 1f32, (out_f, in_f), &dev).unwrap();
        let down = Tensor::randn(0f32, 1f32, (rank, in_f), &dev).unwrap(); // A [rank, in]
        let up = Tensor::randn(0f32, 1f32, (out_f, rank), &dev).unwrap(); // B [out, rank]
        let (alpha, user_scale) = (8.0f64, 0.7f64);
        let ratio = alpha / rank as f64;
        // a = downᵀ [in, rank]; b = (upᵀ·ratio) [rank, out] — the resolver's factor convention.
        let a = down.t().unwrap().contiguous().unwrap();
        let b = (up.t().unwrap().contiguous().unwrap() * ratio).unwrap();
        let mut lin =
            LoraLinear::from_linear(Linear::new(w.clone(), None), in_f, out_f, "p".into());
        lin.push_additive_lora(a, b, user_scale);

        // Folded reference: δ = ratio·user_scale·(up·down); W_merged = W + δ.
        let delta = ((up.matmul(&down).unwrap()) * (ratio * user_scale)).unwrap();
        let folded = Linear::new((w + delta).unwrap(), None);
        let x = Tensor::randn(0f32, 1f32, (3usize, in_f), &dev).unwrap();
        let dmax = (lin.forward(&x).unwrap() - folded.forward(&x).unwrap())
            .unwrap()
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        assert!(dmax < 1e-4, "additive vs folded deviates by {dmax}");
    }

    /// A trainable residual is legal over an immutable packed base: the packed weights remain frozen
    /// and only the independent f32 factors participate in autograd (the LTX q4 trainer path).
    #[test]
    fn install_lora_on_packed_base_applies_residual() {
        let dev = Device::Cpu;
        let (out_f, in_f) = (64usize, 128usize);
        let (wq, s, b) = q4_packed_triple(out_f, in_f);
        let q = QLinear::from_packed(&wq, &s, &b, None, &dev).unwrap();
        let mut ll = LoraLinear::from_qlinear(q, in_f, out_f, "attn2.to_out.0".into());
        let down = Tensor::ones((4, in_f), DType::F32, &dev).unwrap();
        let up = Tensor::ones((out_f, 4), DType::F32, &dev).unwrap();
        ll.install_lora(down, up, 1.0);
        let x = Tensor::ones((1, in_f), DType::F32, &dev).unwrap();
        assert!(ll.forward(&x).is_ok());
    }

    /// Backprop through a later packed projection must reach an adapter installed on an earlier
    /// packed projection. This is the minimal two-block analogue of the LTX DiT: the second frozen
    /// q4 base needs an input gradient even though none of its own packed weights are trainable.
    #[test]
    fn sequential_packed_bases_backprop_to_early_lora() {
        let dev = Device::Cpu;
        let width = 64usize;
        let (first_w, first_s, first_b) = q4_packed_triple(width, width);
        let (second_w, second_s, second_b) = q4_packed_triple(width, width);
        let first_q = QLinear::from_packed(&first_w, &first_s, &first_b, None, &dev).unwrap();
        let second_q = QLinear::from_packed(&second_w, &second_s, &second_b, None, &dev).unwrap();
        let mut first = LoraLinear::from_qlinear(first_q, width, width, "blocks.0.to_q".into());
        let second = LoraLinear::from_qlinear(second_q, width, width, "blocks.1.to_q".into());

        let down = Var::from_tensor(
            &(Tensor::randn(0f32, 1f32, (4, width), &dev).unwrap() * 0.01).unwrap(),
        )
        .unwrap();
        let up = Var::from_tensor(
            &(Tensor::randn(0f32, 1f32, (width, 4), &dev).unwrap() * 0.01).unwrap(),
        )
        .unwrap();
        first.install_lora(down.as_tensor().clone(), up.as_tensor().clone(), 1.0);

        let input = Tensor::randn(0f32, 1f32, (2, width), &dev).unwrap();
        let loss = second
            .forward(&first.forward(&input).unwrap())
            .unwrap()
            .sqr()
            .unwrap()
            .mean_all()
            .unwrap();
        let grads = loss.backward().unwrap();
        for (name, factor) in [("down", &down), ("up", &up)] {
            let max = grads
                .get(factor.as_tensor())
                .unwrap_or_else(|| panic!("missing gradient for early {name} factor"))
                .abs()
                .unwrap()
                .max_all()
                .unwrap()
                .to_scalar::<f32>()
                .unwrap();
            assert!(
                max.is_finite() && max > 0.0,
                "early {name} gradient through later packed base was {max}"
            );
        }
    }

    /// `lora_linear_detect` / `lora_linear_no_bias_detect` route to the packed base when the `.scales`
    /// sibling is present in the VarBuilder, and to the dense base otherwise — the one-call packed-detect
    /// contract used by the vendored SDXL attention. Uses an in-memory safetensors (no weights needed).
    #[test]
    fn lora_linear_detect_packed_vs_dense() {
        use candle_core::safetensors::MmapedSafetensors;
        let dev = Device::Cpu;
        let (out_f, in_f) = (64usize, 128usize);
        let (wq, s, b) = q4_packed_triple(out_f, in_f);
        // A packed `to_out.0` triple + a dense `to_q.weight` (bias-free) sibling in one file.
        let mut map: std::collections::HashMap<String, Tensor> = std::collections::HashMap::new();
        map.insert("to_out.0.weight".into(), wq);
        map.insert("to_out.0.scales".into(), s);
        map.insert("to_out.0.biases".into(), b);
        map.insert(
            "to_out.0.bias".into(),
            Tensor::zeros((out_f,), DType::F32, &dev).unwrap(),
        );
        map.insert(
            "to_q.weight".into(),
            Tensor::randn(0f32, 1f32, (out_f, in_f), &dev).unwrap(),
        );
        let tmp_guard = tempfile::tempdir().unwrap();
        let tmp = tmp_guard.path().join("sc9416_lora_detect.safetensors");
        candle_core::safetensors::save(&map, &tmp).unwrap();
        // SAFETY: we just wrote this file and nothing else touches it during the test.
        let st = unsafe { MmapedSafetensors::new(&tmp).unwrap() };
        let vb = VarBuilder::from_backend(Box::new(st), DType::F32, dev.clone());

        let gs = crate::quant::MLX_GROUP_SIZE;
        let packed = lora_linear_detect(in_f, out_f, &vb, "to_out.0", gs).unwrap();
        assert!(packed.is_packed(), "`.scales` present ⇒ packed base");
        let dense = lora_linear_no_bias_detect(in_f, out_f, &vb, "to_q", gs).unwrap();
        assert!(!dense.is_packed(), "no `.scales` ⇒ dense base");
        // The PEFT path is captured for both (the LoraHost visitor routes adapters by it).
        assert_eq!(packed.path(), "to_out.0");
        assert_eq!(dense.path(), "to_q");
    }

    #[test]
    fn no_adapter_is_base_linear() {
        let lin = fixed_linear(&[1.0, 0.0, 0.0, 1.0], 2, 2);
        let x = Tensor::from_vec(vec![3.0f32, 5.0], (1, 2), &Device::Cpu).unwrap();
        let y = lin
            .forward(&x)
            .unwrap()
            .i(0)
            .unwrap()
            .to_vec1::<f32>()
            .unwrap();
        assert_eq!(y, vec![3.0, 5.0]);
    }

    #[test]
    fn zero_b_residual_is_identity() {
        let mut lin = fixed_linear(&[1.0, 0.0, 0.0, 1.0], 2, 2);
        let down = Tensor::from_vec(vec![0.5f32, -0.3, 0.1, 0.2], (2, 2), &Device::Cpu).unwrap();
        let up = Tensor::zeros((2, 2), DType::F32, &Device::Cpu).unwrap();
        lin.install_lora(down, up, 1.0);
        let x = Tensor::from_vec(vec![3.0f32, 5.0], (1, 2), &Device::Cpu).unwrap();
        let y = lin
            .forward(&x)
            .unwrap()
            .i(0)
            .unwrap()
            .to_vec1::<f32>()
            .unwrap();
        assert_eq!(y, vec![3.0, 5.0]);
    }

    #[test]
    fn lora_residual_math() {
        let mut lin = fixed_linear(&[0.0, 0.0, 0.0, 0.0], 2, 2);
        let down = Tensor::from_vec(vec![1.0f32, 0.0, 0.0, 1.0], (2, 2), &Device::Cpu).unwrap();
        let up = Tensor::from_vec(vec![1.0f32, 0.0, 0.0, 1.0], (2, 2), &Device::Cpu).unwrap();
        lin.install_lora(down, up, 2.0);
        let x = Tensor::from_vec(vec![3.0f32, 5.0], (1, 2), &Device::Cpu).unwrap();
        let y = lin
            .forward(&x)
            .unwrap()
            .i(0)
            .unwrap()
            .to_vec1::<f32>()
            .unwrap();
        assert_eq!(y, vec![6.0, 10.0]);
    }

    #[test]
    fn backward_reaches_factors() {
        let w = Tensor::zeros((2, 2), DType::F32, &Device::Cpu).unwrap();
        let mut lin = LoraLinear::from_linear(Linear::new(w, None), 2, 2, "t".into());
        let down = Var::from_tensor(
            &Tensor::from_vec(vec![0.1f32, 0.2, 0.3, 0.4], (2, 2), &Device::Cpu).unwrap(),
        )
        .unwrap();
        let up = Var::from_tensor(
            &Tensor::from_vec(vec![0.5f32, 0.6, 0.7, 0.8], (2, 2), &Device::Cpu).unwrap(),
        )
        .unwrap();
        lin.install_lora(down.as_tensor().clone(), up.as_tensor().clone(), 1.0);
        let x = Tensor::from_vec(vec![1.0f32, 2.0], (1, 2), &Device::Cpu).unwrap();
        let loss = lin.forward(&x).unwrap().sqr().unwrap().sum_all().unwrap();
        let grads = loss.backward().unwrap();
        assert!(
            grads.get(down.as_tensor()).is_some(),
            "A factor must receive a gradient"
        );
        assert!(
            grads.get(up.as_tensor()).is_some(),
            "B factor must receive a gradient"
        );
    }

    #[test]
    fn optimizer_update_seen_without_reinstall() {
        let w = Tensor::zeros((1, 1), DType::F32, &Device::Cpu).unwrap();
        let mut lin = LoraLinear::from_linear(Linear::new(w, None), 1, 1, "t".into());
        let down = Var::from_tensor(&Tensor::from_vec(vec![1.0f32], (1, 1), &Device::Cpu).unwrap())
            .unwrap();
        let up = Var::from_tensor(&Tensor::from_vec(vec![1.0f32], (1, 1), &Device::Cpu).unwrap())
            .unwrap();
        lin.install_lora(down.as_tensor().clone(), up.as_tensor().clone(), 1.0);
        let x = Tensor::from_vec(vec![2.0f32], (1, 1), &Device::Cpu).unwrap();
        let y0 = lin
            .forward(&x)
            .unwrap()
            .i(0)
            .unwrap()
            .to_vec1::<f32>()
            .unwrap()[0];
        assert_eq!(y0, 2.0);
        up.set(&Tensor::from_vec(vec![3.0f32], (1, 1), &Device::Cpu).unwrap())
            .unwrap();
        let y1 = lin
            .forward(&x)
            .unwrap()
            .i(0)
            .unwrap()
            .to_vec1::<f32>()
            .unwrap()[0];
        assert_eq!(y1, 6.0);
    }

    #[test]
    fn kron2d_matches_reference() {
        let a = Tensor::from_vec(vec![1.0f32, 2.0, 3.0, 4.0], (2, 2), &Device::Cpu).unwrap();
        let b = Tensor::from_vec(vec![0.0f32, 5.0, 6.0, 7.0], (2, 2), &Device::Cpu).unwrap();
        let k = kron2d(&a, &b).unwrap().to_vec2::<f32>().unwrap();
        assert_eq!(
            k,
            vec![
                vec![0.0, 5.0, 0.0, 10.0],
                vec![6.0, 7.0, 12.0, 14.0],
                vec![0.0, 15.0, 0.0, 20.0],
                vec![18.0, 21.0, 24.0, 28.0],
            ]
        );
    }

    /// A zero second Kronecker leg ⇒ zero delta ⇒ the LoKr adapter is the identity over the base at
    /// init (the property training relies on), same as LoRA's `B = 0`.
    #[test]
    fn lokr_zero_init_is_identity() {
        let mut lin = fixed_linear(&[1.0, 0.0, 0.0, 1.0], 2, 2);
        let w1 = Tensor::from_vec(vec![0.3f32, -0.1, 0.2, 0.4], (2, 2), &Device::Cpu).unwrap();
        let w2 = Tensor::zeros((1, 1), DType::F32, &Device::Cpu).unwrap();
        lin.install_lokr(w1, LokrW2::Full(w2), 1.0);
        let x = Tensor::from_vec(vec![3.0f32, 5.0], (1, 2), &Device::Cpu).unwrap();
        let y = lin
            .forward(&x)
            .unwrap()
            .i(0)
            .unwrap()
            .to_vec1::<f32>()
            .unwrap();
        assert_eq!(y, vec![3.0, 5.0]);
    }

    /// sc-5179 — the native LoKr init must match PEFT `LoKrConfig(init_weights=True)`'s
    /// `reset_adapter_parameters` (w1 zero-init, w2 kaiming-uniform `a=√5`), mirroring the MLX
    /// `build_lokr_init_matches_peft_reset_adapter_parameters`, so a Python LoKr lr transfers.
    #[test]
    fn build_lokr_init_matches_peft_reset_adapter_parameters() {
        struct OneHost(LoraLinear);
        impl LoraHost for OneHost {
            fn visit_lora_mut(
                &mut self,
                f: &mut dyn FnMut(&mut LoraLinear) -> Result<()>,
            ) -> Result<()> {
                f(&mut self.0)
            }
        }
        // out=64 → fac(-1)=(8,8); in=48 → (6,8). out_b = in_b = 8. rank 3 < max(8,8)/2 = 4 → low-rank.
        let w = Tensor::zeros((64, 48), DType::F32, &Device::Cpu).unwrap();
        let lin = LoraLinear::from_linear(Linear::new(w, None), 48, 64, "w".into());
        let mut host = OneHost(lin);
        let set =
            build_lokr_targets(&mut host, &["w".to_string()], 3, 3.0, -1, 7, &Device::Cpu).unwrap();
        assert_eq!(set.targets.len(), 1);
        let factors = &set.targets[0].factors;
        let get = |name: &str| {
            factors
                .iter()
                .find(|(k, _)| *k == name)
                .map(|(_, v)| v.as_tensor().clone())
        };
        let maxabs = |t: &Tensor| {
            t.abs()
                .unwrap()
                .max_all()
                .unwrap()
                .to_scalar::<f32>()
                .unwrap()
        };

        // w1 is the ZEROED factor (PEFT), shape [out_a=8, in_a=6].
        let w1 = get("lokr_w1").expect("lokr_w1");
        assert_eq!(w1.dims(), &[8, 6]);
        assert_eq!(
            maxabs(&w1),
            0.0,
            "w1 must be zero-init (PEFT), not N(0,0.02)"
        );

        // w2 is low-rank kaiming: no full w2; w2_a [8,3] bound 1/√3, w2_b [3,8] bound 1/√8.
        assert!(
            get("lokr_w2").is_none(),
            "rank 3 < max(8,8)/2 → low-rank w2"
        );
        let w2a = get("lokr_w2_a").expect("lokr_w2_a");
        let w2b = get("lokr_w2_b").expect("lokr_w2_b");
        let bound_a = 1.0f32 / 3f32.sqrt(); // ≈ 0.577
        let bound_b = 1.0f32 / 8f32.sqrt(); // ≈ 0.354
        assert!(
            maxabs(&w2a) <= bound_a + 1e-6 && maxabs(&w2a) > bound_a * 0.3,
            "w2_a must be kaiming U(±1/√rank): max {} vs bound {bound_a}",
            maxabs(&w2a)
        );
        assert!(
            maxabs(&w2b) <= bound_b + 1e-6 && maxabs(&w2b) > bound_b * 0.3,
            "w2_b must be kaiming U(±1/√in_b): max {} vs bound {bound_b}",
            maxabs(&w2b)
        );
    }

    /// LoKr residual on a 1×1 base: out=in=1 factor as (1,1)⊗(1,1); ΔW = scale·(w1·w2). base 0,
    /// w1=2, w2=3, scale=1, x=5 ⇒ y = 5·(2·3) = 30.
    #[test]
    fn lokr_residual_math() {
        let mut lin = fixed_linear(&[0.0], 1, 1);
        let w1 = Tensor::from_vec(vec![2.0f32], (1, 1), &Device::Cpu).unwrap();
        let w2 = Tensor::from_vec(vec![3.0f32], (1, 1), &Device::Cpu).unwrap();
        lin.install_lokr(w1, LokrW2::Full(w2), 1.0);
        let x = Tensor::from_vec(vec![5.0f32], (1, 1), &Device::Cpu).unwrap();
        let y = lin
            .forward(&x)
            .unwrap()
            .i(0)
            .unwrap()
            .to_vec1::<f32>()
            .unwrap()[0];
        assert_eq!(y, 30.0);
    }

    /// The train→infer round-trip guarantee for LoRA: the weight delta the inference loader merges
    /// ([`reconstruct_lora_delta`]) must equal the residual the training forward adds. With base `W`,
    /// `forward(x) - W·x` is the residual; reconstructing the delta and applying `x·ΔWᵀ` must match —
    /// proving the merged-weight forward `(W+ΔW)·x` reproduces the trained adapter.
    #[test]
    fn reconstruct_lora_delta_matches_forward_residual() {
        let w = Tensor::from_vec(
            vec![0.5f32, -0.2, 0.1, 0.3, -0.4, 0.6],
            (2, 3),
            &Device::Cpu,
        )
        .unwrap(); // base [out=2, in=3]
        let down = Tensor::from_vec(
            vec![0.1f32, 0.2, -0.3, 0.4, 0.5, -0.6],
            (2, 3),
            &Device::Cpu,
        )
        .unwrap(); // A [rank=2, in=3]
        let up = Tensor::from_vec(vec![0.7f32, -0.8, 0.9, 1.0], (2, 2), &Device::Cpu).unwrap(); // B [out=2, rank=2]
        let (alpha, rank) = (4.0f32, 2.0f32); // train scale = alpha/rank = 2.0
        let mut lin = LoraLinear::from_linear(Linear::new(w.clone(), None), 3, 2, "t".into());
        lin.install_lora(down.clone(), up.clone(), (alpha / rank) as f64);

        let x = Tensor::from_vec(vec![1.0f32, -2.0, 3.0], (1, 3), &Device::Cpu).unwrap();
        let residual = (lin.forward(&x).unwrap() - x.matmul(&w.t().unwrap()).unwrap()).unwrap();
        // scale 1.0 ⇒ ΔW = (alpha/rank)·B·A, the exact delta the forward applies.
        let delta = reconstruct_lora_delta(&down, &up, alpha, rank, 1.0).unwrap();
        let from_delta = x.matmul(&delta.t().unwrap()).unwrap();
        let diff = (residual - from_delta)
            .unwrap()
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        assert!(
            diff < 1e-5,
            "reconstruct_lora_delta diverged from forward residual: {diff}"
        );
    }

    /// The train→infer round-trip guarantee for LoKr: [`reconstruct_lokr_delta`] must equal the
    /// residual the LoKr forward adds. 2×2 base factored `1×1 ⊗ 2×2`.
    #[test]
    fn reconstruct_lokr_delta_matches_forward_residual() {
        let w = Tensor::from_vec(vec![0.1f32, 0.2, 0.3, 0.4], (2, 2), &Device::Cpu).unwrap();
        let w1 = Tensor::from_vec(vec![2.0f32], (1, 1), &Device::Cpu).unwrap(); // [out_a=1, in_a=1]
        let w2 = Tensor::from_vec(vec![0.5f32, -0.3, 0.2, 0.6], (2, 2), &Device::Cpu).unwrap(); // [out_b=2, in_b=2]
        let (alpha, rank) = (3.0f32, 1.0f32); // train scale = alpha/rank = 3.0
        let mut lin = LoraLinear::from_linear(Linear::new(w.clone(), None), 2, 2, "t".into());
        lin.install_lokr(w1.clone(), LokrW2::Full(w2.clone()), (alpha / rank) as f64);

        let x = Tensor::from_vec(vec![1.5f32, -0.5], (1, 2), &Device::Cpu).unwrap();
        let residual = (lin.forward(&x).unwrap() - x.matmul(&w.t().unwrap()).unwrap()).unwrap();
        let delta = reconstruct_lokr_delta(
            Some(&w1),
            None,
            None,
            Some(&w2),
            None,
            None,
            alpha,
            rank,
            1.0,
            (2, 2),
        )
        .unwrap();
        let from_delta = x.matmul(&delta.t().unwrap()).unwrap();
        let diff = (residual - from_delta)
            .unwrap()
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        assert!(
            diff < 1e-5,
            "reconstruct_lokr_delta diverged from forward residual: {diff}"
        );
    }

    #[test]
    fn reconstruct_lokr_delta_rejects_invalid_metadata_and_user_scaling() {
        let w1 = Tensor::ones((1, 1), DType::F32, &Device::Cpu).unwrap();
        let w2 = Tensor::eye(2, DType::F32, &Device::Cpu).unwrap();
        let reconstruct = |alpha, rank, scale| {
            reconstruct_lokr_delta(
                Some(&w1),
                None,
                None,
                Some(&w2),
                None,
                None,
                alpha,
                rank,
                scale,
                (2, 2),
            )
        };

        for scale in [f32::NAN, f32::INFINITY, f32::NEG_INFINITY] {
            let error = reconstruct(1.0, 1.0, scale)
                .expect_err("a non-finite user scale must not produce a dense delta");
            assert!(error.to_string().contains("adapter scale must be finite"));
        }
        for alpha in [f32::NAN, f32::INFINITY, f32::NEG_INFINITY] {
            let error = reconstruct(alpha, 1.0, 1.0)
                .expect_err("a non-finite metadata alpha must not produce a dense delta");
            assert!(error.to_string().contains("invalid metadata scale"));
        }
        for rank in [0.0, -1.0, f32::NAN, f32::INFINITY] {
            let error = reconstruct(1.0, rank, 1.0)
                .expect_err("an invalid metadata rank must not produce a dense delta");
            assert!(error.to_string().contains("invalid metadata scale"));
        }

        for (rank, alpha) in [
            (Some("not-a-number"), None),
            (Some("0"), None),
            (Some("-2"), Some("1")),
            (Some("1"), Some("inf")),
        ] {
            assert!(
                parse_lokr_metadata(rank, alpha).is_err(),
                "present malformed metadata must fail closed: rank={rank:?} alpha={alpha:?}"
            );
        }
        assert_eq!(parse_lokr_metadata(None, None).unwrap(), (1.0, 1.0));
        assert_eq!(
            parse_lokr_metadata(Some("4"), Some("2")).unwrap(),
            (4.0, 2.0)
        );
    }

    /// Low-rank LoKr legs reconstruct via the `a·b` product — the trainer's zero-init `w2_a`/`w2_b`
    /// form (and a community low-rank `w1_a`/`w1_b`). A zero `w2_b` ⇒ zero delta, the init identity.
    #[test]
    fn reconstruct_lokr_delta_low_rank_legs() {
        let w1 = Tensor::from_vec(vec![1.0f32, 2.0, 3.0, 4.0], (2, 2), &Device::Cpu).unwrap();
        let w2a = Tensor::from_vec(vec![0.5f32, 0.7], (2, 1), &Device::Cpu).unwrap(); // [out_b=2, r=1]
        let w2b_zero = Tensor::zeros((1, 2), DType::F32, &Device::Cpu).unwrap(); // [r=1, in_b=2]
        let delta = reconstruct_lokr_delta(
            Some(&w1),
            None,
            None,
            None,
            Some(&w2a),
            Some(&w2b_zero),
            2.0,
            1.0,
            1.0,
            (4, 4),
        )
        .unwrap();
        let max = delta
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        assert_eq!(max, 0.0, "zero w2_b must give a zero LoKr delta");
        // A non-zero w2_b yields the kron product scaled by alpha/rank.
        let w2b = Tensor::from_vec(vec![1.0f32, 0.0], (1, 2), &Device::Cpu).unwrap();
        let delta = reconstruct_lokr_delta(
            Some(&w1),
            None,
            None,
            None,
            Some(&w2a),
            Some(&w2b),
            2.0,
            1.0,
            1.0,
            (4, 4),
        )
        .unwrap();
        assert_eq!(delta.dims(), &[4, 4]);
        let nonzero = delta
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        assert!(nonzero > 0.0, "non-zero w2_b must give a non-zero delta");
    }

    #[test]
    fn factorization_matches_lycoris() {
        assert_eq!(factorization(320, -1), (16, 20));
        assert_eq!(factorization(64, -1), (8, 8));
        // factor>0: the pair containing `factor`, smaller-first (MLX convention).
        assert_eq!(factorization(320, 4), (4, 80));
        assert_eq!(factorization(320, 80), (4, 80));
    }

    #[test]
    fn path_match_rules() {
        assert!(path_matches("a.b.attn1.to_q", "to_q"));
        assert!(path_matches("a.b.attn1.to_out.0", "to_out.0"));
        assert!(!path_matches("a.b.attn1.to_qx", "to_q"));
        assert!(path_matches("to_q", "to_q"));
    }

    #[test]
    fn resume_restore_rejects_changed_factor_surface() {
        let dev = Device::Cpu;
        let a = Var::from_tensor(&Tensor::zeros((2, 3), DType::F32, &dev).unwrap()).unwrap();
        let b = Var::from_tensor(&Tensor::zeros((4, 2), DType::F32, &dev).unwrap()).unwrap();
        let set = LoraSet {
            kind: AdapterKind::Lora,
            rank: 2,
            alpha: 2.0,
            decompose_factor: -1,
            vars: vec![a.clone(), b.clone()],
            targets: vec![AdapterTarget {
                path: "blocks.0.attn1.to_q".into(),
                factors: vec![("lora_A.weight", a), ("lora_B.weight", b)],
            }],
        };
        let mut missing: HashMap<String, Tensor> = set
            .named_vars()
            .into_iter()
            .map(|(name, var)| (name, var.as_tensor().clone()))
            .collect();
        missing.remove("blocks.0.attn1.to_q.lora_B.weight");
        let err = set.restore_named(&missing).unwrap_err().to_string();
        assert!(err.contains("surface differs"), "{err}");

        let mut extra: HashMap<String, Tensor> = set
            .named_vars()
            .into_iter()
            .map(|(name, var)| (name, var.as_tensor().clone()))
            .collect();
        extra.insert(
            "blocks.1.attn2.to_k.lora_A.weight".into(),
            Tensor::zeros((2, 3), DType::F32, &dev).unwrap(),
        );
        let err = set.restore_named(&extra).unwrap_err().to_string();
        assert!(err.contains("surface differs"), "{err}");
    }

    /// sc-5225: a 1×1 conv LoRA (rank 2, in 2, out 2). `down`/`up` are `[*, *, 1, 1]`; the fused delta
    /// is `Σ_r up[o,r]·down[r,i]`, scaled by `alpha/rank`. Hand-computed independently (mirrors mlx):
    ///   down2 = [[1,2],[3,4]] (rank,in); up2 = [[5,6],[7,8]] (out,rank)
    ///   δ[0,0]=5·1+6·3=23  δ[0,1]=5·2+6·4=34  δ[1,0]=7·1+8·3=31  δ[1,1]=7·2+8·4=46
    ///   eff = alpha/rank = 4/2 = 2 → [[46,68],[62,92]].
    #[test]
    fn conv_lora_delta_one_by_one_matches_hand_fold() {
        let dev = Device::Cpu;
        let down = Tensor::from_vec(vec![1.0f32, 2.0, 3.0, 4.0], (2, 2, 1, 1), &dev).unwrap();
        let up = Tensor::from_vec(vec![5.0f32, 6.0, 7.0, 8.0], (2, 2, 1, 1), &dev).unwrap();
        let delta = conv_lora_delta(&down, &up, 4.0, 2.0, 1.0).unwrap();
        assert_eq!(delta.dims(), &[2, 2, 1, 1]);
        let got = delta.flatten_all().unwrap().to_vec1::<f32>().unwrap();
        assert_eq!(got, vec![46.0, 68.0, 62.0, 92.0]);
    }

    /// sc-5225: a k×k (here 2×2) conv LoRA with rank 1 reduces to `δ[o,i,y,x] = up[o]·down[0,i,y,x]` —
    /// proving the spatial kernel is preserved (not collapsed). in=1, out=2.
    ///   down[0,0,:,:] = [[1,2],[3,4]]; up = [10, 20]
    ///   δ[0] = 10·[1,2,3,4] = [10,20,30,40];  δ[1] = 20·[...] = [20,40,60,80].
    /// The user scale composes multiplicatively (scale 0 ⇒ a zero delta ⇒ no-op merge).
    #[test]
    fn conv_lora_delta_kxk_rank1_broadcasts_spatial_kernel() {
        let dev = Device::Cpu;
        let down = Tensor::from_vec(vec![1.0f32, 2.0, 3.0, 4.0], (1, 1, 2, 2), &dev).unwrap();
        let up = Tensor::from_vec(vec![10.0f32, 20.0], (2, 1, 1, 1), &dev).unwrap();
        let delta = conv_lora_delta(&down, &up, 1.0, 1.0, 1.0).unwrap();
        assert_eq!(delta.dims(), &[2, 1, 2, 2]);
        let got = delta.flatten_all().unwrap().to_vec1::<f32>().unwrap();
        assert_eq!(got, vec![10.0, 20.0, 30.0, 40.0, 20.0, 40.0, 60.0, 80.0]);
        let zero = conv_lora_delta(&down, &up, 1.0, 1.0, 0.0).unwrap();
        let zmax = zero
            .abs()
            .unwrap()
            .max_all()
            .unwrap()
            .to_scalar::<f32>()
            .unwrap();
        assert_eq!(zmax, 0.0, "scale 0 must give a zero conv delta");
    }

    /// A malformed conv LoRA with 2-D factors must surface a typed error, not panic on the kernel-dim
    /// reshape; a rank mismatch between the factors is rejected too (mirrors mlx-gen's F-006).
    #[test]
    fn conv_lora_delta_rejects_non_4d_or_mismatched_rank() {
        let dev = Device::Cpu;
        let down2d = Tensor::from_vec(vec![1.0f32, 2.0, 3.0, 4.0], (2, 2), &dev).unwrap();
        let up = Tensor::from_vec(vec![10.0f32, 20.0], (2, 1, 1, 1), &dev).unwrap();
        let err = conv_lora_delta(&down2d, &up, 1.0, 1.0, 1.0)
            .unwrap_err()
            .to_string();
        assert!(err.contains("4-D factors"), "got: {err}");

        let down = Tensor::from_vec(vec![1.0f32, 2.0], (1, 1, 1, 2), &dev).unwrap(); // rank 1
        let up_bad = Tensor::from_vec(vec![1.0f32, 2.0, 3.0, 4.0], (2, 2, 1, 1), &dev).unwrap(); // rank 2
        let err = conv_lora_delta(&down, &up_bad, 1.0, 1.0, 1.0)
            .unwrap_err()
            .to_string();
        assert!(err.contains("rank mismatch"), "got: {err}");
    }

    /// sc-5225: the LoHa delta is `((w1_a·w1_b) ⊙ (w2_a·w2_b))·scale`. Hand-computed on a 2×2 base,
    /// rank 1: w1_a=[1;2], w1_b=[3,4] ⇒ m1=[[3,4],[6,8]]; w2_a=[1;0], w2_b=[5,6] ⇒ m2=[[5,6],[0,0]];
    /// m1⊙m2=[[15,24],[0,0]]; scale 0.5 ⇒ [[7.5,12],[0,0]].
    #[test]
    fn reconstruct_loha_delta_matches_hand_fold() {
        let dev = Device::Cpu;
        let w1a = Tensor::from_vec(vec![1.0f32, 2.0], (2, 1), &dev).unwrap();
        let w1b = Tensor::from_vec(vec![3.0f32, 4.0], (1, 2), &dev).unwrap();
        let w2a = Tensor::from_vec(vec![1.0f32, 0.0], (2, 1), &dev).unwrap();
        let w2b = Tensor::from_vec(vec![5.0f32, 6.0], (1, 2), &dev).unwrap();
        let delta = reconstruct_loha_delta(&w1a, &w1b, &w2a, &w2b, 0.5, (2, 2)).unwrap();
        assert_eq!(delta.dims(), &[2, 2]);
        let got = delta.flatten_all().unwrap().to_vec1::<f32>().unwrap();
        assert_eq!(got, vec![7.5, 12.0, 0.0, 0.0]);
    }

    /// sc-5374: a diffusers / PEFT `lora_adapter_metadata` blob with `lora_alpha ≠ r` parses to the
    /// global pair, so the merge can recover the true `(alpha/rank)` scaling (the example from the
    /// story: `lora_alpha = 16`, `r = 8` ⇒ scale 2.0). The pair applies to any module with no override.
    #[test]
    fn lora_adapter_meta_parses_global_alpha_rank() {
        let meta = HashMap::from([(
            "lora_adapter_metadata".to_string(),
            r#"{"lora_alpha": 16, "r": 8, "target_modules": ["to_q", "to_v"]}"#.to_string(),
        )]);
        let cfg = LoraAdapterMeta::from_file_metadata(&meta).expect("blob must parse");
        assert_eq!(
            cfg.effective("transformer_blocks.0.attn.to_q"),
            (Some(16.0), Some(8.0))
        );
    }

    /// sc-5374: PEFT `alpha_pattern` / `rank_pattern` override the globals for a module whose dotted
    /// path ends with the pattern key (`re.match(r".*\.{key}$")`); a non-matching module keeps the
    /// globals. Mirrors PEFT's single-`target_name_key` resolution.
    #[test]
    fn lora_adapter_meta_honors_per_module_patterns() {
        let meta = HashMap::from([(
            "lora_adapter_metadata".to_string(),
            r#"{"lora_alpha": 8, "r": 8,
                "alpha_pattern": {"to_q": 32},
                "rank_pattern": {"to_q": 16}}"#
                .to_string(),
        )]);
        let cfg = LoraAdapterMeta::from_file_metadata(&meta).unwrap();
        // `…attn.to_q` ends with `.to_q` → the override pair.
        assert_eq!(
            cfg.effective("transformer_blocks.0.attn.to_q"),
            (Some(32.0), Some(16.0))
        );
        // `…attn.to_k` matches no pattern → the globals.
        assert_eq!(
            cfg.effective("transformer_blocks.0.attn.to_k"),
            (Some(8.0), Some(8.0))
        );
    }

    /// sc-5374: an absent blob (kohya / candle-trainer files) and a malformed blob both yield `None`,
    /// so the caller falls back to today's per-target-`.alpha`-or-`rank` behavior rather than erroring.
    #[test]
    fn lora_adapter_meta_absent_or_malformed_is_none() {
        assert!(LoraAdapterMeta::from_file_metadata(&HashMap::new()).is_none());
        let bad = HashMap::from([(
            "lora_adapter_metadata".to_string(),
            "{not valid json".to_string(),
        )]);
        assert!(LoraAdapterMeta::from_file_metadata(&bad).is_none());
    }
}
