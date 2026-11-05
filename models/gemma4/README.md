# Gemma 4

Google's Gemma 4 models for on-device inference via Core AI (iOS).

## Supported Models

| Model                                          | Parameters | iOS         |
| ---------------------------------------------- | ---------- | ----------- |
| Gemma 4 E2B Instruct                           | 5.0B       | Yes (27.2+) |
| Gemma 4 E4B Instruct                           | 8.0B       | Yes (27.2+) |
| Gemma 4 E2B Instruct (QAT mobile transformers) | 5.0B       | Yes (27.2+) |

These are the Gemma 4 checkpoints sized for a phone. They export through the
standalone [`export.py`](export.py) rather than the generic `coreai.llm.export`
pipeline, for two reasons: the blocked attention's graph depends on the context
length, so each context bucket is traced as its own static graph, and the
Per-Layer Embeddings (PLE) table is dumped as a sidecar next to the asset.

The `-qat-mobile-transformers` checkpoints are the same architecture, trained
with Google's own quantization-aware training and shipped with `nn.Linear` /
`nn.Embedding` replaced by packed INT2/4/8 weights (see
`transformers.integrations.gemma_quant`). The export carries those exact
quantized values straight into CoreAI's own native quantized weight format
(`coreai.blockwise_shift_scale`, driven by
`coreai_torch`'s `constexpr_blockwise_shift_scale`) instead of dequantizing and
re-palettizing them -- no dequantize/requantize round-trip, and k-means
palettization is skipped entirely for these checkpoints (their weights are
already CoreAI-natively quantized). Attention/MLP/`lm_head` weights all keep
native packing in the exported graph, but not always as affine
`blockwise_shift_scale`:

- CoreAI's affine `blockwise_shift_scale` has no execution path on the
  static-shape engine below INT4 -- the compiler silently promotes anything
  declared INT2 back up to INT4 at compile time. `lm_head` is always declared
  INT4 rather than INT2 up front, so the exported asset's size is honest about
  what actually ships. The `embed_tokens` table is a runtime input of the
  gather, and the runtime cannot gather from a sub-byte tensor, so its 2-bit
  values are kept one per INT8 element (the same layout as the standard
  table) with their per-row scale.
- Some checkpoints (E2B, but not E4B) genuinely ship INT2 weights for the MLP
  of their shared-KV/double-wide layers (`config.native_mlp_nbits`, read
  per-layer from each `QuantizedLinear.num_bits`). For those layers only,
  the MLP's `gate_proj`/`up_proj`/`down_proj` are exported as LUT
  palettization (`coreai.lut_to_dense` decoding a 4-entry table) instead of
  affine quantization, since that's the only way to realize genuine sub-4-bit
  density on the static-shape engine -- affine INT2 there would just be
  promoted back to INT4 by the compiler, as above, silently doubling that
  layer's on-device size.
- `lm_head`'s output dimension (vocab size, 262144) exceeds the static-shape
  engine's per-op tensor size limit, so it's exported as a `nn.ModuleList` of independently
  quantized output-dimension blocks (`DEFAULT_KV_BLOCK_SIZE` each) rather
  than one big quantized matmul -- each block needs its own state-dict
  buffers (not a slice of one shared buffer) for CoreAI's converter to
  promote it to genuinely packed sub-byte constants; a shared/sliced buffer
  silently falls back to a full-byte container instead of erroring.

The externalized PLE table sidecar keeps Google's packed INT2 rows as
shipped, unpacked and dequantized directly by the runner
(`PerLayerEmbeddings.swift`) rather than the graph, so the graph takes a plain
float16 input for it.


## Gated Access

These Gemma 4 models are gated on [Hugging Face](https://huggingface.co/google/gemma-4-E2B-it) (HF). Before you export, accept the [license](https://huggingface.co/google/gemma-4-E2B-it), make an HF token, and add the token to your machine.

```bash
brew install hf
hf auth login --token <YOUR_TOKEN_HERE>
```

## Setup to export models

If you don't have `uv` yet, install it:

```bash
brew install uv
```

Then, from the repo root:

```bash
uv sync
```

## Export models

[`export.py`](export.py) runs directly rather than through `coreai.llm.export`.
It runs in the workspace environment, so `uv sync` is all the setup needed. Run it
from this directory:

```bash
cd models/gemma4
uv run export.py --model google/gemma-4-E2B-it
```

> **Note:** The export defaults to a mixed-precision 4-bit palettization recipe
> shipped alongside the script,
> [`4bit_palettized.yaml`](4bit_palettized.yaml). iOS requires
> `float16` and defaults to a 131072 context, which is also its maximum. Bigger
> contexts cost export time and program size, so pass `--max-context-length` (a
> power of two) if you need less.

**Options:**

```bash
# Other variant
uv run export.py --model google/gemma-4-E4B-it

# QAT mobile-transformers checkpoints (quantization-aware-trained; kept quantized)
uv run export.py --model google/gemma-4-E2B-it-qat-mobile-transformers

# No palettization. The embedding and PLE tables are still 8-bit quantized.
uv run export.py --model google/gemma-4-E2B-it --compression none

# Your own compression recipe
uv run export.py --model google/gemma-4-E2B-it --compression-config my_palett.yaml

# Cap the context to reduce export time and program size
uv run export.py --model google/gemma-4-E2B-it --max-context-length 8192

# Custom output directory
uv run export.py --model google/gemma-4-E2B-it --output-dir ./my-models/
```

The export follows the standard iOS flow (`coreai_models.export.ios`), except
that each transformer (context bucket, query length) pair is traced as its own
fully static program, `extend_{ctx}_{q}` / `prompt_opt_{ctx}_{q}`: the blocked
attention unrolls its block loop, so the graph depends on the context length. A
flat global KV cache is paired with a fixed-depth sliding-window ring, RoPE
arrives precomputed as `rope_cos`/`rope_sin` inputs, and the Per-Layer
Embeddings table is written as a sidecar next to the asset (INT8 per-tensor for
the standard checkpoints; for the QAT checkpoints, the checkpoint's own packed
low-bit rows plus a scale per layer in each row).

## Note on AOT Compilation

Due to a known issue with coreai-build in Xcode 27.2 beta, Ahead-of-time compilation is not supported for this model. Please use on-device specialization from .aimodel directly.

### Image input (vision)

Pass `--include-vision` to also export a vision encoder into the bundle,
upgrading it to `kind:vlm`:

```bash
uv run export.py --model google/gemma-4-E2B-it --include-vision
```

The vision encoder is a ladder of canvas-size buckets, not one fixed
resolution: at runtime, an input image is letterboxed (aspect-preserving
resize + zero-pad, never upscaled) into the smallest bucket that fits it, and
the padding is masked out of attention. Options:

```bash
# Custom bucket ladder (px), smallest first. Each must be a multiple of
# patch_size * pooling_kernel_size (48 for E2B/E4B) so padding stays
# pool-block-aligned. Defaults to 384/768/1152.
uv run export.py --model google/gemma-4-E2B-it --include-vision \
  --vision-image-sizes 384,768,1152

# Compression for the vision tower (default matches the text decoder's
# 4-bit palettization). Use 'none' to ship the tower at fp16.
uv run export.py --model google/gemma-4-E2B-it --include-vision \
  --vision-compression none
```

### Draft head (speculative decoding)

A Gemma 4 assistant checkpoint can be exported as a draft head that proposes tokens for the
exported model. Export the model with its final hidden state as an extra decode output, then add
the draft head to the bundle:

```bash
uv run export.py --model google/gemma-4-E2B-it --emit-hidden-states
uv run export_drafter.py --model google/gemma-4-E2B-it --bundle <bundle>
```

The assistant is the target's own, `<model>-assistant` on the hub (`google/gemma-4-E2B-it-assistant`
for E2B, `google/gemma-4-E4B-it-assistant` for E4B). `export_drafter.py` downloads its safetensors
and `config.json` on first use. `--drafter` takes another hub repo id or a local directory instead.
An assistant is trained for one target, so the script refuses one whose hidden size does not match
`--model`. `--bundle` takes the bundle that `export.py` wrote with `--emit-hidden-states`; the
script refuses a bundle exported without it.

`--emit-hidden-states` makes the decode graphs return their post-norm final hidden state as a
second output, `hidden_states`, and records `language.overrides.emits_hidden_states` in the bundle
metadata. The default export is unchanged.

Pass the same `--max-context-length` to `export.py` and `export_drafter.py`: the head's full-attention
layer covers up to that length, and a head exported for more than the target needs is a larger program.
The other speculative decoding options are described under
[Speculative Decoding](../README.md#speculative-decoding).

`export_drafter.py` exports the head's layer stack as one static-shape program, `draft_step.aimodel`,
with one function per context bucket of the target export's ladder, up to `--max-context-length`.
The token-embedding lookup and the candidate scan stay outside the program, over
`draft_scan.bin`. `--bundle` copies the files into the bundle and declares them as the `drafter`
component: the program under `assets.drafter`, and `drafter_config`, `drafter_scan` and
`drafter_scan_index` under `auxiliary_assets`. It also sets `speculative.drafter_kind` to `mtp`,
because other drafters use the same `drafter` asset key with different semantics; `--bundle`
refuses a bundle that already declares one. `draft_step.json` also records what the head expects of
the target (the hidden-state output name, an unscaled token embedding, and K/V from the target's
last storing layer) under `contract`, and the runner refuses a head whose expectations it does
not implement. The head attends to the target's K/V in the most
recent 512 positions in its sliding layers and to the whole context in its full-attention layer.

Run the model with its draft head through `llm-runner --speculative`:

```bash
llm-runner --model <bundle> --sampling-strategy greedy --speculative --prompt "..."
```

The head and the target live in the same bundle, so `--speculative` takes no separate path. The
output is token for token what greedy decoding of the target alone produces; the head only changes
how many tokens one verify pass of the target commits. The runner needs greedy decoding, a bundle
with a `drafter` of kind `mtp`, and a target exported with `--emit-hidden-states`, and it says which
of the three is missing. `--speculative` combines with `--prompt-lookup` (a block whose recent
tokens recur in the context is proposed by lookup, any other by the head) and with `--json-schema`.
`--num-draft-tokens` sets the drafts per round; by default a round drafts one less than the target's
verify tile is wide, and `--no-align-proposals` drops that limit. `--drafter-top-k` sets how many
centroids the head's candidate scan scores.

The run summary reports the share of drafts accepted and the tokens committed per target pass, then
the same timing summary as a plain run.

### Runner side

There is no Gemma-specific engine. The generic static-shape engine drives these
assets, wiring up handlers from what the graph declares plus the bundle
metadata: precomputed dual-RoPE rows (`language.overrides.rope`), the
sliding-window mask and ring write offset (`language.overrides.sliding_window`),
the final-logit soft cap applied before sampling
(`language.overrides.final_logit_softcapping`), and the per-layer embeddings
gather (`auxiliary_assets.per_layer_embeddings`). The global KV cache is classified as
per-bucket automatically — its backing buffer varies across the ladder — so it is
allocated at the running context bucket and re-laid-out as decode grows into
larger ones, while the fixed-depth sliding ring is allocated once. For the QAT
checkpoints, the embedding table carries a companion per-row `embedding_scale`
tensor (an additive extension to the `load_embeddings`/`gather_embeddings`
contract — absent for the standard checkpoints), and the PLE sidecar's rows are
unpacked and dequantized directly by the runner rather than the graph.

## Run a Core AI Language Model

Exports land in `<repo-root>/exports/` unless you pass `--output-dir`.

### In your iOS applications via Foundation Models

```swift
import FoundationModels
import CoreAILanguageModels

let model = try await CoreAILanguageModel(resourcesAt: modelURL)

let session = LanguageModelSession(model: model)

let response = try await session.respond(to: "What is quantum computing?")

print(response)
```

### On your Mac using built-in Command Line Tool

```bash
swift run -c release llm-runner --model path/to/exported_model_folder --prompt "Hello"
```

For a bundle exported with `--include-vision`, pass `--image`:

```bash
swift run -c release llm-runner --model path/to/exported_model_folder \
  --image path/to/photo.jpg --prompt "Describe this image."
```

## Benchmark a Core AI Language Model

```bash
swift run -c release llm-benchmark --model path/to/exported_model_folder
```

Defaults: 512 prompt tokens, 1024 generation tokens, 5 trials. Override with `-p`, `-g`, and `-n`.

## Evaluation

| HF ID | MMLU (BF16) | MMLU (4-bit palettized, 8-bit PLE) |
| --------------------- | ----------- | ---------------------------------- |
| google/gemma-4-E2B-it | 0.5752 | 0.5240 |
| google/gemma-4-E4B-it | 0.6995 | 0.6546 |
