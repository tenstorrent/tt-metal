# Mistral-Small-4-119B (mistral4) on Tenstorrent Blackhole

`mistralai/Mistral-Small-4-119B-2603` — a **Mistral3 VLM**: a Pixtral vision tower + a
**DeepSeek-V3-class text core** (Multi-head Latent Attention + 128-expert ungrouped top-4 MoE +
1 shared expert), fp8 weights, YaRN RoPE, 36 layers, hidden 4096, vocab 131072. Target:
**Blackhole Loudbox 1×8 (P150x8)**.

> Status: **Correctness complete end-to-end** (every block PCC-verified on P150x8, generic ttnn ops,
> no new kernels) and the **production decode path is captured as a bit-exact trace on the sharded
> 8-device mesh** with on-device sampling. Perf is measured at full depth (below), including the
> **compressed-latent KV decode path that reaches 64K context at 36 layers** (25.6× smaller KV; the
> expanded-kv default OOMs beyond ~8K). Remaining serving optimizations (2CQ, compressed-cache prefill
> fill to make the long-context path the default) are listed under **Current status**.

## Architecture / where the code lives
- **Text core (MLA + MoE)** — model-local modules (`tt/mistral4_text.py`) from generic ttnn ops:
  - **MLA**: low-rank q/kv projections + RMSNorms, interleaved RoPE applied as a permutation-matrix
    matmul (de-interleave → rotate_half, no tile-crossing reshape), MQA k_rot expand, SDPA, o_proj.
    Because HF MLA caches the **expanded** k/v, decode is standard attention — so decode uses
    `ttnn.transformer.scaled_dot_product_attention_decode` over an expanded-kv cache, and the KV write
    uses `paged_update_cache(update_idxs_tensor=…)` with a device-resident position (trace-friendly).
  - **MoE**: router (linear → softmax → top-4/128 kth-threshold mask → normalize) + SwiGLU experts +
    shared expert. Experts are **sharded across the 8 devices** (16/device, `bfloat8_b`); each device
    extracts its local experts' routing weights **on-device** via a precomputed sharded column selector
    (`W_full @ select_d`), and partial sums combine with `all_reduce_async` — no host round-trip, so
    the whole MoE is trace-capturable.
- **Generator** (`tt/mistral4_generator.py`) — a compact model-local generator (deepseek_v3-demo
  pattern, not the GQA-bound `tt_transformers` Generator): parallel prefill (fills the KV cache via
  `fill_cache`) → token-by-token decode with **on-device `ttnn.argmax`** sampling. `TracedDecode`
  captures the decode step as a replayable trace (persistent device input buffers + `execute_trace`).
- **Vision tower + projector** — reuse the `tt_transformers` Pixtral path (config-driven; bf16).
- **fp8** — vanilla per-tensor + per-expert `scale_inv` dequant (`dequantize_fp8_state_dict`), distinct
  from transformers' block-wise FineGrainedFP8. Experts run on-device as `bfloat8_b` (≈ the native fp8).

## Measured PCC (TT vs HF reference, P150x8)
| Component | PCC |
|---|---|
| Vision tower (Pixtral, 24 layers, bf16) | 0.9987 |
| MLA attention block (full) | 0.99976 |
| MoE block (router+experts+shared) | 0.99980 |
| MoE block, expert-sharded 16/device | 0.99980 |
| Decoder layer (norms+MLA+MoE+residuals) | 0.99928 |
| Projector (Mistral3 multi-modal) | 0.99991 |
| **Full-depth 36-layer logits** | **0.98164** |
| End-to-end VLM logits (vision→projector→text) | 0.99762 |
| MLA decode (op) / forward_decode + KV cache | 0.99988 / 0.99971 |
| 2-layer model decode (incremental) logits | 0.99804 |
| **Decode trace capture/replay (replicated & sharded)** | **1.0 (bit-exact)** |
| Greedy generation IDs vs HF (free-running) | 7/8 match |
| fp8 dequant loader | 3 CPU unit tests pass |

Full-depth 0.9816 reflects bf16 + bfp8-expert + bf16-routing error accumulating over 36 layers
(`ttnn.topk` is bf16/bfp8-only, so a borderline expert can flip vs the fp32 reference); all per-block
PCCs are ~0.999. Passes the >0.98 full-depth gate.

