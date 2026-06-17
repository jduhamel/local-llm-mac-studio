# Model Docs

Model catalog, deployment notes, and benchmark results for the Mac Studio stack. Layout reflects content type — keep new files in the matching subdirectory.

## Layout

| Path | Purpose |
|:--|:--|
| [`model-summary.md`](model-summary.md) | Canonical catalog. Index + per-model spec tables. Start here. |
| [`per-model/`](per-model/) | Long-form deployment write-ups for individual models (Ling, MiMo). Catalog entry should stub-link here when a per-model file exists. |
| [`techniques/`](techniques/) | Inference-side technique notes (speculative decoding, caching, quantisation profiles) — what they are, when they help, hardware sensitivity. |
| [`benchmarks/`](benchmarks/) | Cross-model benchmark write-ups + raw JSON/log outputs grouped by model slug. |
| [`how-to/`](how-to/) | One-off conversion / template / debugging guides. |
| [`known-issues/`](known-issues/) | Cross-cutting model failure modes (doom looping, etc.) — what they are, how to detect, mitigation. |
| [`uncen-model/`](uncen-model/) | Private submodule for uncensored-model research. |

## Per-model deep dives

| File | Topic |
|:--|:--|
| [`per-model/model-summary-ling.md`](per-model/model-summary-ling.md) | Ling-2.6-flash deployment recipe (`bailing_hybrid` patches, server flags, caveats). |
| [`per-model/model-summary-mimo-v2.5.md`](per-model/model-summary-mimo-v2.5.md) | MiMo V2.5 three-config investigation and failure analysis. |
| [`per-model/model-summary-qwen-3-coder.md`](per-model/model-summary-qwen-3-coder.md) | Qwen3-Coder family (Coder-Next 6-bit, Coder-30B-A3B 4-bit). |
| [`per-model/model-summary-qwen-3-5.md`](per-model/model-summary-qwen-3-5.md) | Qwen3.5 family (4 variants: 27B Opus Distilled, 122B-A10B 4-bit, 122B-A10B JANG 2S, 35B-A3B JANG 4K). |
| [`per-model/model-summary-qwen-3-6.md`](per-model/model-summary-qwen-3-6.md) | Qwen3.6 family (14 variants: 35B-A3B 6-bit/4-bit/Ollama MLX, Osaurus JANGTQ4, 27B JANG/MLX/GGUF/MTP variants, uncensored 35B GGUF variants, Rust LoRA, MoE MTP). |
| [`per-model/model-summary-nemotron.md`](per-model/model-summary-nemotron.md) | Nemotron family (Nano 30B, Super 120B, Cascade-2 30B) + cross-cutting server compatibility note. |
| [`per-model/model-summary-gemma.md`](per-model/model-summary-gemma.md) | Gemma 4 family (7 variants: 26B-A4B 4-bit MoE, 31B-it 6-bit dense, DavidAU Heretic 31B, TrevorJS Uncensored 26B-A4B Q8_0 + 31B-it Q4_K_M, Huihui abliterated 26B-A4B i1-Q6_K). |
| [`per-model/model-summary-granite-4.1.md`](per-model/model-summary-granite-4.1.md) | IBM Granite 4.1 30B Q8_0 GGUF — Apache 2.0, 24.8 tok/s on lm-studio. |
| [`per-model/model-summary-qwen3-asr.md`](per-model/model-summary-qwen3-asr.md) | Qwen3-ASR family (1.7B / 0.6B / ForcedAligner-0.6B) — speech-to-text on M3 Ultra MPS, 19.06× RTF on 1.7B. |
| [`per-model/model-summary-zaya1-8b.md`](per-model/model-summary-zaya1-8b.md) | Zyphra ZAYA1-8B (8.4B / 760M-active CCA + top-1 MoE) — Markovian RSA explanation, quant matrix, why vmlx-swift-lm via Osaurus is the only viable path. |
| [`per-model/model-summary-deepseek-v4.md`](per-model/model-summary-deepseek-v4.md) | DeepSeek-V4-Flash (284B/13B-active `deepseek4` MoE) — quant landscape (only `antirez` q2-imatrix 81 GB fits 96 GB), why persadian IQ1_S/arishma108 is CUDA-only, why `ds4` (DwarfStar 4) is the sole Apple-Silicon path, full benchmarks. |
| [`per-model/model-summary-lfm2.md`](per-model/model-summary-lfm2.md) | LiquidAI LFM2.5-8B-A1B Q8_0 (`lfm2moe` 8.3B/1.5B-active MoE) — why lm-studio tool calls fail (pythonic format + reasoning-only → `[TOOL_REQUEST]` buried in `<think>`), the `{# List of tools: [ #}` template-marker patch that makes llama.cpp `--jinja` parse tool calls, deployment recipe, benchmarks. |
| [`per-model/model-summary-hypernova.md`](per-model/model-summary-hypernova.md) | Multiverse Computing HyperNova 60B (CompactifAI MPO-compressed gpt-oss-120b, 60B/4.8B-active MXFP4) — analysis only, candidate experiment: architecture, compression technique, conversion requirements, server-fit matrix. |

