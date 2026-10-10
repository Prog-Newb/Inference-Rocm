# `tools/golden/` — real-weights parity goldens

This directory holds the reference tensors (`*.safetensors`) and inspection images (`*.png`) that
the **`#[ignore]`d real-weights parity tests** compare against. **Everything here except this
`README.md` and `CHECKSUMS.txt` is gitignored** — the goldens are large (the 1024² Z-Image txt2img
golden alone is ~15 MB), regenerable from the scripts below, and sensitive to the MLX version
(e.g. the 0.31.1 bump shifted VAE-decode precision), so committing them would bloat history for no
gain. They also can't be produced — or consumed — without the licensed multi-GB HuggingFace
weights and a Mac with Metal, which is exactly why the tests that read them are `#[ignore]`d.

## Fixtures vs. goldens — the convention

| | committed? | runs in default `cargo test`? | needs model weights? |
|---|---|---|---|
| **`tests/fixtures/*.safetensors`** (per crate) | yes | yes | no — synthetic / small dumped intermediates |
| **`tools/golden/*` (here)** | no (gitignored) | no (`#[ignore]`) | yes — real HF weights + Metal |

Default-running tests only depend on committed inputs; anything needing un-committable inputs is
`#[ignore]`d. So a fresh clone's `cargo test` is green without this directory.

## These goldens are single-host. That is the intent, not a gap.

**Read this before treating a missing golden as something to fix.**

On any machine that is not the one a golden was dumped on, the row that reads it fails in **0.00 s**
on `Weights::from_file(GOLDEN)` — before any weights load, any device, any work. On a fresh clone
that is *every* row: this directory ships `README.md` and `CHECKSUMS.txt` and nothing else. As of
this writing that is **118 distinct golden artifacts, referenced by 110 test files across 22
crates** — 119 until sc-17519 promoted `qwen_edit_rope_golden.safetensors` out of this directory and
into `mlx-gen-qwen-image/tests/fixtures/` (see the section on it below).

The "Regenerating" section above says the goldens are regenerable, and in principle they are. In
practice a second party with the licensed weights and a Metal Mac still cannot reproduce one,
because two of the three inputs are named by *location* rather than derivable:

- **the frozen `mflux` fork at `~/repos/mflux`** — a private checkout, not a published artifact, and
  the only place the reference implementation exists;
- **the reference venv at `~/Repos/mflux/.venv-0320`** — python 3.12 + diffusers 0.37.1 +
  transformers 5.10.1 + torch 2.12.0, *plus* MLX 0.32.0 **built from source** at
  `MACOSX_DEPLOYMENT_TARGET=15.0`. There is no lockfile and no build script; the pip wheel is
  explicitly not a valid substitute on M3-class-or-newer hosts.

So the honest statement is the one this section exists to make: **these rows are single-host and are
not currently intended to be reproducible elsewhere.** A missing golden off-host is the expected
state, not an accident and not a gap for a downstream consumer to close.

### What that means if you are gating on real-weight conformance