## Performance (measured, P150x8, full 36 layers, sharded bfp8, steady-state, traced)

**Prefill** (batch-1; single-shot ≤4K, chunked beyond):

| ISL | 128 | 1024 | 4096 | 8192 (chunked) |
|---|---|---|---|---|
| TTFT | 222 ms | 632 ms | 2587 ms | 7.8 s |
| prefill tok/s | 576 | 1619 | 1584 | ~1050 (217 ms/layer) |

CCL ops (MoE all-reduce, LM-head all-gather, sparse all-to-all) use **both** of the P150x8's ethernet
links per axis (`num_links = get_num_links(mesh)`), which lifts prefill ~2–3.5% over the single-link
default; B=1 decode is unchanged (its all-reduce payload is latency-bound, not bandwidth-bound).

Largest full-depth ISL = **8192** (chunked prefill). 16384 runs at reduced layer counts but **OOMs at 36L**
(the per-layer paged KV caches + 119B weights exceed DRAM) — a paged-cache memory-management follow-up.

**Decode — throughput vs batch** (captured trace, B=1 measured device + E2E):

| batch | tok/s/user | tok/s aggregate | ms/step |
|---|---|---|---|
| 1 | **9.3** (device; 8.6 E2E) | 9 | 108 |
| 32 — dense MoE | 1.34 | 43 | 741 |
| 32 — **sparse MoE** | 1.88 | **60** (**+39.2%** vs dense) | 532 |

**Decode — throughput vs context** (batch-1, decoding at `cur_pos = ctx`; latency rises only gently as
context grows because decode is dominated by MoE weight streaming, not attention). Two KV-cache paths:

| ctx | 128 | 2048 | 4096 | 8192 | 32768 | 65536 |
|---|---|---|---|---|---|---|
| **expanded-kv** tok/s/user (default) | 9.2 | 9.0 | 8.8 | 8.3 | OOM | OOM |
| **compressed-latent** tok/s/user (A6) | 9.2 | 9.2 | 9.1 | 9.1 | 8.8 | **8.5** |
| compressed-latent ms/step | 108 | 109 | 110 | 110 | 113 | 117 |

(All cells measured at the full 36 layers, B=1.)

The **expanded-kv** path (HF-style — caches per-head k+v = 2·n_heads·qk = **16 KB/token/layer** = 576
KB/token across 36 layers/device) is the wired default, but the 119B fp8 weights leave little DRAM so it
OOMs beyond ~8K. The **compressed-latent** path (`forward_decode_mla` + `TracedDecodeMLA`: caches only the
MLA latent kv_lora+rope = 320 = **640 B/token/layer**, **25.6× smaller**) reaches **65536 at the full 36
layers** — ≈1.4 GB of KV/device vs ≈36 GB for expanded (which would OOM) — at the **same tok/s**: only
**~9% slower from 128 → 65536**, a **512× context increase**. This is the A6 unlock: it lifts the decode
context ceiling from ~8K to **≥64K** on the 1×8 mesh. Numerically verified — op 0.99974, live single-MLA
0.99974, 2-layer model 0.9978 (`test_m4_mla_compressed_decode` / `test_m4_text_decode_compressed`). The
earlier "compressed decode is op-nondeterministic" finding was wrong: it was an undersized cache (the
paged-MLA decode op reads a full `k_chunk_size`=128 window per step, so the cache block must be ≥128;
`init_compressed_cache` now floors it). Expanded-kv stays the default; the compressed path is opt-in
pending a compressed-cache prefill fill + full-depth logit PCC.

At high batch the dense MoE is compute-bound (all 16 local experts × B tokens), so per-user throughput
drops while aggregate rises; **sparse dispatch** (top-4 routed experts) recovers it (+39.2% @B=32). The
sparse win grows with depth (2-layer traced: +13.9% @B=8, +16.9% @B=32 → +39.2% at 36L). Sparse
matches dense logits (PCC 0.9958) and is trace-compatible (capture/replay PCC 1.0); dense is the default,
sparse is opt-in for batched serving.

**MoE sparse dispatch** mechanism (`forward_decode(use_sparse=True)`): `mesh_partition` shards the batch
1/device → `all_to_all_dispatch` routes each token to its top-4 experts' devices → local experts →
`all_to_all_combine` → `all_gather` back. (Perf + PCC in the decode table above.)