## Benchmarks

| File | Coverage |
|:--|:--|
| [`benchmarks/model-benchmark-api-server.md`](benchmarks/model-benchmark-api-server.md) | API throughput / TTFT / prefill across servers. |
| [`benchmarks/model-benchmark-tool-call.md`](benchmarks/model-benchmark-tool-call.md) | OpenCode agent loop end-to-end latency. |
| [`benchmarks/model-benchmark-agent-local.md`](benchmarks/model-benchmark-agent-local.md) | llama-agent in-process agent loop (no API server in the path). |
| [`benchmarks/model-benchmark-standalone.md`](benchmarks/model-benchmark-standalone.md) | Standalone generation benchmarks. |
| [`benchmarks/model-benchmark-turboquant-jang.md`](benchmarks/model-benchmark-turboquant-jang.md) | TurboQuant / JANG benchmark notes. |
| [`benchmarks/logs/<model-slug>/`](benchmarks/logs/) | Raw `agent-bench.json`, `api-server-<server>.json`, and per-run logs. |

## How-to

| File | Topic |
|:--|:--|
| [`how-to/model-conversion-gguf-mlx.md`](how-to/model-conversion-gguf-mlx.md) | GGUF → MLX safetensors conversion. |
| [`how-to/model-qwen-null-think-template-test.md`](how-to/model-qwen-null-think-template-test.md) | Qwen null-think chat template test. |
| [`how-to/eval-benchmark-local-runners.md`](how-to/eval-benchmark-local-runners.md) | Run MMLU / MMLU-Pro / TruthfulQA / HarmBench / refusal-rate locally against lm-studio / vmlx / vllm-mlx OpenAI endpoints. |

## Known issues

| File | Topic |
|:--|:--|
| [`known-issues/doom-loop-edge-model.md`](known-issues/doom-loop-edge-model.md) | Doom looping in small reasoning models — Maxime Labonne's framing, Qwen3.5/3.6 evidence, detection methods, bench-rig recipe. |

## Conventions

- Production-track specs go in [`model-summary.md`](model-summary.md) — keep one row in the Index plus one per-model section.
- If a model needs more than ~150 lines of detail, put it in [`per-model/`](per-model/) and stub-link from the catalog.
- Benchmark JSON belongs under [`benchmarks/logs/<model-slug>/`](benchmarks/logs/) named `<benchmark-type>.json` or `<benchmark-type>-<server>.json` for cross-server comparisons.
- Add new content following the [Sync Policy](../../CLAUDE.md#sync-policy-read-this-first-when-changing-live-state) — README.md, model-summary.md, and the relevant client config file all need to land together.
