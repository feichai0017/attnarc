# Roadmap

## K0: Backend Foundation

Status: complete.

- backend-independent Rust contracts and CPU oracle;
- safe CUDA resource ownership and C ABI;
- reproducible correctness and latency report format.

## K1: Useful Normalization Family

Status: in progress.

1. ~~vectorized FP16 and BF16 RMSNorm~~ — H20 correctness gate complete;
2. ~~fused residual Add+RMSNorm~~ — double in-place H20 gate complete;
3. ~~RMSNorm plus dynamic per-token FP8 output quantization~~ — H20 and named
   vLLM bitwise/performance gates complete; INT8 remains planned;
4. ~~named vLLM baseline and engine integration~~ — IR provider, compilation,
   CUDA Graph, and synthetic-Qwen2 generate-loop gates complete;
5. source packaging and a production model/workload gate.

Exit: one fused path improves a real decode workload, not only a microbenchmark.

## K2: MLP Activation And Quantization

Status: in progress.

1. ~~split-half SiLU-and-Mul for F32/FP16/BF16~~ — Rust, CUDA, PyTorch,
   vLLM layer override, and H20 compatibility gates complete;
2. ~~SiLU-and-Mul plus dynamic per-block FP8 output quantization~~ — groups
   64/128, exact vLLM compatibility, compiler-fusion registration, and H20
   named-baseline gates complete; a real FP8-model engine gate remains open;
3. dynamic INT8 output quantization when a named model path requires it;
4. GELU/GELU-tanh and gated variants admitted by model coverage;
5. vendor GEMM integration with bias, activation, and quantization epilogues.

Exit: a fused activation+quantization path removes an HBM round trip and
improves a real model workload. Standalone SiLU parity alone does not close it.

## K3: KV-Cache Update Family

Status: planned.

- RoPE plus paged-KV write;
- append/copy with layout conversion;
- FP8/INT8 quantize and dequantize;
- gather/scatter for paged cache movement.

Exit: fewer HBM passes and lower TPOT in a real engine.

## K4: Decode Tail

Status: planned.

- fused SwiGLU/GELU epilogues;
- repetition/frequency penalties, top-k/top-p, sampling, and selected logprob;
- MoE top-k routing and token permutation.

Exit: fewer launches and temporary tensors with identical token results.

## K5: MoE Routing And Movement

Status: planned.

- top-k routing, renormalization, and expert mapping;
- token histogram, prefix sum, permutation, and inverse permutation;
- grouped-GEMM vendor dispatch and fused expert-output reduction.

Exit: routing and movement reduce model-level MoE latency on a named engine.

## K6: Attention

Status: planned after K1-K4 establish the common backend.

- paged MQA/GQA decode attention under the standard operator contract;
- vendor attention integration where it wins;
- split-KV/LSE merge, sliding-window variants, and MLA when a consumer exists.

Exit: hardware-qualified engine evidence determines admission; prior Loom
Attention prototype code is not carried forward automatically.

## K7: Communication-Aware Fusion

Status: planned after reproducible single-GPU and multi-GPU engine baselines.

- tensor-parallel reduction plus residual/norm epilogues;
- sharded-vocabulary sampling and selected-logprob merge;
- expert-parallel dispatch/combine integration.

Exit: end-to-end TP or EP goodput improves under an equivalent NCCL/transport
baseline; local adapters do not count as distributed evidence.

The complete intended surface, including profile-gated layout primitives, is
tracked in the [operator catalog](operator-catalog.md).