**Chunked prefill** (`forward_prefill_chunked`, paged k/v + `chunked_scaled_dot_product_attention`)
processes the prompt in chunk-token windows so L1 holds only one chunk's attention — lifting the
single-shot ~4K L1 cap. PCC 1.0 vs single-shot (`test_m4_chunked_prefill`/`test_m4_text_prefill_chunked`).
At the **full 36 layers it is measured to 8K** (TTFT 7.8 s); **16K runs at reduced layer counts but OOMs
at full depth** (the per-layer paged KV caches plus the 119B weights exceed DRAM) — a paged-cache
memory-management follow-up. Single-shot prefill stays the default ≤4K; generator integration + per-chunk
trace are tracked follow-ups.

**Multi-user batched decode** (traced, dense MoE) trades latency for throughput — the MoE streams
each expert's weights once and applies them to all B tokens, so aggregate tok/s grows with batch
(measured 2-layer; full-depth scales by depth):

| Batch | tok/s/user | tok/s aggregate |
|---|---|---|
| 1 | 133.7 | 134 |
| 8 | 46.2 | 370 |
| 32 | 14.4 | 462 |

Scaling is sub-linear because the dense MoE amortizes weight-streaming but its compute (16 experts ×
B tokens/device) grows with batch. Sparse dispatch (top-4 only) is the remaining lever at both ends —
see status.

## Current status / remaining work
- **Done:** full-depth logit correctness; e2e VLM correctness; on-device sampling; decode trace
  (replicated + sharded production mesh); fully on-device MoE; ISL perf sweep harness + measured
  full-depth numbers; **chunked prefill** (paged k/v, measured to 8K full-depth — lifts the single-shot
  ~4K cap); sharded LM head; **MoE sparse dispatch** (`forward_decode(use_sparse=True)`: `mesh_partition` →
  all-to-all dispatch → top-4 routed experts → combine → all_gather; full-model decode sparse == dense
  logits PCC 0.9958; computes only the 4 routed experts/token vs all 16 local dense).
- **Remaining (optimization/polish):** chunked-prefill **16K at full depth** (paged-cache memory
  management — OOMs at 36L today) + generator integration + per-chunk trace; sparse-decode **generator
  wiring** (sub-device auto-setup; tok/s + trace already done); **paged compressed-latent KV** (12.8×
  smaller cache, op-execution-nondeterministic on this BH build — see A6); **2CQ** (low value). CI
  registration done; rebase onto latest main.
- **Dependency:** requires `transformers >= 5.10` (native `mistral4`/`mistral3`/`pixtral` + fp8 dequant).

## Reproduce
```sh
export HF_MODEL=<Mistral-Small-4-119B snapshot dir>   MESH_DEVICE=P150x8
# correctness — text blocks
pytest models/demos/mistral4/tests/test_m4_mla.py -s
pytest models/demos/mistral4/tests/test_m4_moe_sharded.py -s
pytest models/demos/mistral4/tests/test_m4_decoder_layer.py -s
# full-depth logit gate (one-time ~40-min golden build, cached after)
M4_N_LAYERS=36 M4_SHARD=1 M4_EXPERT_DTYPE=bfp8 pytest models/demos/mistral4/tests/test_m4_text_model.py -s --timeout=0
# e2e VLM + projector
pytest models/demos/mistral4/tests/test_m4_vlm.py models/demos/mistral4/tests/test_m4_projector.py -s
# serving: decode trace (bit-exact), greedy generation, decode/prefill correctness
pytest models/demos/mistral4/tests/test_m4_trace.py models/demos/mistral4/tests/test_m4_generate.py -s
pytest models/demos/mistral4/tests/test_m4_text_decode.py models/demos/mistral4/tests/test_m4_forward_decode.py -s
# perf sweep (full depth)
M4_PERF_LAYERS=36 M4_PERF_ISLS=128,1024,4096 pytest models/demos/mistral4/tests/test_m4_perf.py -s --timeout=0
# fp8 loader (CPU)
pytest models/demos/mistral4/tests/test_m4_fp8_dequant.py
```

## Deps note
`transformers >= 5.10` supports `mistral4`/`mistral3`/`pixtral` natively and provides the fp8 dequant
path. The repo currently pins an older transformers — bumping it is a documented merge prerequisite
(coordinate with sibling model PRs that pin a different major version; they cannot share an env).

