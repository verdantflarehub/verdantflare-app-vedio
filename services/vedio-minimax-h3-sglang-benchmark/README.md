# vedio-minimax-h3-sglang-benchmark

Single-RTX-4090 MiniMax H3 Ref2VA benchmark using SGLang's official consumer
GPU execution path. This is an offline benchmark image, not a second product
API and not a ComfyUI installation.

## Locked runtime

| Component | Version |
| --- | --- |
| SGLang | `bbbcbf9418f0d8fbea968d96f3b470f5b883bac3` |
| Base CUDA image | `registry.cn-qingdao.aliyuncs.com/wod/verdantflare-app:vedio-minimax-h3-api-v0.1.1` |
| comfy-kitchen | `0.2.31` |
| FlashInfer Python/cubin | `0.6.17` |
| MiniMax H3 | `42ed227ee7df40d41602854ae760620d6eb651fe` |
| Comfy-Org serialized INT8 | `4cc1d817b6184899b41293954329f576cb5ae86b` |

The base image only supplies the CUDA environment and build dependencies
already validated on the target cluster. The Docker build checks out the
revision that introduced SGLang's measured RTX 4090 results before reinstalling
its diffusion package; the old API entrypoint and patched v0.5.18 Python code
are not used at runtime.

The server selects `--model-type diffusion` explicitly because the benchmark
PVC contains a deliberately partial local model snapshot. Automatic backend
detection otherwise treats that local root as an LLM checkpoint.

Serialized ConvRot checkpoints set `H3_QUANTIZATION=serialized_kitchen_int8`
and `H3_TRANSFORMER_WEIGHTS_PATH` to a verified local safetensors file. Their
per-layer metadata selects `kitchen_int8`; the server intentionally does not
also pass `--quantization`, which SGLang rejects for serialized checkpoints.

## Fixed 4090 placement

Every run uses one GPU, TP1, Ulysses1, exact FlashAttention, eager execution,
zero resident DiT layers, and layerwise offload for only the DiT and text
encoder. The video VAE remains outside layerwise offload, matching the official
1344x768 RTX 4090 recipe.

`num_inference_steps` is recorded as sigma points. MiniMax H3 performs one
fewer DiT evaluation because the grid contains the terminal zero: 50 points is
49 NFE, 21 points is 20 NFE, and 5 points is 4 NFE.

## Output contract

Each case runs a seed-0 warmup followed by the timed seed-7 request. The server
synchronizes pipeline stage boundaries so asynchronous DiT tail work is not
incorrectly charged to VAE decoding; only the timed request persists those
measurements. Its run directory contains the complete `perf.json` and a compact
`stage-summary.json`; the latter retains all pipeline stages, separately selects
`MiniMaxH3VisualEncodingStage` and `MiniMaxH3DecodingStage` as the two video-VAE
boundaries, and reports their combined duration and share of pipeline time.
These boundary figures are an upper bound for TensorRT video-VAE savings:
visual encoding also includes reference preprocessing, while the decoding stage
also includes audio-VAE decode and output normalization. If the boundary share
justifies a TensorRT experiment, instrument the individual video-VAE calls in
that experiment rather than treating the boundary total as pure VAE time.

Synchronization makes the stage attribution usable but adds stage-boundary
barriers. Compare elapsed time only between runs produced by the same
instrumented benchmark version; do not compare it directly with older
unsynchronized wall-time results.

The output directory also contains the source reference and SHA-256, request
and status JSON, MP4 and ffprobe JSON, elapsed wall time, GPU samples, cgroup
peak memory, and the complete SGLang server log. Existing output directories
are rejected so a rerun cannot overwrite evidence.

Before starting SGLang, the runner waits up to five minutes for external CUDA
contexts left by the previous workload to leave the HAMI-assigned GPU. This
keeps model-load memory measurements isolated from a preceding workload.

The Kubernetes jobs and serial execution instructions live in
`deploys/k8s.cn-chengdu.bc-cloud.com/verdantflare-vedio/benchmarks/` in the
design repository.
