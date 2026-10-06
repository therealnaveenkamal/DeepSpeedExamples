# Benchmark results

rdsp against MegatronMIMO and Megatron-Bridge, training Qwen3.5-2B and 4B on CORD-v2. Main results: one AWS g7.48xlarge, 8× RTX PRO 4500 Blackwell, 32 GB, PCIe, no NVLink. A first 4B run on 8× H100 with NVLink follows them. Settings held equal, software versions and how to rerun: [REPRODUCE.md](REPRODUCE.md). Raw logs: `bench/published/{2b,4b,h100}/`; `python bench/mimo/summarize.py bench/published/2b` prints the table rows, and `tests/unit/test_bench_summarize.py` checks them against the README.

## Results: 8× RTX PRO 4500, PCIe

Median over steps 6–50. Tokens/s counts real tokens only; both systems see the same tokens. Per GPU divides by the layout's GPU count, so the 5-GPU MIMO layout and the 8-GPU layouts compare directly. Cost assumes $5.32/h for 8 GPUs, prorated to 5 for the MIMO layout.

| Model | Layout | Megatron | rdsp | Step time | Megatron tok/s | rdsp tok/s | Megatron tok/s per GPU | rdsp tok/s per GPU | Megatron $/M tok | rdsp $/M tok |
|---|---|---|---|---|---|---|---|---|---|---|
| 2B | Vision 1 GPU + language TP2×DP2, vs MIMO | 9.64 s | 8.30 s | −14% | 6,780 | 7,837 | 1,356 | 1,567 | 0.136 | 0.118 |
| 2B | TP2×PP2×DP2, vs Bridge | 7.39 s | 5.30 s | −28% | 8,711 | 12,187 | 1,089 | 1,523 | 0.170 | 0.121 |
| 4B | TP2×PP2×DP2, vs Bridge | 10.04 s | 8.69 s | −13% | 6,459 | 7,460 | 807 | 932 | 0.229 | 0.198 |
| 4B | TP4×PP2×DP1, vs Bridge | 15.93 s | 13.29 s | −17% | 4,073 | 4,901 | 509 | 613 | 0.363 | 0.302 |

Loss: every pair starts from the same step-0 loss. Over steps 1–49, rdsp's mean difference from Megatron is +0.0005 (2B MIMO layout), +0.003 (4B TP2×PP2×DP2) and −0.0024 (4B TP4×PP2×DP1). Steps 4–5 vary by up to 0.08 between repeated runs of either system, from GPU kernels that aren't bit-for-bit deterministic.

## Results: 8× H100, NVLink (first run)

Qwen3.5-4B on one AWS p5.48xlarge: 8× H100 SXM 80 GB, every pair of GPUs linked by NVLink through NVSwitch (`nvidia-smi topo -m`: NV18). Same software, data, settings and recipes as above. Megatron-Bridge's settings were diffed against the PCIe runs: the only difference was the step count. Median over steps 6–50; cost assumes $22.28/h for 8 GPUs (spot, us-east-2).

| Layout | Megatron | rdsp | Step time | Megatron tok/s | rdsp tok/s | Megatron tok/s per GPU | rdsp tok/s per GPU | Megatron $/M tok | rdsp $/M tok |
|---|---|---|---|---|---|---|---|---|---|
| Vision 1 GPU + language TP2×DP2, vs MIMO | 7.99 s | 7.89 s | −1% | 8,171 | 8,239 | 1,634 | 1,648 | 0.473 | 0.469 |
| TP2×PP2×DP2, vs Bridge | 8.79 s | 6.49 s | −26% | 7,372 | 9,901 | 921 | 1,238 | 0.840 | 0.625 |
| TP4×PP2×DP1, vs Bridge | 18.24 s | 12.30 s | −33% | 3,522 | 5,274 | 440 | 659 | 1.757 | 1.174 |
| Colocated vision + language TP2×PP2×DP2 (rdsp only) | — | 5.62 s | | | 11,580 | — | 1,447 | | 0.534 |

Loss: every pair starts from the same step-0 loss; over steps 1–49 rdsp's mean difference from Megatron is +0.003, −0.003 and −0.008, and colocated's from Megatron-Bridge TP2×PP2×DP2 is −0.002. Logs: `bench/published/h100/`, with the GPU topology in `hardware.txt`.

Per GPU, MIMO's 5-GPU layout is the most efficient here (1,634 and 1,648 tokens/s per GPU); colocated is the fastest per step and the second most efficient per GPU (1,447).

**Read with care:**
- **One round.** No repeats yet, so no spread. On PCIe, repeats landed within about 2%.
- **The host CPU limits launch-heavy runs.** This instance has an AMD EPYC 7R13. A torch-profiler step on rdsp's language GPUs in the MIMO layout shows the CPU busy for the whole step while GPU kernels run for only part of it: the layout is bound by kernel launches, not by the GPUs. That's why it ends in a near-tie. Megatron's TP4×PP2×DP1 (64 one-row microbatches per GPU, 26.7 TFLOP/s per GPU) is slower here than on the PCIe GPUs, most likely for the same reason. That's an inference, since its profiler trace was lost, and it inflates the −33%.
- **rdsp's TP4 split is off on H100.** Stage 0 (vision encoder + 12 layers) is busy 12.1 s per step while stage 1 waits 3.2 s. The balanced estimate doesn't model how much less efficiently the encoder's small matrices run under TP4.
- **Colocated ran without compiling the encoder.** The recipe's `compile_vision` doesn't apply to a colocated encoder (now rejected at start-up); `recipes/qwen35-4b-coloc-tp2pp2dp2.sh` compiles it, and is unmeasured.
- **NVLink was used by both systems.** With `NCCL_DEBUG=INFO`, every NCCL connection on both sides is `P2P/CUMEM`, with no `SHM` or `NET` fallback.
- **Defaults on both sides.** Megatron's TP communication overlap (`tp_comm_overlap`) is off in its stock recipe, as on PCIe; rdsp has no equivalent. A run with it on would be a separate, labelled number.