A consumer running these suites to gate an engine pin (SceneWorks issue #311 was filed by one) must
treat every golden-backed row as **contributing nothing to that gate off-host**. The failure mode is
quiet in the direction that matters: a 0.00 s failure or a skipped row still *looks* like a line of
coverage in the run output, so counting rows overstates what was actually verified. Count only rows
whose inputs you can supply.

### What would change this, and why it has not

Three routes were considered (#311). None is done, and the reason is recorded here so it is not
re-litigated from scratch:

1. **Publish the dumps** — an HF dataset repo, or release assets keyed to the MLX version this
   README already says the goldens are sensitive to. The blocker is that a golden is a derived work
   of licensed multi-GB weights, so republishing it is a licensing question per source model, not an
   infrastructure one.
2. **Publish a reproducible recipe for the reference venv** — a lockfile or an exact build script,
   so `~/Repos/mflux/.venv-0320` becomes derivable. This is the cheapest of the three and the one
   worth doing first, but it is only half a fix while the `mflux` fork itself is unpublished.
3. **Say so explicitly** — this section. It does not add coverage; it stops the absence reading as
   an accident, which is the part that was actively misleading.

Route 3 landing does not close 1 or 2. If you need these rows to execute off-host, they are still
the work.

## Regenerating

> **sc-12896 (MLX 0.32.0): use the version-matched NON-NAX env.** Goldens must be dumped with
> **mlx 0.32.0 built from source at `MACOSX_DEPLOYMENT_TARGET=15.0`** into a venv carrying the
> ORIGINAL reference stack (python 3.12, diffusers 0.37.1, transformers 5.10.1, torch 2.12.0) —
> the canonical one is `~/Repos/mflux/.venv-0320`. The pip wheel is NOT a valid reference on
> M3-class-or-newer hosts for every kernel: 0.32.0 gates NAX kernels on the build's deployment
> target AND gates the affine-quant `qmv_wide` kernel on **GPU generation >= 15** (a hardware gate
> no build flag can flip — see `mlx-gen-mochi/tools/dump_mochi_quant_fixtures.py` for the one
> committed golden this poisons). Also note (sc-12896): 0.32.0 broke cross-stack f32/dense-bf16
> bit-identity between the Python reference and the Rust port (shape-dependent kernel-variant
> selection), so the bit-exact suites now gate with tight measured bounds instead of `== 0.0`
> where the mode demands it — each affected test documents its own contract.

Goldens are produced by running the dump scripts **from the frozen Python `mflux` fork** (which has
the reference implementation), pointed at this repo's `tools/`:

```sh
cd ~/repos/mflux
PYTHONPATH=~/Repos/mflux/src ~/Repos/mflux/.venv-0320/bin/python /path/to/mlx-gen/tools/dump_<name>.py
```

Each script writes into `tools/golden/` next to itself (paths are `__file__`-relative, so this
works from any checkout/worktree). Run the matching `#[ignore]`d test with, e.g.:

```sh
cargo test -p mlx-gen-z-image --release --test e2e_real_weights -- --ignored --nocapture
```

Prerequisites: macOS + Metal; the frozen `mflux` fork at `~/repos/mflux`; the model weights in
`~/.cache/huggingface/hub/` (auto-downloaded by the fork on first run).

## Licensed adapter parity set (`sc-15505`)

The FLUX Hyper, Z-Image LoRA/LoKr, and Qwen LoRA/LoKr gates use the
provenance-locked inventory in `../adapter_parity_artifacts.json`. The manifest records every
gitignored binary's source, license, size, checksum, producing script, and frozen reference
revision. Before the real-weight transcript exists, the verifier deliberately exits nonzero with
`results remain non-proof until transcript is verified`; mutation tests still validate the pending
manifest's structure and pinned scripts:

```sh
python3 -m unittest scripts.tests.test_adapter_parity_artifacts -v
```

On the licensed Metal host used for `sc-15505`, the exact production commands are:

```sh
# Frozen reference checkout and version-matched runtime.
export PYTHONPATH=/Users/michael/Repos/mflux/src
export REF_PY=/Users/michael/Repos/mflux/.venv-0320/bin/python
export REF_HF=/Users/michael/Repos/mflux/.venv-0320/bin/hf
export TOOLS="$PWD/crates/media/mlx-gen/tools"
export HF_MODELS_ROOT="${HF_HOME:-$HOME/.cache/huggingface}/hub"

# Authoritative ByteDance Hyper-FLUX artifact. The dump script also refuses any
# file whose cache repository, ref, revision, filename, or SHA-256 differs.
export HYPER_LORA="$("$REF_HF" download ByteDance/Hyper-SD \
  Hyper-FLUX.1-dev-8steps-lora.safetensors \
  --revision bc08d970a87c74c71209491d64e3525845698863)"

# Reference goldens. Keep the 512² base and adapter configurations identical.
ZIMAGE_REFERENCE_MODEL="$HF_MODELS_ROOT/models--Tongyi-MAI--Z-Image-Turbo/snapshots/f332072aa78be7aecdf3ee76d5c247082da564a6" \
  ZIMAGE_W=512 ZIMAGE_H=512 "$REF_PY" "$TOOLS/dump_z_image_golden.py"
ZIMAGE_REFERENCE_MODEL="$HF_MODELS_ROOT/models--Tongyi-MAI--Z-Image-Turbo/snapshots/f332072aa78be7aecdf3ee76d5c247082da564a6" \
  ZIMAGE_W=512 ZIMAGE_H=512 "$REF_PY" "$TOOLS/dump_z_image_adapter_golden.py"

QWEN_REFERENCE_REPOSITORY=SceneWorks/qwen-image-mlx \
  QWEN_REFERENCE_REVISION=8080a4171f1c8b7fca6c30491eafbe6ffab754bf \
  QWEN_REFERENCE_MODEL="$HF_MODELS_ROOT/models--SceneWorks--qwen-image-mlx/snapshots/8080a4171f1c8b7fca6c30491eafbe6ffab754bf/bf16" \
  QWEN_W=512 QWEN_H=512 "$REF_PY" "$TOOLS/dump_qwen_image_golden.py"
QWEN_REFERENCE_REPOSITORY=SceneWorks/qwen-image-mlx \
  QWEN_REFERENCE_REVISION=8080a4171f1c8b7fca6c30491eafbe6ffab754bf \
  QWEN_REFERENCE_MODEL="$HF_MODELS_ROOT/models--SceneWorks--qwen-image-mlx/snapshots/8080a4171f1c8b7fca6c30491eafbe6ffab754bf/bf16" \
  QWEN_W=512 QWEN_H=512 "$REF_PY" "$TOOLS/dump_qwen_adapter_golden.py"

FLUX_DEV="$HF_MODELS_ROOT/models--black-forest-labs--FLUX.1-dev/snapshots/3de623fc3c33e44ffbe2bad470d0f45bccf2eb21" \
  "$REF_PY" "$TOOLS/dump_hyper_flux_golden.py"

# Before tightening, the exact tolerance-based diagnostic measured 0 differing
# bytes across 786,432 RGB samples. The assertion is now byte equality and the
# retained runner itself executes
# five exact cargo invocations in a constructed environment (ambient variables
# are not inherited), captures real argv/env, stdout/stderr/return codes plus
# rustc/cargo/platform/hardware identity, and checks artifact/model/source
# identities before and after. It rejects a zero-test cargo result because each
# run must emit its one structured SC15505_RESULT line.
python3 "$TOOLS/record_adapter_parity_transcript.py"
```

The scripts reject a dirty/index-modified or source-augmented frozen fork, the wrong Git remote,
and a model path whose Hugging Face cache repository/revision/subdirectory does not match its
claim. The retained runner computes a canonical digest from the exact executable source contents
instead of Git's staging representation, and rejects every baseline-relative changed path outside
the reviewed sc-15505 allowlist (including untracked files).

If a direct-output no-adapter control is not worse than the adapted render, it cannot support a
mutation-sensitive threshold and must not be widened into one. Run the pre-tightening residual
diagnostic instead:

```sh
python3 "$TOOLS/record_adapter_parity_transcript.py" --residual-diagnostic
```

That exact, sanitized runner records `(Rust adapted - Rust base)` versus
`(fork adapted - fork base)` and compares it with the dropped-adapter control (a zero Rust
residual). It writes only the ignored diagnostic transcript and never the durable receipt. A final
residual cap may be locked only after the adapted residual is measured below the zero-residual
control; the reviewed rule is their integer midpoint. If there is no separation, the parity claim
must be reframed instead of forcing a passing cap.

The retained residual diagnostic separated Z LoRA (15,692 adapted vs 26,587 zero control) and
Z LoKr (15,476 vs 40,120), but rejected Qwen LoRA (63,030 vs 43,903) and Qwen LoKr
(69,111 vs 50,446): both Qwen adapted residual errors were worse than the dropped-adapter
control. Qwen therefore keeps the original floor-relative fork gate
`adapted_px_gt8 <= 2 * base_floor + rgb_samples / 200` and uses a separate same-runtime effect
gate to prove the adapter is active. Measure that effect before locking its nonzero minimum:

```sh
python3 "$TOOLS/record_adapter_parity_transcript.py" --qwen-effect-diagnostic
```

This dedicated diagnostic records active-adapter-vs-base px>8, scale-zero byte differences, exact
applied-module count (LoRA 24; LoKr 21), empty unmatched-path count, and RGB sample count. It has a
fixed schema and output path and, like the residual diagnostic, cannot write the acceptance
transcript or receipt. The retained measurement is LoRA effect 44,799 (minimum 22,399) and LoKr
effect 39,409 (minimum 19,704), each over 786,432 RGB samples; both scale-zero counts are 0 and
their apply reports are exactly 24/21 applied with no unmatched paths. The fixed minimum is
`measured_effect_samples_gt8 / 2`, so dropping/inerting an adapter produces zero and turns the
effect clause red while the separate floor-relative clause continues to constrain fork parity.

After recording, update the manifest with the measured `SC15505_RESULT` values plus every
artifact/transcript size and SHA-256, then run
`python3 "$TOOLS/verify_adapter_parity_artifacts.py"`. That final verifier cross-checks the
safetensors metadata, model inventories, exact artifact hashes, and retained cargo output. The
binaries and raw transcript remain uncommitted. The recorder also emits the committed,
path-redacted `../adapter_parity_receipt.json`; the manifest binds both its checksum and the
ignored raw transcript checksum, and the verifier requires the receipt to be the exact redacted
projection of that transcript. A deliberate reference refresh must update the manifest,
receipt, and `CHECKSUMS.txt` in the same review as any changed acceptance number; silently
accepting a new golden is not permitted.

**What the transcript binds, and what it deliberately does not (sc-17070).** `source_state()` keeps
two different sets. The **hashed** set — `bound_source_files()` — is the Rust sources plus every
manifest `scripts` entry *except* `UNBOUND_SOURCE_FILES`, and its SHA-256 map is frozen into the
transcript's `source.files`/`source_sha256`. The **changed-path allowlist** is that set plus
`UNBOUND_SOURCE_FILES` plus `EVIDENCE_CHANGE_FILES`. `verify_adapter_parity_artifacts.py` is the sole
unbound entry: the dump scripts, `_adapter_parity_provenance.py`, and `record_adapter_parity_transcript.py`
*produced* the goldens and the measurements, so freezing their bytes is meaningful; the verifier only
checks, so freezing its bytes would mean any edit to it — a pure bugfix included — invalidated the
proof and demanded a licensed real-weight re-record that buys no extra assurance about the parity
numbers. It keeps its `scripts` hash pin, which `validate_manifest` still enforces and which *is*
repairable in place. Both halves are covered by tests that do not mock `source_state`; if the verifier
is ever renamed, `bound_source_files()` refuses rather than silently rebinding it.

**The source binding is current as of the sc-17651 re-record (2026-08-04).** The frozen
`source.files` now matches `main` at the re-record, all 11 bound entries, and the two bookkeeping
entries that used to differ are gone: `verify_adapter_parity_artifacts.py` is no longer in the
frozen map at all (sc-17070 narrowed `source_state()`'s hashed set before this record, so verifier
edits no longer re-stale it), and `record_adapter_parity_transcript.py` is re-bound to its current
bytes. `adapter_parity_receipt.json`'s `proof.source.files` is the committed, path-redacted copy of
the frozen map, so the comparison needs no gitignored binaries:

```python
import hashlib, json, pathlib, sys
sys.path.insert(0, 'crates/media/mlx-gen/tools')
import record_adapter_parity_transcript as R
frozen = json.loads(pathlib.Path('crates/media/mlx-gen/tools/adapter_parity_receipt.json').read_text())['proof']['source']['files']
manifest = json.loads(pathlib.Path('crates/media/mlx-gen/tools/adapter_parity_artifacts.json').read_text())
for name in R.bound_source_files(manifest):
    live = hashlib.sha256(pathlib.Path(name).read_bytes()).hexdigest()
    print(name, 'MATCH' if frozen.get(name) == live else f'DRIFT {frozen.get(name)} -> {live}')
```

*What the re-record settled (sc-17651).* Between `071b84ff` and the re-record, two bound harnesses
had moved — `mlx-gen-z-image/tests/adapter_real_weights.rs` and
`mlx-gen-qwen-image/tests/adapter_real_weights.rs`, the files that emit the `SC15505_RESULT` lines —
via `11eab9cf` (sc-16057, process-unique temp fixtures) and `716c97d9` (sc-17284, macOS real-weight
CI lanes). Re-running the full acceptance proof reproduced **every one of the 34 pinned measurement
fields exactly**, so neither change moved a number. Two things are worth keeping, because reading
the diffs alone would not have established either:

- sc-16057 touched only `kohya_matches_peft_on_real_tree()`, which emits no `SC15505_RESULT` and is
  never selected — each recorded run names one test with `--exact`.
- sc-17284 renamed the Qwen snapshot variable to `MLX_GEN_QWEN_SNAPSHOT` on the measured path and
  renamed `expected_runs()` in lockstep, so the resolved model directory is unchanged. But
  `verify_result_transcript` compares `run["env"]` against a freshly built `expected_runs()`, so the
  *old* transcript's two Qwen rows had become unverifiable (`env mismatch`) independently of any
  measurement question. A stale binding here is not always just bookkeeping — check whether the
  recorded run spec still reproduces before assuming the numbers are the only question.

*Reproducing the artifact set.* The **11 generated** artifacts regenerate byte-for-byte on the
reference host from the commands in each `artifacts.*.source.command`, given the frozen fork at
`81106c83` and `.venv-0320`; that includes the MLX renders, not just the synthetic adapters. The
12th, `hyper_flux_lora`, is `source.kind: "huggingface"` — a pinned 1.38 GB ByteDance download with
no `command`, verified by hash rather than regenerated. If a regenerated golden's SHA-256 does *not*
match, treat it as a real signal rather than as expected float noise — the one historical exception
was a defect, not nondeterministic math: `dump_hyper_flux_golden.py` is the only dump here that
writes via `safetensors.numpy.save_file`, which serializes `__metadata__` out of a Rust `HashMap`
with per-process iteration order, so its file hash changed every run while all eight tensors stayed
bit-identical. `_canonicalize_metadata_order()` sorts the metadata after the write — a key
permutation that preserves the serialized length, re-padded into the original header slot, with the
write confined to the header bytes so the payload cannot move. That made the artifact reproducible
and moved its pinned hash, in the sc-17651 review.

Two consequences worth knowing before you touch that script. Its own SHA-256 is embedded in the
golden it writes (`golden_metadata()` sets `reference_script_sha256`), so **any byte edit to
`dump_hyper_flux_golden.py` invalidates this artifact's pin and forces a licensed regeneration plus
a re-record** — it is a bound source file too. That is the same ratchet sc-17070 removed for the
verifier, and it is why the canonicalization helper lives in this script rather than in
`_adapter_parity_provenance.py`: that module's hash is embedded in *all five* generated goldens as
`reference_provenance_sha256`, so hoisting the helper there would invalidate every one of them. Do
not "simplify" it by moving it. The sibling dumps use `mx.save_safetensors` and were never affected.

Note also what the recorded Hyper-FLUX run does and does not pin. `hyper_flux_scale_zero_is_bit_exact_noop`
compares `injected_render(None)` against `injected_render(Some(0.0))` — both sides read the same
golden — so `byte_differences=0` is insensitive to the golden's tensor *values*; the tests that
would detect a changed Hyper-FLUX golden (they compare against `image_u8`/`final_latents`) are not
in the recorded run set. What evidences a faithful regeneration here is therefore the artifact's
unchanged byte count and the ten sibling artifacts reproducing byte-exactly from the same
fork/venv/models — not that single acceptance number.

One operational note. A full (non-`--manifest-only`) run from an ordinary `main` checkout never
reaches the source comparison at all: `source_state()` raises `proof worktree contains changes
outside the bound allowlist` first (944 paths differ from `implementation_base` at the time of
writing). The comparison is only reachable from a detached checkout at `implementation_base`
(`39a11d36…`) with the proof's source overlaid — the 11 bound files plus `UNBOUND_SOURCE_FILES` plus
`EVIDENCE_CHANGE_FILES` — which is the same protocol a re-record runs under. And when it is reached,
any file-hash drift also moves `source_sha256`, which is compared first — so the failure you
actually see is `result transcript source source_sha256 mismatch`, not the `files` one.

## Manifest

### Z-Image (`mlx-gen-z-image`)

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `z_image_golden.safetensors` (+ `.png`) | `dump_z_image_golden.py` | `tests/e2e_real_weights.rs` | txt2img stage + full pipeline. Env: `ZIMAGE_PROMPT/SEED/STEPS/W/H` (use `W=H=1024` for the e2e size; default 256²). Emits the **static shift=3.0** schedule (sc-2536). |
| `z_image_q8_golden.safetensors`, `z_image_q4_golden.safetensors` (+ `.png`) | `dump_z_image_golden.py` with `QUANTIZE=8`/`4` **and `ZIMAGE_W=1024 ZIMAGE_H=1024`** | `tests/e2e_real_weights.rs` (`transformer_q8/q4_pipeline_matches_fork` + `q8/q4_full_generate_renders`) | sc-2532 Q4/Q8 parity, **regenerated at 1024²** (production res; at 256² the per-pixel metric is a pessimistic artifact). `ZImage(quantize=N)` runs the fork's real whole-model quantized path; the full-`generate()` tests match it end-to-end (transformer + text encoder + VAE), the cap_feats-fed `transformer_q*` tests isolate the transformer. |
| `zq8_pack_probe.safetensors` | `dump_z_image_q8_pack_probe.py` | `tests/e2e_real_weights.rs` (`q8_packing_byte_identical_to_fork`) | sc-2532 byte-level Q8 packing proof on a **real bf16 model weight** (`layers.0.attention.to_q`) — confirms mlx-rs `mx.quantize`/`quantized_matmul` reproduce the fork's exactly. |
| `z_image_img2img_golden.safetensors` (+ `*_init.png`, `*_out.png`) | `dump_z_image_img2img_golden.py` | `tests/img2img_real_weights.rs` | img2img (`Conditioning::Reference`). Env: `ZIMAGE_PROMPT/SEED/STEPS/W/H/STRENGTH/IW/IH`. Dumps `init_image_u8` so Rust uses byte-identical pixels. |

### Qwen-Image / Qwen-Image-Edit (`mlx-gen-qwen-image`)

| golden | dump script | consumed by |
|---|---|---|
| `qwen_image_golden.safetensors`, `qwen_image_q8_golden.safetensors` | `dump_qwen_image_golden.py` (Q8 via its suffix arg) | `tests/e2e_real_weights.rs` |
| `qwen_image_edit_golden.safetensors`, `qwen_image_edit_q8_golden.safetensors` | `dump_qwen_image_edit_golden.py` | `tests/edit_real_weights.rs` |
| `qwen_text_encoder_golden.safetensors` | `dump_qwen_text_encoder_golden.py` | `tests/text_encoder_real_weights.rs` |
| `qwen_transformer_golden.safetensors` | `dump_qwen_transformer_golden.py` | `tests/transformer_real_weights.rs` |
| `qwen_vae_golden.safetensors` | `dump_qwen_vae_golden.py` | `tests/vae_real_weights.rs` |
| `qwen_vision_golden.safetensors`, `qwen_vl_encoder_golden.safetensors`, `qwen_vl_tokenize_golden.safetensors` | `dump_qwen_vision_golden.py`, `dump_qwen_vl_encoder_golden.py`, `dump_qwen_vl_tokenize_golden.py` | `tests/vision_real_weights.rs` |
| `qwen_edit_tokenize_debug.safetensors`, `qwen_edit_vision_stages_debug.safetensors` | `dump_qwen_edit_tokenize_debug.py`, `dump_qwen_edit_vision_stages_debug.py` | `tests/edit_real_weights.rs` (debug/bisection gates) |
| ~~`qwen_edit_rope_golden.safetensors`~~ | `dump_qwen_edit_rope_golden.py` | **PROMOTED to `mlx-gen-qwen-image/tests/fixtures/` (sc-17519)** — see below |

See each script's module docstring for its exact env vars / arguments.

### `qwen_edit_rope_golden.safetensors` — promoted out of this directory (sc-17519)

Two rows elsewhere in this file already flag `mage_flow_noise_golden` and `pil_resize_golden` as
weight-free and "candidate to promote into `tests/fixtures/`". This is the first one to actually make
the move, and the reasoning is the template for the rest.

**Why it qualified.** `dump_qwen_edit_rope_golden.py` imports exactly one symbol —
`mflux.models.qwen.model.qwen_transformer.qwen_rope.QwenEmbedRopeMLX` — and calls it. It resolves no
snapshot, reads no HF cache, and never touches the `Qwen/Qwen-Image-Edit-2511` torch original. The
Rust side (`QwenRope3d::forward_multi`) is pure math too. So neither half of the gate needs weights,
and the "can't be produced or consumed without the licensed multi-GB weights" rationale at the top of
this file — the reason everything here is gitignored — simply does not apply to it.

**Why vendoring is allowed.** Committing a golden minted from a third-party fork is a licence
decision, not a size decision. `mflux` is **MIT** (`LICENSE`: "MIT License, Copyright (c) 2026 Filip
Strand"; `pyproject.toml` `license = { file = "LICENSE" }`), so redistribution is permitted with its
notice. That is the same reasoning `crates/media/mlx-gen/.gitignore` already records for the sc-14036
Mage-Flow exception ("microsoft/Mage is MIT — redistribution is permitted with its notice"), which is
the in-repo precedent for an exception to the blanket rule a few lines above it.

**Provenance.**

| | |
|---|---|
| artifact | `crates/media/mlx-gen/mlx-gen-qwen-image/tests/fixtures/qwen_edit_rope_golden.safetensors` |
| size / sha256 | 78,133 bytes / `ab31b3836089fe90dae9dc8347c0c50726e74648e8e989c2c106c5ce7bd6f212` |
| minted | 2026-08-07, `cd ~/Repos/mflux && uv run python .../tools/dump_qwen_edit_rope_golden.py` |
| fork pin | `mflux` @ `81106c833435d1a1f62ca04a8c01c1d380d39272` (2026-06-04, "sc-2997: Qwen-Image-Edit-2511 zero_cond_t") |
| upstream licence | MIT — `~/Repos/mflux/LICENSE` |
| contents | `img_cos`/`img_sin` `[132, 64]` and `txt_cos`/`txt_sin` `[20, 64]`, all f32, for `video_fhw=[(1,8,12), (1,6,6)]`, `txt_seq_lens=[20]` |
| consumer | `tests/edit_real_weights.rs::edit_rope_multi_image_matches_fork`, **not `#[ignore]`d** |

Do NOT re-add the `#[ignore]`. The test runs in the default `cargo test` on any clone, measured
0.03 s, max abs diff 5.960e-8 against its 1e-5 bound on all four tables with `MLX_GEN_MODELS_ROOT`
and `QWEN_IMAGE_EDIT_SNAPSHOT` unset. Mutation-checked: perturbing the conditioning grid to `(6, 7)`
fails it. `*.safetensors binary` in the root `.gitattributes` already covers the path, so the
`text=auto` 8000-byte sniff cannot rewrite its bytes.

The other four weight-free Qwen gates — the index/Gate-A tests in `tests/vision_real_weights.rs` —
CANNOT follow yet, and the blocker is not licence or weights. `dump_qwen_vision_golden.py` writes its
Gate-1 (line 9, "zero model download") and Gate-A (line 70, "NO snapshot/weights") tensors into the
same output file as Gate B (line 96 onward), which loads the Edit-2511 original. Splitting that
producer in two is the entire fix and costs no download. Tracked in **sc-18085**, deliberately apart
from the oracle-bundle story (sc-17909) so it does not wait on a ~60 GB decision it has no stake in.

### FLUX.2-klein (`mlx-gen-flux2`)

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `flux2_te_real.safetensors`, `flux2_te_real_f32.safetensors` | `dump_flux2_te_real_golden.py` (`FLUX2_TE_F32=1` for the f32 ref) | `tests/te_real_weights.rs` | sc-2346 S1 Qwen3 text encoder + tokenizer. The f32 golden is the **correctness** ref (Rust runs f32 activations → peak_rel ~1e-5); the bf16 golden is the fork's production precision (the residual there is bf16-vs-f32 over 36 layers). The committed `tests/fixtures/te_golden.safetensors` (tiny synthetic) proves the encoder math on CI without weights. |
| `flux2_vae.safetensors` | `dump_flux2_vae_golden.py` | `tests/vae_real_weights.rs` | sc-2346 S2 VAE: `decode_packed_latents` (BN-denorm + 2×2 unpatchify + decode) and `encode`. f32 golden (Rust VAE runs f32) → mean_rel ~2e-3. Tensors are NCHW; the test transposes to the Rust VAE's NHWC. |
| `flux2_e2e.safetensors` | `dump_flux2_e2e_golden.py` | `tests/e2e_real_weights.rs` | sc-2346 S4 txt2img e2e (256², 4 steps, guidance 1.0), f32. Gates: seeded noise byte-match, step-0 velocity (real-weights transformer, chaos-free) mean_rel ~4e-4, full `generate()` render ~0.9% px>8 vs the fork's f32 image (the residual is the NAX-vs-wheel build delta over the sampler). |
| `flux2_edit.safetensors` | `dump_flux2_edit_golden.py` | `tests/edit_real_weights.rs` | sc-2346 S5 single-reference edit e2e (256², 4 steps), f32. Gates: reference-encoding chain (VAE-encode → patchify → BN-normalize → pack) mean_rel ~4e-4, full edit `generate()` render **0.00% px>8** vs the fork's f32 image (the dense ref conditioning makes the sampler even more stable than txt2img). Includes the 256²-resized `ref_u8` so the Rust test feeds byte-identical reference pixels. |

### SDXL acceleration samplers (`mlx-gen-sdxl`, sc-2769)

The few-step samplers (LCM / SDXL-Lightning / Hyper-SD) exist only in **diffusers**, so unlike the
other SDXL goldens (vendored Apple `mlx_sd`) these are dumped from diffusers — run the script from a
torch+diffusers venv (e.g. `/Users/michael/Repos/mflux/.venv` after `uv pip install diffusers`).

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `sdxl_accel_sched_golden.safetensors` | `dump_sdxl_accel_golden.py` (default) | `tests/accel_sampler_parity.rs` (core crate) | **Scheduler-math isolation:** per-step deterministic outputs of `LCMScheduler` / `EulerDiscreteScheduler(trailing)` / `TCDScheduler` on fixed synthetic tensors. Validates the Rust `mlx_gen::sampler` port to ~1e-6 (torch-f32 vs MLX-f32), no model needed. Small + fast. |
| `sdxl_accel_render_{ancestral,lightning,hyper,lcm}.safetensors` (+ implied `.png` via the test) | `dump_sdxl_accel_golden.py render` | `mlx-gen-sdxl/tests/accel_real_weights.rs` (`lightning_hyper_match_torch_teacher_forced`) | **Deterministic e2e:** torch initial latent + final RGB8 per variant. The Rust test teacher-forces the init latent and reports px>8 vs the torch render (a *qualitative* torch↔MLX backend gap, NOT bit-exact). Needs the full fp16 SDXL pipeline + accel LoRAs. |

### PuLID-FLUX face-identity (`mlx-gen-pulid`, epic 3069)

The reference is the **vendored torch `pulid_flux`** (SceneWorks worker `_vendor/pulid_flux/`), so
these dump from a torch venv, not `mflux`. Run from the vendored reference dir under `pulidenv`:

```sh
cd /Users/michael/Repos/SceneWorks/apps/worker/scene_worker/_vendor/pulid_flux
HF_HUB_OFFLINE=1 PYTHONPATH=. /private/tmp/pulidenv/bin/python /path/to/mlx-gen/tools/dump_eva_clip_golden.py
```

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `eva_clip_golden.safetensors` | `dump_eva_clip_golden.py` | `mlx-gen-pulid/tests/eva_clip_parity.rs` | **EVA02-CLIP-L-14-336 visual tower (sc-3070).** f32 reference weights + `enc_in` + 5 hidden states + `id_cond_vit`, plus the `rope.freqs_*` buffers (weight-free RoPE-construction gate) and a 512²→336² resize/normalize case (`ffi_512`/`tf_*`). Gate is cosine-primary: torch-CPU-f32 golden vs MLX-Metal-f32 has a depth-accumulating mean-rel floor (~1e-2 by block 20), but the final `id_cond_vit` re-normalizes to cos 0.999997 (bf16 0.999945). The float antialiased bicubic matches torchvision to ~1e-6. |
| `idformer_golden.safetensors` | `dump_idformer_golden.py` | `mlx-gen-pulid/tests/idformer_parity.rs` | **IDFormer perceiver-resampler (sc-3071).** f32 `pulid_encoder.*` weights (from `pulid_flux_v0.9.1.safetensors`) + deterministic `id_cond` [1,1280] + 5 EVA hidden states → `id_embedding` [1,32,2048]. cos 1.000000 / mean-rel 1.3e-3 (bf16 0.999999). |
| `pulid_ca_golden.safetensors` | `dump_pulid_ca_golden.py` | `mlx-gen-pulid/tests/pulid_ca_parity.rs` | **PerceiverAttentionCA ×20 + injection schedule (sc-3072).** f32 `pulid_ca.{0..19}.*` weights + `id_embedding` [1,32,2048] + `img` [1,64,3072] + per-module outputs at ca indices {0,9,10,19}. Driving these through the `PulidCa` injector validates the CA math (cos ~1.0) and the double→single ca_idx schedule (double i→ca[i/2], single i→ca[10+i/4]) in one shot. |
| _(reuses goldens above)_ | — | `mlx-gen-pulid/tests/pulid_flux_e2e.rs` | **PuLID-FLUX e2e (sc-3074).** No new golden: reuses `eva_clip_golden` (EVA, prefix `w`) + `scrfd_10g`/`arcface_iresnet100`/`bisenet_parsing`/`face_align_goldens` (face stack + reference face), with FLUX.1-dev from the HF cache and `pulid_flux_v0.9.1.safetensors` from `guozinan/PuLID`. Validates id_weight=0 == plain-FLUX bit-identical, id injection changes the render, and ArcFace identity cosine (0.68 @ 20-step/512²; sc-2012 baseline ≈0.80). Heavy — loads the full stack. |
### InstantID (`mlx-gen-instantid`, consumes `mlx-gen-sdxl`, epic 3109)

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `instantid_kps_golden.safetensors` | `dump_instantid_kps_golden.py` | `tests/instantid_kps.rs` (mlx-gen-instantid) | sc-3111 kps control-image renderer. cv2 ground truth (OpenCV 4.13.0) for `draw_kps` across 4 (canvas, kps) cases — square+view-angle, non-square+detected, extreme profile, tiny 64². The Rust port must bit-match OpenCV's integer rasterization (`ellipse2Poly` + `fillConvexPoly` + filled `circle`). Small (committed-size, but gitignored per the dir rule). |
| `instantid_e2e_ref.safetensors` | `dump_instantid_e2e_ref.py` | `tests/instantid_e2e.rs` (mlx-gen-instantid) | sc-3115 T2I end-to-end + identity. Raw RGB of a single large face cropped (with margin) from insightface `t1.jpg` — the reference whose ArcFace embedding + 5 kps drive generation. The test detects it (native face stack), generates 1024²/30-step, re-detects the output, and gates on **ArcFace-cosine(ref, generated) ≈ 0.82** (sc-2009 torch baseline ≈0.876; directional, not bit-exact). Also needs `scrfd_10g.safetensors` + `arcface_iresnet100.safetensors` (epic 3079 converters: `convert_scrfd.py` / `convert_glintr100.py`), the converted `instantid/ip-adapter.safetensors`, the SDXL base snapshot, and the InstantID `ControlNetModel`. Writes `instantid_e2e_out.png` for inspection. |
| `instantid/ip-adapter.safetensors` | `convert_instantid.py` | `tests/instantid_convert_smoke.rs` | sc-3112 weight conversion. Re-serializes `ip-adapter.bin` (pickle → safetensors) bundling `image_proj.*` (Resampler) + `ip_adapter.*` (70 decoupled-cross-attn K/V pairs), mirroring the h94 IP-Adapter namespace. The IdentityNet `ControlNetModel/diffusion_pytorch_model.safetensors` needs **no conversion** (stock SDXL ControlNet, loads via `ControlNet::from_weights` + `UNetConfig::sdxl_base()`). Source dtype (f32) preserved; loader casts. |
| `instantid_resampler_golden.safetensors` | `dump_instantid_resampler_golden.py` | `tests/instantid_resampler_real_weights.rs` | sc-3110 face Resampler. InstantID's `image_proj_model` is the *same* Tencent `Resampler` as the SDXL IP-Adapter (sc-3059), validated under `ResamplerConfig::instantid_face()` (embedding_dim=512) on a seeded `[1,1,512]` ArcFace embed → `[1,16,2048]` face tokens. **Bundles the f32 `image_proj.*` weights** (from `InstantX/InstantID` `ip-adapter.bin`) so the test needs no separate converted file — hence ~313 MB (larger than the other goldens). f32 vs torch CPU → peak_rel 5.3e-4 (the `norm_out` renormalizes, like the IP-Adapter Resampler's 4.9e-4). |

### SAM2 segmenter (`mlx-gen-sam2`, epic 3704)

Dumped from the **MLX-native reference** `avbiswas/sam2-mlx` (the impl this crate ports) — run from
the MLX venv with the reference checkout on `PYTHONPATH`, e.g.
`PYTHONPATH=/tmp/sam2-mlx/src ~/mlx-flux-venv/bin/python tools/dump_<name>.py --size large`. Both
sides run MLX Metal, so parity is near-bit.

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `sam2_encoder_golden_large.safetensors` | `dump_sam2_encoder_golden.py` | `tests/encoder_parity.rs` | sc-3705 Hiera trunk + FPN neck — `enc_in` [1,3,1024,1024] → the 3 backbone-FPN maps + position encodings. |
| `sam2_segmenter_golden_large.safetensors` | `dump_sam2_segmenter_golden.py` | `tests/segmenter_parity.rs` | sc-3706 box-prompt decoder — encode→prompt-encode→two-way-transformer→mask. Bundles the full `trunk/neck/sam_prompt_encoder/sam_mask_decoder` weights + `enc_in`/`box_1024` + ref low-res masks/IoUs. |
| `sam2_photo_golden.safetensors` | `dump_sam2_photo_golden.py` | `tests/photo_parity.rs` | sc-3708 real-photo box→mask vs the spike baseline (zidane/bus). |
| `sam2_memory_golden_large.safetensors` | `dump_sam2_memory_golden.py` | `tests/memory_parity.rs` | sc-3713 Phase-B video layer — `memory_encoder.*`/`memory_attention.*` weights + two fixtures: the memory encoder (`mem_pix_feat`/`mem_masks` → 64-ch feature map + pos enc) and the memory attention (a 3-frame bank + 2 object pointers: `ma_curr`/`ma_mem`/… + `ma_num_obj` → conditioned tokens). Exercises the depthwise-conv ConvNeXt fuser and the interleaved axial RoPE self/cross attention with key-repeat + object-pointer RoPE exclusion. cos 1.0 (encoder mean-rel 0; attention mean-rel ~3e-5). |

### Kolors (`mlx-gen-kolors`, epic 3090)

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `kolors_tokenizer_golden.safetensors` | `build_kolors_tokenizer.py` | `tests/tokenizer_parity.rs` | sc-3092 ChatGLM3 tokenizer. The script ALSO materializes the fast `tokenizer.json` into the snapshot `tokenizer/` dir (LLaMA-style byte_fallback BPE replica). Golden = reference `ChatGLMTokenizer(prompt, padding="max_length", max_length=256, truncation=True)` input_ids/attention_mask/position_ids for a 5-prompt EN/EN-long(truncated)/CN/mixed/empty battery. Rust `KolorsTokenizer` matches byte-identical. |
| `kolors_t2i_golden.safetensors` | `dump_kolors_t2i_golden.py` | `mlx-gen-kolors/tests/t2i_parity.rs` | sc-3094 Kolors T2I e2e. diffusers `KolorsPipeline` f32, 512²/8 steps/CFG 5, fixed init noise. Bundles: `init_noise` (raw, NHWC), pos/neg `context`+`pooled`, `final_latents`, `step0/step1_latents`, decoded `image`. Gate A (tight) = early-step latent integration (step0 ~4e-3, step1 ~1e-2). Gate B = full-render coherence + cross-backend px delta (mean\|Δ\|~13/255; full-trajectory bit-parity vs torch is chaos-limited — see the test's note). |
| `kolors_img2img_golden.safetensors` | `dump_kolors_img2img_golden.py` | `mlx-gen-kolors/tests/img2img_parity.rs` | sc-3095 Kolors img2img e2e. diffusers `KolorsImg2ImgPipeline` components driven directly (f32, 512²/8 steps/strength 0.6→4 eff steps/CFG 5) on a fixed 512² init pattern. Init = VAE encoder **mean** (`sample_mode="argmax"`, matching Rust `encode_init_latents`); `add_noise` = raw `x₀ + noise·σ_start` at the strength-derived `begin_index` (start_sigma ~1.22). Bundles: `init_image` (f32 [0,1] [H,W,3]), `init_latents`+`noise` (NHWC), pos/neg `context`+`pooled`, `step0/step1_latents`, `final_latents`, decoded `image`. Gate A (tight) = early-step latent integration (step0 ~2e-3, step1 ~5e-3 — tighter than T2I, smaller start σ). Gate B = full-render coherence (mean\|Δ\|~12/255; chaos-limited like T2I). |
| `kolors_unet_golden.safetensors` | `dump_kolors_unet_golden.py` | `mlx-gen-kolors/tests/unet_parity.rs` | sc-3093 Kolors U-Net wiring. diffusers Kolors `UNet2DConditionModel` single forward (f32) fed the ChatGLM3 conditioning: latents (NHWC) + timestep 999 + context `[1,256,4096]` + pooled `[1,4096]` + time_ids `(1024,1024,0,0,1024,1024)` → eps (NHWC). Validates the auto-detected `encoder_hid_proj` (4096→2048) + 5632 `add_embedding`. Rust peak_rel ~5e-4. |
| `kolors_controlnet_golden.safetensors` | `dump_kolors_controlnet_golden.py` | `mlx-gen-kolors/tests/controlnet_parity.rs` | sc-3097 Kolors ControlNet single forward. diffusers `ControlNetModel` (`Kwai-Kolors/Kolors-ControlNet-Pose`, f32) fed fixed latents + a 512² 'pose' control pattern + the ChatGLM3 conditioning **reused from the T2I golden** (the dump projects 4096→2048 externally with the CN's own `encoder_hid_proj`; the Rust `ControlNet::forward` projects internally — same weights). Bundles `latents`/`control_image`/`context`(4096)/`pooled`/`time_ids` + the 9 `down{i}` + `mid` residuals (NHWC, `conditioning_scale=1.0`). Gate A (component) = residuals match (worst peak_rel ~6e-3 f32 conv floor). Two Rust-only gates: `control_scale=0` byte-identical to plain T2I (f32; bf16 chaos-amplifies the zero-add, see test) + scale>0 perturbs & renders coherently. |
| `kolors_ip_adapter_golden.safetensors` | `dump_kolors_ip_adapter_golden.py` | `mlx-gen-kolors/tests/ip_adapter_parity.rs` | sc-3098 Kolors IP-Adapter-Plus components. `Kwai-Kolors/Kolors-IP-Adapter-Plus`: CLIP-**ViT-L/14-336** tower (transformers `CLIPVisionModelWithProjection`) + the IP-Adapter-Plus Resampler (a faithful torch port of the Tencent `Resampler`, dim 2048/depth 4/dim_head 64/heads 12 — loaded from `image_proj.*` with zero missing keys, pinning the config). Bundles `image` (raw u8 ref), `pixels` (CLIP-preprocessed NHWC [1,336,336,3]), `penultimate` ([1,577,1024]), `tokens` ([1,16,2048]). Gates: preprocess **byte-exact**, encoder penultimate cosine ~0.9997 (peak ~1.7e-2 = 24-layer f32 floor), resampler tokens peak_rel ~1.5e-3. Two Rust-only gates: `ip_scale=0` byte-identical to plain T2I (f32) + scale>0 perturbs & renders coherently. |
| `kolors_chatglm_golden.safetensors` | `dump_kolors_chatglm_golden.py` | `tests/chatglm_parity.rs` | sc-3091 ChatGLM3-6B text encoder. Diffusers `KolorsPipeline` `ChatGLMModel` (`text_encoder/` fp16 shards, ~12.5 GB) run with `output_hidden_states=True` on two fixed inputs — `packed` (pure causal) and `padded` (right-pad → causal+padding mask) — for BOTH f32 and fp16 (`f16_` prefix). Bundles per case/dtype: `input_ids`/`attention_mask` + all 29 hidden states (permuted `[S,B,H]→[B,S,H]`) + `context` (`hidden_states[-2]`) + `pooled` (`hidden_states[-1]` last token). f32 worst hidden ~1.1e-3 (flat over depth = Metal-vs-CPU floor), fp16 worst ~1.7e-3. |

### LTX-2.3 video (`mlx-gen-ltx`)

Dumped from the frozen `mflux` fork's LTX reference (`~/repos/mflux`). Components feed staged parity
tests; the e2e/i2v/av goldens gate the full pipeline. Several scripts also write shared input bundles
(`transformer.safetensors`, `upsampler.safetensors`, `vae_decoder.safetensors`, `connector.safetensors`,
`audio_vae.safetensors`) next to the golden — those are reused inputs, not goldens themselves.

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `ltx_s0_golden.safetensors` | `dump_ltx_s0_golden.py` | `tests/s0_parity.rs` | sc-2679 S0 spike. |
| `ltx_block_golden.safetensors` | `dump_ltx_block_golden.py` | `tests/block_parity.rs` | single DiT block forward. |
| `ltx_dit_golden.safetensors` (+ `_bf16`) | `dump_ltx_dit_golden.py` | `tests/dit_parity.rs` | full DiT forward (f32 + bf16). |
| `ltx_connector_golden.safetensors` | `dump_ltx_connector_golden.py` | `tests/connector_parity.rs` | TE→DiT connector. |
| `ltx_gemma_golden.safetensors` (+ `_q8`/`_q4`) | `dump_ltx_gemma_golden.py` | `tests/gemma_parity.rs` | Gemma-3-12B TE, 49 hidden states; quant suffixes gate TE-quant (sc-2686). |
| `ltx_te_golden.safetensors` | `dump_ltx_te_golden.py` | `tests/te_parity.rs` | text encoder + connector chain. |
| `ltx_vae_golden.safetensors` | `dump_ltx_vae_golden.py` | `tests/vae_parity.rs` | VAE encode/decode. |
| `ltx_vae_tiling_golden.safetensors` | `dump_ltx_vae_tiling_golden.py` | `tests/vae_parity.rs` | tiled VAE decode. |
| `ltx_upsampler_golden.safetensors` | `dump_ltx_upsampler_golden.py` | `tests/upsampler_parity.rs` | latent upsampler. |
| `ltx_pipeline_golden.safetensors` | `dump_ltx_pipeline_golden.py` | `tests/pipeline_parity.rs` | staged pipeline integration. |
| `ltx_e2e_golden.safetensors` (+ `ltx_e2e_te`, `_q4`, `_q4_bf16`) | `dump_ltx_e2e_golden.py`, `dump_ltx_e2e_te.py` | `tests/e2e_parity.rs` | txt2v e2e (dense + Q4); the `_te` variant isolates the encode stage. |
| `ltx_i2v_golden.safetensors` (+ `_bf16`) | `dump_ltx_i2v_golden.py` | `tests/i2v_parity.rs` | image-to-video (sc-2818). |
| `ltx_keyframe_cond_golden.safetensors` | `dump_ltx_keyframe_cond_golden.py` | `tests/keyframe_cond_parity.rs` | keyframe-append / IC-LoRA conditioning (epic 3040). |
| `ltx_replace_mask_golden.safetensors` | `dump_ltx_replace_mask_golden.py` | `tests/replace_mask_parity.rs` | replace-latent video mode (epic 3040). |
| `ltx_lora_golden.safetensors` | `dump_ltx_lora_golden.py` | `tests/lora_real_weights.rs` | LoRA/LoKr in generate (sc-2687). |
| `ltx_audio_vae_golden.safetensors` | `dump_ltx_audio_vae_golden.py` | `tests/audio_vae_parity.rs` | AV audio VAE. |
| `ltx_av_dit_golden.safetensors` (+ `_bf16`) | `dump_ltx_av_dit_golden.py` | `tests/av_dit_parity.rs`, `tests/perf.rs` | audio-video joint DiT (`AvDiT`). |
| `ltx_av_e2e_golden.safetensors` | `dump_ltx_av_e2e_golden.py` | `tests/av_e2e_parity.rs` | AV e2e. |
| `ltx_av_lora_e2e_golden.safetensors` | `dump_ltx_av_lora_e2e_golden.py` | `tests/av_lora_e2e_parity.rs` | AV e2e with LoRA (sc-2687). |
| `ltx_vocoder_golden.safetensors` | `dump_ltx_vocoder_golden.py` | `tests/vocoder_parity.rs` | audio vocoder. |

### Wan-VACE video (`mlx-gen-wan`, sc-3388)

Wan/VACE controllable-video goldens (the broader Wan converter/quant goldens live in `tests/fixtures/`
and the `convert_*`/`*_parity` tests run weight-gated). Dumped from the diffusers Wan-VACE reference.

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `wanvace_cond_golden.safetensors` | `dump_wanvace_cond_golden.py` | `tests/wanvace_cond_parity.rs` | VACE conditioning construction. |
| `wanvace_transformer_golden.safetensors` (+ `wanvace_bisect`) | `dump_wanvace_transformer_golden.py`, `dump_wanvace_bisect.py` | `tests/wanvace_transformer_parity.rs` | VACE transformer forward (+ a bisection debug bundle). |
| `wanvace_real_io.safetensors` | `dump_wanvace_real_golden.py` | `tests/wanvace_real_parity.rs`, `tests/wanvace_lora_real_parity.rs` | real-weight e2e I/O. |
| `wanvace_lora_real_io.safetensors`, `wanvace_real_lora.safetensors` | `dump_wanvace_lora_real_golden.py` | `tests/wanvace_lora_real_parity.rs` | real-weight LoRA e2e. |

### SVD image-to-video (`mlx-gen-svd`)

Stable-Video-Diffusion goldens, dumped from the diffusers `StableVideoDiffusionPipeline` reference.

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `svd_clip_preprocess_golden.safetensors` | `dump_svd_clip_preprocess_golden.py` | `tests/clip_preprocess_parity.rs` | CLIP image preprocess. |
| `svd_image_encoder_golden.safetensors` | `dump_svd_image_encoder_golden.py` | `tests/image_encoder_parity.rs` | CLIP image encoder (conditioning). |
| `svd_unet_golden.safetensors` | `dump_svd_unet_golden.py` | `tests/unet_parity.rs` | temporal U-Net forward. |
| `svd_vae_golden.safetensors` | `dump_svd_vae_golden.py` | `tests/vae_parity.rs` | temporal VAE decode. |
| `svd_scheduler_golden.safetensors` | `dump_svd_scheduler_golden.py` | `tests/scheduler_parity.rs` | EulerDiscrete (SVD) scheduler math. |
| `svd_pipeline_golden.safetensors` | `dump_svd_pipeline_golden.py` | `tests/pipeline_parity.rs` | full pipeline integration. |

### Mochi 1 video (`mlx-gen-mochi` / `candle-gen-mochi`, sc-11984 / epic A1)

Native Mochi 1 (`genmo/mochi-1-preview`, Apache-2.0) parity oracle. Dumped from the diffusers
`MochiPipeline` reference by a **single** harness (`dump_mochi_golden.py --stage {te,vae,dit_block,dit,e2e,all}`)
that loads the pipeline once at a fixed seed/prompt/geometry (bf16 reference precision). The
`dit_block` and `dit` goldens are captured via forward hooks on `transformer_blocks[0]` and the whole
`transformer` during the `e2e` denoise. Weights are pinned in `release/real-weight-models.toml`
(`mochi-1-preview`, env `MOCHI_SNAPSHOT`). The consuming crates + `#[ignore]`d parity tests land in
stories A2–A4.

| golden | dump script | consumed by (A2–A4) | notes |
|---|---|---|---|
| `mochi_te_golden.safetensors` | `dump_mochi_golden.py --stage te` | Mochi `te_parity` (A2) | T5-XXL `encode_prompt` — prompt/negative embeds + attention masks. |
| `mochi_vae_golden.safetensors` | `dump_mochi_golden.py --stage vae` | Mochi `vae_parity` (A2) | `AutoencoderKLMochi` decode of a seeded 12-ch latent (per-channel mean/std de-norm). |
| `mochi_dit_block_golden.safetensors` | `dump_mochi_golden.py --stage dit_block` | Mochi `block_parity` (A3) | one `MochiTransformerBlock` forward — real (post patch-embed/time-embed/RoPE) inputs + output, hook-captured at e2e step 0. |
| `mochi_dit_golden.safetensors` | `dump_mochi_golden.py --stage dit` | Mochi `dit_parity` (A3) | whole `MochiTransformer3DModel` forward — raw `hidden_states`/`encoder_hidden_states`/`timestep`/`encoder_attention_mask` inputs + **pre-CFG** `noise_pred` (both `[neg, pos]` branches), hook-captured at e2e step 0. |
| `mochi_e2e_golden.safetensors` | `dump_mochi_golden.py --stage e2e` | Mochi `e2e_parity` (A4) | full txt2v denoise → final latent + VAE-decoded frame. |

### SenseNova-U1 unified AR + image gen (`mlx-gen-sensenova`, epic 3180)

Two tiers: weight-free **synthetic** goldens (`*_golden.safetensors`) that gate the math on CI-sized
inputs, and **real-weight** goldens (`*_realweight_golden.safetensors`) for the 35 GB e2e paths.

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `tokenizer_golden.safetensors` | `build_sensenova_tokenizer.py` | `tests/tokenizer_parity.rs` | builds + validates the snapshot `tokenizer.json`. |
| `backbone_golden.safetensors` | `dump_sensenova_backbone_golden.py` | `tests/backbone_parity.rs`, `tests/quant_smoke.rs` | dense dual-path Qwen3 backbone (sc-3182). |
| `vision_golden.safetensors` | `dump_sensenova_vision_golden.py` | `tests/vision_parity.rs` | Conv patch-embed vision tower (sc-3183). |
| `fm_golden.safetensors` | `dump_sensenova_fm_golden.py` | `tests/fm_parity.rs` | flow-matching head + sampler (sc-3184). |
| `runtime_golden.safetensors` | `dump_sensenova_runtime_golden.py` | `tests/runtime_parity.rs` | AR KvCache + decode runtime (sc-3187). |
| `t2i_golden.safetensors` | `dump_sensenova_t2i_golden.py` | `tests/t2i_parity.rs`, `tests/it2i_parity.rs` | T2I denoise (synthetic). |
| `t2i_realweight_golden.safetensors` | `dump_sensenova_t2i_realweight.py` | `tests/t2i_realweight.rs`, `tests/it2i_realweight.rs` | T2I real-weight e2e (sc-3188). |
| `it2i_golden.safetensors` | `dump_sensenova_it2i_golden.py` | `tests/it2i_parity.rs` | image-edit / Character (synthetic, sc-3189). |
| `it2i_realweight_golden.safetensors` | `dump_sensenova_it2i_realweight.py` | `tests/it2i_realweight.rs` | image-edit real-weight e2e. |
| `vqa_golden.safetensors` | `dump_sensenova_vqa_golden.py` | `tests/vqa_parity.rs` | VQA token stream (synthetic, sc-3191). |
| `vqa_realweight_golden.safetensors` | `dump_sensenova_vqa_realweight.py` | `tests/vqa_realweight.rs` | VQA real-weight greedy decode. |
| `interleave_golden.safetensors` | `dump_sensenova_interleave_golden.py` | `tests/interleave_parity.rs` | interleaved doc gen (synthetic, sc-3190). |
| `interleave_realweight_golden.safetensors` | `dump_sensenova_interleave_realweight.py` | `tests/interleave_realweight.rs` | interleave real-weight e2e. |
| `distill_golden.safetensors` | `dump_sensenova_distill_golden.py` | `tests/distill_parity.rs` | fast 8-step distill-LoRA merge (sc-3192). |
| `fast_realweight_golden.safetensors` | `dump_sensenova_fast_realweight.py` | `tests/fast_realweight.rs` | fast variant real-weight e2e. |

### Chroma (`mlx-gen-chroma`, epic 3531)

FLUX-derived DiT with a distilled-guidance Approximator; T5-only conditioning. Dumped from the
diffusers `ChromaPipeline` reference.

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `chroma_tiny_io.safetensors`, `chroma_tiny_weights.safetensors` | `dump_chroma_golden.py` | `tests/transformer_parity.rs`, `tests/approximator_parity.rs`, `tests/adapter_routing.rs` | tiny synthetic DiT + Approximator forward (+ LoRA/LoKr routing). |
| `chroma_text_mask.safetensors` | `dump_chroma_text_mask_golden.py` | `tests/text_mask_parity.rs` | MMDiT text-mask construction. |
| `chroma_e2e.safetensors` (`_hd`/`_base`/`_flash`) | `dump_chroma_e2e_golden.py {hd,base,flash}` | `tests/e2e_real_weights.rs` | full e2e parity for all three variants. |
| _(tokenizer build, no golden)_ | `build_chroma_t5_tokenizer.py` | — | materializes the T5 `tokenizer.json` into the snapshot `tokenizer/` dir. |

### Mage-Flow (`mlx-gen-mage` / `candle-gen-mage`, sc-14036 / epic 14034)

Unlike every other family here, the Mage-Flow reference is **vendored in-tree** at
`../../_vendor/mage_flow/` (microsoft/Mage, MIT — see `../../_vendor/VENDORED.md` for the pinned
upstream commit, the exact env pins, and the license rationale), so the oracle survives a
model-card/repo pull. One staged harness
(`dump_mage_flow_golden.py --stage {noise,vae,te,dit_block,dit,e2e,edit,all}`) loads the
pipeline once per repo at a fixed prompt/seed/geometry; the `dit_block` and `dit` goldens are
hook-captured during the `e2e` denoise. The reference runs **bf16** end to end (hard-coded in
`load_from_repo`); tensors are stored upcast to f32.

Build the pinned venv per `../../_vendor/VENDORED.md`, then:

```sh
cd crates/media/mlx-gen
MAGE_DEVICE=cpu /tmp/mageflow-ref-venv/bin/python tools/dump_mage_flow_golden.py --stage all
```

Weights: `microsoft/Mage-Flow` (gen) and `microsoft/Mage-Flow-Edit` (edit) from the HF cache, or
`$MAGE_SNAPSHOT` / `$MAGE_EDIT_SNAPSHOT`. **`MAGE_DEVICE=cpu` is mandatory on macOS, and the
default is auto-select, which picks MPS** — always pass it. An MPS dump is *silently* corrupt:
`neg_txt` — the packed negative's post-drop tail — comes out corrupted while the
`gen_hidden_full` tail it must equal is intact. The magnitude is stable (max_abs 61.4342,
reproducible across three runs); the *signature* is not — the bad tail has been observed both
zero-filled and as non-zero garbage, so do not bisect by looking for all-zero rows. The live
torch tensors agree in-process, so the corruption is in the MPS→CPU copy. Nothing raises —
`verify_mage_flow_golden.py` is what catches it. Do not treat the DiT's separate *loud* MPS
failure (`repeat_interleave` with int32 repeats) as a guard: it only fires when the pack has ≥2
segments, so at `cfg <= 1` an MPS run completes the whole stack and writes real images. CUDA
hosts should use the default `MAGE_ATTN=flash2` with `flash-attn==2.8.3`. ~7 min for the
256²/4-step gen stack on an M-series CPU.

| golden | dump script stage | consumed by (P1–P4) | notes |
|---|---|---|---|
| `mage_flow_noise_golden.safetensors` | `--stage noise` | Gaussian-Shading noise parity | **Weight-free** — runs anywhere. The initial latent is `mage_latent.encode_noise` (payload `"MageFlow"`, 256 bits, key 20260720), NOT `randn`: the reference computes a plain seeded `randn` and throws it away. Dumps `gs_noise` **and** `plain_randn` so the port asserts a match against one and a mismatch against the other, plus `gs_noise_bf16` (what the pipeline actually feeds the denoise loop — compare the e2e `traj_step0` against *this* one, not the f32 tensor) and the key-schedule internals (`msg_bits`/`pad_tiny`/`pos_tiny`) for bisection. Small + fast — candidate to promote into `tests/fixtures/`. |
| `mage_flow_vae_golden.safetensors` | `--stage vae` | Mage-VAE encode/decode parity | Needs only `vae/` (~0.5 GB). Encode is a single forward at t=0 with zero `z_t`; dumps `enc_mean` + `enc_logvar` (the pipeline's edit path samples the posterior off the global RNG, which no port reproduces — gate the moments) and `enc_latent` (the deterministic mean branch). Decode is dumped twice: from the real encoded latent and from a seeded synthetic one, so a broken encoder can't mask a broken decoder. |
| `mage_flow_vae_f32_{256,1024,2048,512x2048,768x1280,768x1152}.safetensors` | `dump_mage_vae_sizes.py` | Mage-VAE **decode parity at every geometry** (sc-14039) | Same tensor names as the bf16 bundle above, so `mlx-gen-mage/tests/vae_decode_real_weights.rs` reads both through one path — but dumped in **f32**, for two reasons. (1) It is the *tighter* oracle: the bf16 bundle's residual is dominated by the reference's own rounding, while f32-vs-f32 isolates the port's error (measured: mean_abs 1.7e-4 vs bf16's 2.0e-3 at 256²). (2) torch's CPU bf16 kernels here are effectively single-threaded — a 1024² `--stage vae` run takes ~35 min and 2048 hours, while the whole f32 sweep takes ~30 s, which is what makes the DoD's explicit **2048** large-decode check practical. Keep both: the bf16 bundle measures production fidelity, the f32 bundle measures the port. The **non-square** entries are not extras: every square geometry hides a transposed h/w, and `768x1152` (a 48x72 latent) is the only geometry here whose two attention pads **differ** (16 on h, 24 on w). Everything else pads its axes equally — 256² and `768x1280` both (16,16), and 1024²/2048/`512x2048` not at all — so a `pad_h`/`pad_w` swap survives all of them and is caught only by `768x1152`. |
| `mage_flow_vae_f32_{768,992,1056}.safetensors` | `dump_mage_vae_sizes.py` | bisection witnesses for the **2^20-pixel precision step** (sc-14039) | MLX's decode error is **not flat in resolution**: it steps ~2x at exactly `H*W = 2^20`, and follows *pixel count*, not side length. `dec_from_latent` mean_abs: 768² 0.000255, 768x1280 0.000250, **992² 0.000250 -> 1024² 0.000535**, 1056² 0.000519, 2048² 0.000460; `512x2048` is the tell — same 1.05 MP as 1024², totally different shape, same stepped error. Benign (spatially uniform across the step; not padding-driven, since 1056² pads and stays high while 992² pads and stays low) — MLX kernel selection, not a defect. **Consequence: every production geometry is >=1 MP, i.e. above the step, so headroom there is ~2.0x on both bounds, NOT the ~9x the 256² row implies. Calibrate `RefDtype::tolerance` against 1024².** `992` is kept in the suite's `GEOMETRIES` as the just-below witness so the step stays visible in CI output. |
| `mage_flow_te_golden.safetensors` | `--stage te` | Qwen3-VL conditioning parity | Both templates in one file. `gen_*` = `mage-flow` (drop_idx 34), `edit_*` = `mage-flow-edit` (drop_idx 64, with `pixel_values`/`image_grid_thw` through the VL vision tower). `*_hidden_full` is the **pre-drop** hidden state (final 36th layer, **after** the final RMSNorm — not the penultimate layer) and `*_txt` the post-drop slice, so "wrong layer" and "wrong drop_idx" are distinguishable failures. |
| `mage_flow_dit_block_golden.safetensors` | `--stage dit_block` | one NR-MMDiT dual-stream block | Hook-captured on `transformer_blocks[0]` at e2e step 0 — real post-embed inputs (`block_in.*`) + outputs (`block_out.*`), so no patchify/RoPE/time-embed wiring is hand-replicated. The msrope table is **complex**, split into `block_in.image_rotary_emb_re`/`_im` (an `f32` cast would silently drop the imaginary half). It also pins a trap: under `batch_cfg` the duplicated uncond half is rotated at msrope **frame index 1**, not 0, so the fused CFG path is *not* numerically identical to two separate forwards — see `../../_vendor/MAGE_FLOW_GAPS.md` (GAP 3). |
| `mage_flow_dit_golden.safetensors` | `--stage dit` | full 12-block stack | Hook-captured on the whole `transformer` at step 0: raw `img`/`txt`/`timesteps`/`img_cu_seqlens`/`txt_cu_seqlens` + `img_shapes` in, **pre-CFG** velocity out (the CFG combine happens downstream in `_velocity`). `img_shapes` is the msrope coordinate table. |
| `mage_flow_e2e_golden.safetensors` (+ `.png`) | `--stage e2e` | txt2img e2e | Final tokens + `final_latent` (captured by wrapping `_decode_one`, which is otherwise the only place the final latent is observable) + decoded `image_u8`, plus `traj_step0/1` (the batch-CFG-doubled latent entering steps 0 and 1 — `traj_step0`'s first half must equal the `noise` golden's `gs_noise`). Also carries the `sigmas_4`/`sigmas_30` schedules: **Turbo is the same static-shift formula at N=4**, there is no separate distilled timestep table. |
| `mage_flow_edit_golden.safetensors` (+ `.png`) | `--stage edit` | instruction-edit e2e | Needs the **Edit** repo. `seq_step0` is the literal assembled image stream — `[noisy_target, ref_1, …]`, target FIRST, refs clean and re-concatenated every step, doubled by `batch_cfg` — and `img_shapes` is one `(frame_count, h, w)` row per segment, in the order `[target, ref_1, …]` then the `batch_cfg` duplicate. The msrope **frame index** is the row's *position* in that list (target 0, ref_j j), not the `frame_count` column, which is always 1. |

After dumping, run the companion checker — it needs only numpy + safetensors (no torch, no
weights, no reference checkout):

```sh
python tools/verify_mage_flow_golden.py
```

It asserts two kinds of invariant. **Structural** ones cover shapes, ranges, drop indices and
the schedule ladder. **Payload** ones recompute or cross-derive the actual numbers, so they fail
if a tensor is replaced by shape- and moment-matched noise, rescaled, or captured at the wrong
point — the failure a golden is worst at surfacing, because every downstream parity test would
then happily "match" the wrong thing:

- `traj_step1 == traj_step0 + (σ1−σ0)·(unc + cfg·(cond−unc))` — the DiT velocity, the CFG
  combine and the Euler step, closed over three files; the check also proves it discriminates by
  re-scoring the cond-only / uncond-only / swapped / no-step combinations;
- the msrope table **recomputed in numpy** from `img_shapes` + `theta=10000` +
  `axes_dim=[16,56,56]`, which also pins the batch_cfg frame-index shift (segment *j* rotates at
  frame *j*: cond is exact identity, the duplicated uncond half is frame 1);
- `dit_in.txt == cat(gen_txt, neg_txt)` **bit-for-bit** — the conditioning the transformer
  actually consumed is the dumped TE output, which is what pins GAP 1 (final post-RMSNorm, not
  penultimate); backed by a per-token RMS envelope that a rescaled wrong-layer capture fails;
- `dec_from_latent` reconstructs `pixels` (encode→decode round-trip), `enc_mean`'s channels track
  the input image, and the `edit` golden's ref segment correlates with that same `enc_mean`;
- `final_tokens` ↔ `final_latent` reshape identity, plus "this latent is the one that decoded to
  `image_u8`";
- cond/uncond halves of `dit_out` and `block_out.1` stay near-collinear, and both block outputs
  are heavy-tailed activations rather than Gaussian noise.

Missing goldens are a **failure**, not a skip (they are gitignored, so "absent" is the state of a
fresh clone and a checker that greens there greens when it verified nothing); pass
`--allow-missing` to check a partial bundle deliberately, and `--golden DIR` to point it
elsewhere.

**Turbo / `cfg <= 1` bundles are supported.** Every CFG-dependent invariant is gated on the real
branch count, because at Turbo's documented default of cfg 1.0 the reference never builds the
negative branch (`pipeline.py:326`, `:535`): the image stream is not duplicated, `img_shapes` is
not concatenated, `dit_in.txt` is the positive conditioning alone, and `_velocity` returns the
raw transformer output. A checker written as if the stream were always doubled would reject a
*correct* Turbo golden outright — and at cfg exactly 1.0 the combine `unc + 1·(cond−unc)` equals
`cond`, so its "only this combination fits" assertion would be false by construction. The CFG-off
path therefore falls back to the single-branch Euler identity `traj_step1 == traj_step0 +
(σ1−σ0)·dit_out`, scored against a dropped step, a sigma off-by-one, a sign flip and a missing
Δσ — a real check, not a skip. Verified end to end against a cfg=1.0 / 4-step CPU bundle: 71/71
invariants hold, and `--self-test --golden <that bundle>` rejects all 9 corruptions.

The discrimination claim is itself executable — a checker that has never been shown to fail is
not evidence of anything:

```sh
python tools/verify_mage_flow_golden.py --self-test
```

It corrupts a scratch copy one tensor at a time (moment-matched, and with any structural
invariant the mutation would otherwise trip deliberately repaired: `enc_latent` stays equal to
`enc_mean`, `final_latent` is re-derived from the corrupted `final_tokens`, the randomized msrope
keeps unit modulus and matched spatial halves, the rescaled TE keeps its slice relation) and
asserts every one is rejected while the pristine bundle passes.

The six epic-14034 GAP answers these goldens pin (TE layer index, latent scale/shift,
`axes_lens`/msrope coords, Turbo timesteps, edit ordering, training timestep distribution) are
written up with `file:line` citations in `../../_vendor/MAGE_FLOW_GAPS.md`.

### Weight-independent

| golden | dump script | consumed by | notes |
|---|---|---|---|
| `pil_resize_golden.safetensors` | `dump_pil_resize_golden.py` | `src/image.rs` (`resize_bicubic_matches_pil`) | Only needs Python + PIL (no model weights). Candidate to shrink + promote into `tests/fixtures/` so its test can run un-`#[ignore]`d on any clone. |

## `CHECKSUMS.txt`

SHA-256 of the goldens the **currently committed tests were last validated against**, as a
regression tripwire: after regenerating, `shasum -a 256 -c CHECKSUMS.txt` flags an unexpected
change. Caveats — re-bless (regenerate the file) deliberately when:
- the MLX version changes (precision drift; see sc-2517), or a scheduler/port fix changes outputs;
- you regenerate at a different resolution/seed/steps than the committed baseline.

A mismatch across a *different machine/GPU* is possible (Metal float results aren't guaranteed
bit-identical cross-device) and isn't necessarily a bug — treat `CHECKSUMS.txt` as "what this
baseline produced," not a hard cross-machine contract. Only the goldens present when the file was
generated are listed.

> **Coverage caveat (F-153):** the committed `CHECKSUMS.txt` was last blessed against the
> Z-Image / Qwen / FLUX.2 / SDXL families, plus the seven Mage-Flow goldens appended under
> sc-14036. It still does **not** list the LTX, Wan-VACE, SVD, SenseNova or Chroma goldens
> documented in the manifest above. It can only be regenerated on a machine that actually holds
> the (gitignored, weights-dependent) goldens. **Re-bless from the full directory** so every
> family is covered, rather than hand-editing a subset:
>
> ```sh
> cd tools/golden && shasum -a 256 *.safetensors > CHECKSUMS.txt   # after a full re-dump
> ```
>
> **Only run that after a genuinely full re-dump.** `>` truncates, so on a host holding a subset
> of the directory it silently *deletes* every row it cannot see. sc-17651 regenerated only the
> 11 sc-15505 artifacts out of the ~76 rows listed here; re-blessing from the directory would
> have dropped the other 65, so that review hand-edited the single changed line instead. Editing
> the affected rows is the correct move whenever you re-dumped less than everything.
>
> Until that next full re-dump, the `shasum -c` tripwire silently passes for any family it doesn't
> list — so the manifest above is the source of truth for *what should exist*. The byte tripwire
> is also single-purpose: it fires on *any* change, including a legitimate re-dump, and says
> nothing about whether the bytes it pins are correct. For Mage-Flow that second question is
> answered by `tools/verify_mage_flow_golden.py`, which recomputes the payload (the msrope table,
> the Euler step, the reshape) and cross-derives the rest between files — so it survives a
> legitimate re-dump while still rejecting a bundle whose tensors were replaced by shape- and
> moment-matched noise, rescaled, or captured at the wrong boundary.