## Framework dependency (self-review note)
All mistral4-specific code lives in `models/demos/mistral4/`. To **reuse** the framework rather than
fork it (the model uses tt_transformers' `MistralVisionTower` + `ModelArgs` + checkpoint loaders), the
branch carries generic, backward-compatible additions in `models/tt_transformers/tt/`:
- `load_checkpoints.py` — `dequantize_fp8_state_dict` (vanilla per-tensor/per-expert fp8 → bf16; any fp8 checkpoint benefits);
- `model_config.py` — `_fp8_dequantize_config` + broadening the existing Mistral3 branch from a `Mistral-Small-3.1-24B` name-match to `model_type == "mistral3"` (still matches the 24B; now also Mistral-Small-4) so `ModelArgs` parses the nested Pixtral-VLM checkpoint;
- `common.py` — `_as_token_ids` (normalizes mistral-common tokenizer output; called by model_config's encode path);
- `attention.py` — generic Blackhole WO-prefill chunking by `prefill_len_cutoff` instead of a hardcoded 1024 (a generic L1-CB fix; **not used by mistral4's model-local MLA** — a co-resident generic improvement).

These carry **no mistral4-name-specific branching** (the Mistral3 branch is keyed on `model_type`, generic).
They are shared **framework** work (shared with the Devstral/Mistral3 effort), not mistral4-model code.
**Merge structure:** land these via the shared framework PR (with the **D1c all-models Tier-1/2/3 regression
run** that any tt_transformers change requires) and rebase mistral4's PR on top, so mistral4's own diff is
model-dir-only; or, if co-merged, gate on that regression run. mistral4 adds none of its own edits to shared infra.

## Status snapshot (self-review vs review-ign-model)
Done: A1 framework adherence, A2 device-side (no hot-loop host round-trip), A3 trace — **prefill AND
decode** captured/replayed bit-exactly (PCC 1.0), A5 on-device sampling, A7 sharded LM head, A9 (prefill to
4K, no L1 clash), B1–B3 full-depth ungated logit PCC, C1 ISL-sweep harness, C-perf measured, D1
rebased (current), D1a CI registration, D4 pinned deps, E docs.
**A6 paged compressed-latent MLA** — the weight-absorption recipe (CPU PCC 1.0), the
`paged_flash_multi_latent_attention_decode` op contract (op-only, fully-populated cache, PCC 0.9999),
and the compressed-cache write (round-trip 1.0) are all reliably proven, and the full
`forward_decode_mla` path is implemented (12.8× smaller KV: 320-dim latent vs 4096 expanded). However
the end-to-end compressed decode is **compile-nondeterministic on this Blackhole build** (same code →
PCC ~0.9997 on some kernel compiles, ~0.02 on others) — an op-execution reliability issue to raise
upstream, not a model-integration fix (`test_m4_mla_compressed_decode` is xfail). The **expanded-kv
decode (0.99971, fully reproducible) is the verified default**, so the model is unaffected.

**A10 MoE sparse dispatch — DONE** (on the native 1×8 mesh; no 2×4 remap needed). `forward_decode(use_sparse=True)`
routes each token to only its top-4 experts via `ttnn.mesh_partition` (device-side replicated→sharded, the
inverse of all_gather) → `all_to_all_dispatch` → local experts → `all_to_all_combine` → `all_gather`. The
original blocker was thinking it needed a 2D DP×EP mesh; the real fix was that the dispatch input must be
**token-sharded, not replicated** — `mesh_partition` provides that on 1×8 with `cluster_axis=1` spanning all
8. Matches dense logits **PCC 0.9958**, trace-compatible (PCC 1.0), **+39.2% decode tok/s @B=32** (see perf
table); `test_m4_moe_sparse` passes. Dense is the default; sparse is opt-in for batched serving.

Remaining (optional, non-blocking): **A6 paged compressed-latent KV** (12.8× smaller cache, the
op-nondeterministic xfail above) + **chunked prefill at 16K full-depth** (8K works; 16K OOMs at 36L — a
paged-cache memory-management follow-up); sparse-decode generator auto-wiring; A4 2CQ (low value for the
tiny decode inputs). All documented, not hidden.