## rdsp settings per layout

All runs: `--prefetch --sharded-loss --drop-padding-mask --pad-per-microbatch --cuts balanced`, with the recipe in `recipes/`.

| Layout | Recipe | Extra settings | Cut chosen |
|---|---|---|---|
| Vision 1 GPU + TP2×DP2 | `qwen35-2b-vision1-tp2dp2.sh` | `--cuts 0` (vision-only stage), `--loss microbatch-mean`, 2 rows × 32 microbatches, stage 0 compiled | encoder alone |
| TP2×PP2×DP2 (2B) | `qwen35-2b-tp2pp2dp2.sh` | `--untie-embeddings`, 2 rows × 32 microbatches, vision encoder compiled | 5 of 24 layers on stage 0 |
| TP2×PP2×DP2 (4B) | `qwen35-4b-tp2pp2dp2.sh` | same | 13 of 32 |
| TP4×PP2×DP1 (4B) | `qwen35-4b-tp4pp2dp1.sh` | `--untie-embeddings`, 1 row × 64 microbatches, vision encoder compiled | 12 of 32 |

Megatron used its default even split (12 of 24, 16 of 32). It accepts uneven splits through flags; we didn't tune them.

## The balanced cut

In a two-stage pipeline the step runs at the pace of the slower stage. `--cuts balanced` estimates each part's work before training and minimises the most expensive stage, each stage's cost divided by its GPU count:

- A decoder layer costs its parameter count; so does the output head, on the last stage.
- The vision encoder costs its parameter count times a ratio measured from the first batch:

```
ratio = Σ_images patches × (1 + 2 × patches × width / layer_params) / text tokens computed
```

The second term is the encoder's attention over each image: about 4 × patches × width multiply-adds per patch, against 2 × layer_params for the matrix products. A CORD-v2 image has about 3,800 patches, so attention makes the encoder about 1.6× more expensive than its parameters suggest. "Text tokens computed" counts each microbatch at its padded length, not the configured 2048.

An earlier version divided by 2048 and left out attention. Both errors made the encoder look about half as expensive, so the cut landed too late. We checked the corrected estimate by timing every candidate cut for a few steps:

| Layout | Even | Old estimate | Balanced | Fastest measured |
|---|---|---|---|---|
| 2B TP2×PP2×DP2 | 12 | 11 (6.07 s) | 5 (5.30 s) | 5 |
| 4B TP2×PP2×DP2 | 16 | 16 (OOM) | 13 (8.69 s) | 13 |
| 4B TP4×PP2×DP1 | 16 | 16 (14.54 s) | 12 (13.29 s) | 11 (13.15 s) |

Under TP4 the estimate misses by one layer (about 1%). The encoder's small matrices lose efficiency when split four ways, and the estimate doesn't model that. The timing sweep was only a check and isn't part of rdsp.

## What moved the numbers

rdsp started 40% slower than MegatronMIMO in MIMO's own layout. 2B step time after each change:

| Change | Step time |
|---|---|
| Start: encoder shares the first stage, with recompute | 13.51 s |
| Vision-only first stage: frees enough memory to drop recompute | 11.3 s |
| Prefetch: the next step's data (about 576 MB of images) ships while this step runs; dispatch fell from 1.1 s to 1 ms | 10.3 s (12-step run) |
| `torch.compile` on the vision encoder: its forward and backward fell from 7.8 s to 6.7 s per step | 9.62 s |
| Split-vocabulary loss: TP ranks keep their slice of the 248k-wide logits instead of gathering 2 GB per microbatch | 9.25 s |
| No padding mask: rows pad only on the right, so causal attention ignores the padding anyway, and SDPA picks its flash kernel | 9.05 s |
| bf16 gradients freed after fp32 accumulation (2 bytes per parameter less, as in Megatron), and padding per microbatch (1.71 → 1.20 padded tokens per real token) | 8.30 s |

Same chain for 4B TP2×PP2×DP2: 13.51 s → 11.57 s → 10.58 s → 8.71 s → 8.69 s. The freed gradients removed the out-of-memory errors that had forced recompute, and the corrected balanced cut did the rest.

## Not included

- **4B in MIMO's layout.** Neither system fits it in 32 GB without recompute.
- **2B TP4.** Qwen3.5-2B has 2 key/value heads, which can't be split 4 ways.
- **9B and up.** These need 80 GB-class GPUs in these layouts.
- **Colocated vision.** rdsp only; neither Megatron system supports it for Qwen3.5. 4B ran at 9.66 s, slower than TP2×PP2×DP2; 2B didn't fit.
- **Repeats.** One 50-step run per configuration, except the rdsp 4B TP2×PP2×DP2 repeat (8.71 s and 8.69 s).
- **Interconnect.** On NVLink machines, rdsp's communication savings would matter less.

## Validation provenance

The supported-layout rows in [CONTRACTS.md](CONTRACTS.md) passed on Modal (8× L4, real DeepSpeed and NCCL, fp32 tiny models, SGD with momentum), with:
- loss parity against the unsplit model within 1e-4;
- per-parameter update parity within 2.4e-5 (3e-4 with AutoEP folding);
- checkpoint round trip;
- rank-kill recovery.

The two-stage baseline uses Qwen3-0.6B in bf16. The three vision placements match the unsplit model on 4× L40S (`tests/integration/test_vl_layouts_gpu.py`, tiny Qwen3.5-VL, fp32). Evidence per row is in `src/ray_deepspeed_pipeline/support_matrix.py`.
