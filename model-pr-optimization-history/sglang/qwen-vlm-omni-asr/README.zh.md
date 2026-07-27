# sglang Qwen VLM/Omni/ASR 模型 PR 优化历史

## 模型实现文件覆盖

| 文件 | git 追溯到的 PR |
| --- | --- |
| `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` | [#23907](https://github.com/sgl-project/sglang/pull/23907), [#23968](https://github.com/sgl-project/sglang/pull/23968), [#23998](https://github.com/sgl-project/sglang/pull/23998), [#25198](https://github.com/sgl-project/sglang/pull/25198) |
| `docs_new/cookbook/omni/FishAudio/S2-Pro.mdx` | 无直接 PR 号提交 |
| `docs_new/cookbook/omni/intro.mdx` | 无直接 PR 号提交 |
| `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` | [#23907](https://github.com/sgl-project/sglang/pull/23907), [#25198](https://github.com/sgl-project/sglang/pull/25198) |
| `examples/chat_template/qwen3_vl_reranker.jinja` | 无直接 PR 号提交 |
| `examples/runtime/qwen3_vl_reranker.py` | 无直接 PR 号提交 |
| `python/sglang/srt/configs/qwen3_asr.py` | [#22073](https://github.com/sgl-project/sglang/pull/22073), [#22181](https://github.com/sgl-project/sglang/pull/22181), [#24187](https://github.com/sgl-project/sglang/pull/24187) |
| `python/sglang/srt/configs/qwen3_omni.py` | [#10911](https://github.com/sgl-project/sglang/pull/10911) |
| `python/sglang/srt/configs/qwen3_vl.py` | [#10323](https://github.com/sgl-project/sglang/pull/10323), [#10911](https://github.com/sgl-project/sglang/pull/10911) |
| `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py` | [#22089](https://github.com/sgl-project/sglang/pull/22089), [#22181](https://github.com/sgl-project/sglang/pull/22181) |
| `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py` | 无直接 PR 号提交 |
| `python/sglang/srt/models/glmasr.py` | [#15570](https://github.com/sgl-project/sglang/pull/15570), [#15772](https://github.com/sgl-project/sglang/pull/15772) |
| `python/sglang/srt/models/qwen2_5_vl.py` | [#5003](https://github.com/sgl-project/sglang/pull/5003), [#5349](https://github.com/sgl-project/sglang/pull/5349), [#6136](https://github.com/sgl-project/sglang/pull/6136), [#8801](https://github.com/sgl-project/sglang/pull/8801), [#13055](https://github.com/sgl-project/sglang/pull/13055), [#13075](https://github.com/sgl-project/sglang/pull/13075), [#13126](https://github.com/sgl-project/sglang/pull/13126), [#13904](https://github.com/sgl-project/sglang/pull/13904), [#14292](https://github.com/sgl-project/sglang/pull/14292), [#15138](https://github.com/sgl-project/sglang/pull/15138), [#15320](https://github.com/sgl-project/sglang/pull/15320) |
| `python/sglang/srt/models/qwen2_audio.py` | 无直接 PR 号提交 |
| `python/sglang/srt/models/qwen2_vl.py` | [#2055](https://github.com/sgl-project/sglang/pull/2055), [#5003](https://github.com/sgl-project/sglang/pull/5003), [#5349](https://github.com/sgl-project/sglang/pull/5349), [#5783](https://github.com/sgl-project/sglang/pull/5783), [#6136](https://github.com/sgl-project/sglang/pull/6136), [#13055](https://github.com/sgl-project/sglang/pull/13055), [#13736](https://github.com/sgl-project/sglang/pull/13736) |
| `python/sglang/srt/models/qwen3_asr.py` | [#22073](https://github.com/sgl-project/sglang/pull/22073) |
| `python/sglang/srt/models/qwen3_omni_moe.py` | [#10911](https://github.com/sgl-project/sglang/pull/10911), [#11791](https://github.com/sgl-project/sglang/pull/11791), [#12333](https://github.com/sgl-project/sglang/pull/12333), [#12662](https://github.com/sgl-project/sglang/pull/12662), [#18185](https://github.com/sgl-project/sglang/pull/18185) |
| `python/sglang/srt/models/qwen3_vl.py` | [#10323](https://github.com/sgl-project/sglang/pull/10323), [#10911](https://github.com/sgl-project/sglang/pull/10911), [#11458](https://github.com/sgl-project/sglang/pull/11458), [#11481](https://github.com/sgl-project/sglang/pull/11481), [#12333](https://github.com/sgl-project/sglang/pull/12333), [#12662](https://github.com/sgl-project/sglang/pull/12662), [#13724](https://github.com/sgl-project/sglang/pull/13724), [#13736](https://github.com/sgl-project/sglang/pull/13736), [#14292](https://github.com/sgl-project/sglang/pull/14292), [#15205](https://github.com/sgl-project/sglang/pull/15205), [#15320](https://github.com/sgl-project/sglang/pull/15320), [#16366](https://github.com/sgl-project/sglang/pull/16366), ... (18 total) |
| `python/sglang/srt/models/qwen3_vl_moe.py` | [#10323](https://github.com/sgl-project/sglang/pull/10323), [#10911](https://github.com/sgl-project/sglang/pull/10911), [#11481](https://github.com/sgl-project/sglang/pull/11481), [#13983](https://github.com/sgl-project/sglang/pull/13983), [#21469](https://github.com/sgl-project/sglang/pull/21469) |
| `python/sglang/srt/multimodal/processors/glmasr.py` | [#15570](https://github.com/sgl-project/sglang/pull/15570), [#15772](https://github.com/sgl-project/sglang/pull/15772) |
| `python/sglang/srt/multimodal/processors/qwen3_asr.py` | [#22073](https://github.com/sgl-project/sglang/pull/22073), [#22089](https://github.com/sgl-project/sglang/pull/22089), [#22181](https://github.com/sgl-project/sglang/pull/22181) |
| `python/sglang/srt/multimodal/processors/qwen_vl.py` | [#10323](https://github.com/sgl-project/sglang/pull/10323), [#10911](https://github.com/sgl-project/sglang/pull/10911), [#11377](https://github.com/sgl-project/sglang/pull/11377), [#12240](https://github.com/sgl-project/sglang/pull/12240), [#12458](https://github.com/sgl-project/sglang/pull/12458), [#12662](https://github.com/sgl-project/sglang/pull/12662), [#26094](https://github.com/sgl-project/sglang/pull/26094), [#26116](https://github.com/sgl-project/sglang/pull/26116), [#26167](https://github.com/sgl-project/sglang/pull/26167) |
| `python/sglang/test/external_models/custom_qwen2_vl.py` | 无直接 PR 号提交 |
| `test/manual/models/test_qwen3_asr.py` | [#22181](https://github.com/sgl-project/sglang/pull/22181), [#22848](https://github.com/sgl-project/sglang/pull/22848) |
| `test/registered/ascend/accuracy/qwen3_omni_30b_a3b_thinking/test_npu_qwen3_omni_30b_a3b_thinking_1p_mmmu.py` | 无直接 PR 号提交 |
| `test/registered/ascend/accuracy/qwen3_vl_30b_a3b_thinking/test_npu_qwen3_vl_30b_a3b_thinking_1p_mmmu.py` | 无直接 PR 号提交 |
| `test/registered/ascend/accuracy/qwen3_vl_8b_thinking/test_npu_qwen3_vl_8b_thinking_1p_mmmu.py` | 无直接 PR 号提交 |
| `test/registered/ascend/vlm_models/test_npu_qwen2_5_vl_3b_instruct.py` | 无直接 PR 号提交 |
| `test/registered/ascend/vlm_models/test_npu_qwen2_5_vl_72b_instruct.py` | 无直接 PR 号提交 |
| `test/registered/ascend/vlm_models/test_npu_qwen3_vl_235b_a22b_instruct.py` | 无直接 PR 号提交 |
| `test/registered/ascend/vlm_models/test_npu_qwen3_vl_30b_a3b_instruct.py` | 无直接 PR 号提交 |
| `test/registered/ascend/vlm_models/test_npu_qwen3_vl_4b_instruct.py` | 无直接 PR 号提交 |
| `test/registered/ascend/vlm_models/test_npu_qwen3_vl_8b_instruct.py` | 无直接 PR 号提交 |
| `test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py` | [#21469](https://github.com/sgl-project/sglang/pull/21469) |

## PR 覆盖总览

- git 追溯 PR 数: 49
- 原文档显式引用补充 PR 数: 52
- 当前文档总 PR 数: 101
- 文件追溯命令: `git log --name-only -- <model-files>`
- diff 审计来源: GitHub Pull Request files API

## 时间线

| 日期 | PR | 状态 | 标题 | 主要文件 |
| --- | --- | --- | --- | --- |
| 2024-11-21 | [#2055](https://github.com/sgl-project/sglang/pull/2055) | merged | Add support for Qwen2-VL-based embedding models | `python/sglang/srt/models/qwen2_vl.py` |
| 2025-04-14 | [#5003](https://github.com/sgl-project/sglang/pull/5003) | merged | Support for Qwen2.5-VL Model in bitsandbytes Format | `python/sglang/srt/models/qwen2_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-04-24 | [#5349](https://github.com/sgl-project/sglang/pull/5349) | merged | vlm: enable radix cache for qwen-vl models | `python/sglang/srt/models/qwen2_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-05-01 | [#5783](https://github.com/sgl-project/sglang/pull/5783) | merged | Remove unused method `calculate_num_image_tokens` from qwen2_vl.py | `python/sglang/srt/models/qwen2_vl.py` |
| 2025-05-16 | [#6136](https://github.com/sgl-project/sglang/pull/6136) | merged | Support precomputed multimodal features for Qwen-VL and Gemma3 models. | `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py` |
| 2025-08-12 | [#9014](https://github.com/sgl-project/sglang/pull/9014) | merged | Fuse writing KV buffer into rope kernel (part 2: srt) | `python/sglang/srt/models/gpt_oss.py`, `python/sglang/srt/layers/rotary_embedding.py`, `python/sglang/srt/entrypoints/engine.py` |
| 2025-09-08 | [#8801](https://github.com/sgl-project/sglang/pull/8801) | merged | Qwen2.5-VL eagle3 infer | `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-09-23 | [#10323](https://github.com/sgl-project/sglang/pull/10323) | merged | model: support qwen3-vl series | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/configs/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2025-09-26 | [#10749](https://github.com/sgl-project/sglang/pull/10749) | merged | Fuse write kv buffer into rope for qwen3 moe & bailing moe | `python/sglang/srt/models/utils.py`, `python/sglang/srt/models/gpt_oss.py`, `python/sglang/srt/models/bailing_moe.py` |
| 2025-10-01 | [#10985](https://github.com/sgl-project/sglang/pull/10985) | merged | Quick Fix: fix Qwen3-VL launch failure caused by MRotaryEmbedding arg | `python/sglang/srt/models/qwen3_moe.py`, `python/sglang/srt/layers/rotary_embedding.py` |
| 2025-10-12 | [#11481](https://github.com/sgl-project/sglang/pull/11481) | merged | [smol] [perf] Qwen3-VL in place op. | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2025-10-15 | [#11458](https://github.com/sgl-project/sglang/pull/11458) | merged | [BugFix][Qwen3-VL]: fix cu_seqlens in qwen3-vl | `python/sglang/srt/models/qwen3_vl.py` |
| 2025-10-16 | [#10911](https://github.com/sgl-project/sglang/pull/10911) | merged | model: qwen3-omni (thinker-only) | `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/configs/qwen3_omni.py`, `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2025-10-21 | [#11377](https://github.com/sgl-project/sglang/pull/11377) | merged | [BugFix][Qwen3-VL]: add metadata for video in qwen3-vl | `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2025-10-28 | [#12261](https://github.com/sgl-project/sglang/pull/12261) | open | [BugFix][Qwen2.5-VL]: fix cu_seqlens in qwen2.5-vl | `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-11-05 | [#12703](https://github.com/sgl-project/sglang/pull/12703) | open | add qwen3-omni docs | `docs/basic_usage/qwen3_omni.md`, `docs/index.rst` |
| 2025-11-06 | [#12240](https://github.com/sgl-project/sglang/pull/12240) | merged | [VLM] Optimize qwen_vl preprocess_video | `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2025-11-10 | [#12554](https://github.com/sgl-project/sglang/pull/12554) | merged | [Docs] Add docs for Qwen3-VL image and video support | `docs/basic_usage/qwen3_vl.md`, `docs/index.rst` |
| 2025-11-12 | [#12458](https://github.com/sgl-project/sglang/pull/12458) | merged | fix: duplicate resize images logic of qwen-vl series models | `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2025-11-12 | [#13075](https://github.com/sgl-project/sglang/pull/13075) | merged | [VLM] Support PP for Qwen2.5-VL | `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-11-18 | [#13126](https://github.com/sgl-project/sglang/pull/13126) | merged | [VLM][feat] Support encoder DP for Qwen2.5-VL | `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-11-20 | [#13055](https://github.com/sgl-project/sglang/pull/13055) | merged | [VLM] Support Piecewise CUDA Graph for Qwen2.5-VL | `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py` |
| 2025-11-22 | [#13736](https://github.com/sgl-project/sglang/pull/13736) | merged | [VLM] Replace torch.repeat_interleave with faster np.repeat for Qwen-VL series | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen2_vl.py` |
| 2025-11-26 | [#13983](https://github.com/sgl-project/sglang/pull/13983) | merged | Support KTransformers for Qwen3-VL moe | `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2025-11-28 | [#13904](https://github.com/sgl-project/sglang/pull/13904) | merged | [Bugfix] qwen2.5-vl spec decode accept_len low | `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-11-28 | [#13724](https://github.com/sgl-project/sglang/pull/13724) | merged | support qwen3_vl vision model dp | `python/sglang/srt/models/qwen3_vl.py` |
| 2025-12-04 | [#14292](https://github.com/sgl-project/sglang/pull/14292) | merged | [VLM] Introduce Cache for positional embedding ids for Qwen-VL family | `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen3_vl.py` |
| 2025-12-06 | [#11791](https://github.com/sgl-project/sglang/pull/11791) | merged | fix rmsnorm -> layernorm in qwen3 omni | `python/sglang/srt/models/qwen3_omni_moe.py` |
| 2025-12-11 | [#14886](https://github.com/sgl-project/sglang/pull/14886) | open | Support qwen3-omni with DP Encoder | `python/sglang/srt/models/qwen3_omni_moe.py`, `test/nightly/test_encoder_dp.py` |
| 2025-12-15 | [#14907](https://github.com/sgl-project/sglang/pull/14907) | merged | [VLM] Support chunked vit attention | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/managers/mm_utils.py` |
| 2025-12-17 | [#12333](https://github.com/sgl-project/sglang/pull/12333) | merged | [PP] Add pp support for Qwen3-VL | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_omni_moe.py` |
| 2025-12-17 | [#15138](https://github.com/sgl-project/sglang/pull/15138) | merged | [bug fix][pp] fix weight load for qwen2.5-vl | `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-12-18 | [#15205](https://github.com/sgl-project/sglang/pull/15205) | merged | [VLM] Support cos sin cache for Qwen3-VL & GLM-4.1V | `python/sglang/srt/models/qwen3_vl.py` |
| 2025-12-20 | [#15320](https://github.com/sgl-project/sglang/pull/15320) | merged | [VLM] Support ViT Piecewise CUDA Graph for Qwen3-VL | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py` |
| 2025-12-23 | [#15570](https://github.com/sgl-project/sglang/pull/15570) | merged | [GLM-ASR] GLM-ASR Support | `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/glmasr.py` |
| 2025-12-25 | [#15772](https://github.com/sgl-project/sglang/pull/15772) | merged | Change GLM-ASR class name | `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/glmasr.py` |
| 2026-01-05 | [#16491](https://github.com/sgl-project/sglang/pull/16491) | open | [Qwen3-VL][PP] Skip loading expert weights not on this rank | `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2026-01-06 | [#16571](https://github.com/sgl-project/sglang/pull/16571) | open | [Feature] [ROCM] Support Add & LayerNorm fused for Qwen3-VL VIT | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/layers/layernorm.py` |
| 2026-01-09 | [#16785](https://github.com/sgl-project/sglang/pull/16785) | open | [Bugfix] fix recompile in qwen3 vl | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`, `python/sglang/srt/model_executor/piecewise_cuda_graph_runner.py` |
| 2026-01-13 | [#16996](https://github.com/sgl-project/sglang/pull/16996) | open | feat: Support 'use_audio_in_video' option for qwen3omnimoe model | `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/entrypoints/openai/protocol.py` |
| 2026-01-16 | [#17202](https://github.com/sgl-project/sglang/pull/17202) | open | [Feat] Accelerate qwen3vl by remove cpu op | `python/sglang/srt/layers/attention/vision.py`, `python/sglang/srt/managers/mm_utils.py` |
| 2026-01-22 | [#16366](https://github.com/sgl-project/sglang/pull/16366) | merged | Optimize Qwen3-VL video memory usage | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-01-30 | [#17624](https://github.com/sgl-project/sglang/pull/17624) | merged | [BUGFIX] Fix dp size > 1 for qwen3 vl model | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/mm_utils.py`, `python/sglang/srt/layers/linear.py` |
| 2026-02-02 | [#18024](https://github.com/sgl-project/sglang/pull/18024) | merged | fix: correct weight loading prefix mapping for Qwen3-VL | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-02-05 | [#16781](https://github.com/sgl-project/sglang/pull/16781) | merged | Refactor(qwen3-vl) optimize position encoding interpolation | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-02-12 | [#18721](https://github.com/sgl-project/sglang/pull/18721) | open | [BUG] fix mm_enable_dp_encoder hang for Qwen3-VL models | `python/sglang/srt/layers/vocab_parallel_embedding.py`, `python/sglang/srt/models/qwen3_vl.py` |
| 2026-02-13 | [#18771](https://github.com/sgl-project/sglang/pull/18771) | open | Add Qwen3-Omni to Qwen MoE architecture handling in fused_moe_triton | `benchmark/kernels/fused_moe_triton/common_utils.py` |
| 2026-02-24 | [#19003](https://github.com/sgl-project/sglang/pull/19003) | merged | [VLM] Introduce FlashInfer CUDNN Prefill as ViT Backend | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/layers/attention/vision.py`, `test/manual/nightly/test_vlms_vit_flashinfer_cudnn.py` |
| 2026-02-27 | [#19333](https://github.com/sgl-project/sglang/pull/19333) | merged | fix qwen3_vl visual module loading | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-03-02 | [#19693](https://github.com/sgl-project/sglang/pull/19693) | open | [NPU] Fix Qwen3-VL-8B Accuracy for NPU | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/llama.py`, `python/sglang/srt/layers/rotary_embedding.py` |
| 2026-03-02 | [#19291](https://github.com/sgl-project/sglang/pull/19291) | merged | [Qwen3.5] Fix missing `quant_config` in `Qwen3VL` | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-03-14 | [#18185](https://github.com/sgl-project/sglang/pull/18185) | merged | [Omni] Optimize AudioEncoder for Qwen3_Omni_Thinker | `python/sglang/srt/models/qwen3_omni_moe.py` |
| 2026-03-18 | [#20788](https://github.com/sgl-project/sglang/pull/20788) | merged | [DP encoder] Fix `pos_emb `layer TP issue when DP encoder enabled for Qwen3 VL | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-03-18 | [#20857](https://github.com/sgl-project/sglang/pull/20857) | open | add EVS support for Qwen3-VL | `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/layers/rotary_embedding/mrope_rope_index.py`, `python/sglang/srt/models/qwen3_vl.py` |
| 2026-03-19 | [#20759](https://github.com/sgl-project/sglang/pull/20759) | merged | [Bugfix] fix qwen3vl hang when --mm-enable-dp-encoder is enable | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-04-01 | [#21469](https://github.com/sgl-project/sglang/pull/21469) | merged | [3/n] lora moe - Support Qwen3-VL-30B-A3B-Instruct | `python/sglang/srt/models/qwen3_vl_moe.py`, `test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py` |
| 2026-04-01 | [#21458](https://github.com/sgl-project/sglang/pull/21458) | merged | [AMD] Optimize Qwen3-VL decode - fuse QK-norm + 3D mRoPE + KV cache write | `python/sglang/srt/models/qwen3.py` |
| 2026-04-03 | [#19135](https://github.com/sgl-project/sglang/pull/19135) | merged | qwen3 vl skip layer id for pp | `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2026-04-03 | [#22052](https://github.com/sgl-project/sglang/pull/22052) | open | [Fix] Enable precise embedding interpolation by default for Qwen3-VL | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/server_args.py`, `docs/advanced_features/server_arguments.md` |
| 2026-04-04 | [#22038](https://github.com/sgl-project/sglang/pull/22038) | merged | [VLM] Chunk-aware ViT encoding with per-image cache and lazy device transfer | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/mem_cache/multimodal_cache.py`, `python/sglang/srt/models/deepseek_vl2.py` |
| 2026-04-06 | [#21849](https://github.com/sgl-project/sglang/pull/21849) | merged | [VLM]: allow Qwen3.5 models for encoder disaggregation | `python/sglang/srt/multimodal/processors/qwen_vl.py`, `test/registered/distributed/test_epd_disaggregation.py`, `python/sglang/srt/disaggregation/encode_server.py` |
| 2026-04-07 | [#22073](https://github.com/sgl-project/sglang/pull/22073) | merged | [Feature] Adding Qwen3-asr Model Support | `python/sglang/srt/models/qwen3_asr.py`, `python/sglang/srt/configs/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py` |
| 2026-04-08 | [#22266](https://github.com/sgl-project/sglang/pull/22266) | merged | [NPU] fix qwen3.5 video processor | `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py` |
| 2026-04-08 | [#22181](https://github.com/sgl-project/sglang/pull/22181) | merged | [refactor] [asr] Add transcription adapter for extensible ASR models support | `python/sglang/srt/configs/qwen3_asr.py`, `test/manual/models/test_qwen3_asr.py`, `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py` |
| 2026-04-09 | [#22230](https://github.com/sgl-project/sglang/pull/22230) | merged | [Feature] Support eagle3 for qwen3-vl | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-04-09 | [#22089](https://github.com/sgl-project/sglang/pull/22089) | merged | [Feature] Add chunk-based streaming ASR for Qwen3-ASR | `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py` |
| 2026-04-15 | [#22839](https://github.com/sgl-project/sglang/pull/22839) | open | fix(config): Add from_dict() for Qwen3VL config classes | `test/registered/unit/configs/test_qwen3_vl_config.py`, `python/sglang/srt/configs/qwen3_5.py`, `python/sglang/srt/configs/qwen3_vl.py` |
| 2026-04-18 | [#23115](https://github.com/sgl-project/sglang/pull/23115) | open | fix: guard self.model access in Qwen3VLMoeForConditionalGeneration.load_weights | `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2026-04-18 | [#22431](https://github.com/sgl-project/sglang/pull/22431) | merged | Fix Qwen3.5 video processing when passing video_data in "processor_output" format | `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2026-04-21 | [#23304](https://github.com/sgl-project/sglang/pull/23304) | closed | [Bugfix] Fix Qwen3-VL rope config compatibility | `python/sglang/srt/models/qwen3.py` |
| 2026-04-28 | [#23907](https://github.com/sgl-project/sglang/pull/23907) | merged | [Docs] add Nemotron 3 Nano Omni cookbook | `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` |
| 2026-04-28 | [#23968](https://github.com/sgl-project/sglang/pull/23968) | merged | [Docs] update Docker image for Nemotron 3 Nano Omni | `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` |
| 2026-04-30 | [#24163](https://github.com/sgl-project/sglang/pull/24163) | merged | Revert "[ci] split stage-c-test-4-gpu-b200 to enable a low-disk runner pool" | `.github/workflows/pr-test.yml`, `scripts/ci/utils/slash_command_handler.py`, `test/registered/4-gpu-models/test_gpt_oss_4gpu.py` |
| 2026-05-05 | [#23998](https://github.com/sgl-project/sglang/pull/23998) | merged | update Nemotron3 Nano Omni cookbook benchmarks | `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` |
| 2026-05-10 | [#24875](https://github.com/sgl-project/sglang/pull/24875) | merged | Support Intern-S2-Preview | `python/sglang/srt/configs/interns2preview.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/models/interns2preview.py` |
| 2026-05-12 | [#24187](https://github.com/sgl-project/sglang/pull/24187) | merged | [Fix] Qwen3-ASR config: set thinker_config before super().__init__ | `python/sglang/srt/configs/qwen3_asr.py` |
| 2026-05-14 | [#25197](https://github.com/sgl-project/sglang/pull/25197) | merged | ci: decouple stage and runner for cuda registry | `test/registered/layers/test_fla_layernorm_guard.py`, `test/registered/models/test_dummy_grok_models.py`, `test/registered/models/test_ministral3_models.py` |
| 2026-05-14 | [#25203](https://github.com/sgl-project/sglang/pull/25203) | merged | ci: B200 conditional split + LPT_SLOP removal (stage-c partition 8→3) | `scripts/ci/utils/compute_partitions.py`, `test/registered/lora/test_lora_gpt_oss_20b_logprob_diff.py`, `test/registered/lora/test_lora_nemotron_3_super_120b_a12b_logprob_diff.py` |
| 2026-05-14 | [#25130](https://github.com/sgl-project/sglang/pull/25130) | merged | [NPU]Bugfix:Set default values for npu_wrapper_preprocess parameters | `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py`, `python/sglang/srt/hardware_backend/npu/attention/ascend_gdn_backend.py` |
| 2026-05-16 | [#25420](https://github.com/sgl-project/sglang/pull/25420) | merged | [CI] Rename basic CI `stage-a/b/c` -> `base-a/b/c` for symmetry with extra CI | `.github/workflows/pr-test-multimodal-gen.yml`, `test/registered/bench_fn/test_bench_serving_reasoning_stream.py`, `test/registered/function_call/test_kimik2_detector.py` |
| 2026-05-21 | [#25759](https://github.com/sgl-project/sglang/pull/25759) | merged | [BugFix][EPD]Fix Qwen3VLMoe encoder-only AttributeError | `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2026-05-22 | [#24751](https://github.com/sgl-project/sglang/pull/24751) | merged | fix(mm): make multimodal data loading non-blocking to prevent health check stalls | `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/internvl.py`, `python/sglang/srt/multimodal/processors/minicpm.py` |
| 2026-05-22 | [#23220](https://github.com/sgl-project/sglang/pull/23220) | merged | Bugfix: Qwen3-VL-MoE adapt encoder_only | `python/sglang/srt/models/qwen3_vl_moe.py` |
| 2026-05-23 | [#24144](https://github.com/sgl-project/sglang/pull/24144) | merged | [BugFix][EPD] adapt for qwen3.5-mtp & del duplicated logs | `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2026-05-23 | [#26116](https://github.com/sgl-project/sglang/pull/26116) | merged | [VLM] Reuse Qwen pretokenized ids | `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2026-05-24 | [#26100](https://github.com/sgl-project/sglang/pull/26100) | merged | [VLM] adopt simplified get_rope_index for image-only requests | `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2026-05-24 | [#26101](https://github.com/sgl-project/sglang/pull/26101) | merged | [VLM] accept precomputed multimodal metadata | `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2026-05-24 | [#26167](https://github.com/sgl-project/sglang/pull/26167) | merged | [VLM] feat: replace small H2D calls with a single one for qwen-vl | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2026-05-24 | [#23469](https://github.com/sgl-project/sglang/pull/23469) | closed | [NPU] adapt the Qwen3-ASR model for deployment on NPU | `python/sglang/srt/utils/common.py` |
| 2026-05-25 | [#26094](https://github.com/sgl-project/sglang/pull/26094) | merged | [VLM] fix: fix only the grids from last split mm item is collected for qwen-vl | `python/sglang/srt/multimodal/processors/qwen_vl.py` |
| 2026-05-25 | [#19242](https://github.com/sgl-project/sglang/pull/19242) | closed | [feat] feat: add Qwen3-ASR support like whisper | `python/sglang/srt/multimodal/processors/qwen3_asr.py`, `python/sglang/srt/configs/qwen3_asr.py`, `python/sglang/srt/configs/__init__.py` |
| 2026-05-27 | [#12662](https://github.com/sgl-project/sglang/pull/12662) | merged | [CPU] Add support for Qwen3-vl and Qwen3-omni | `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/models/qwen3_vl.py` |
| 2026-05-27 | [#22848](https://github.com/sgl-project/sglang/pull/22848) | merged | [Feature] WebSocket streaming audio input for ASR | `test/manual/models/test_qwen3_asr.py` |
| 2026-06-02 | [#25813](https://github.com/sgl-project/sglang/pull/25813) | merged | docs(cookbook): port popular model usage guides into cookbook pages | `docs_new/docs/basic_usage/deepseek_v32.mdx`, `docs_new/docs/basic_usage/deepseek_v3.mdx`, `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V3_2.mdx` |
| 2026-06-03 | [#25198](https://github.com/sgl-project/sglang/pull/25198) | merged | [Docs] Update Nemotron3-Nano-Omni cookbook to reflect new model paths | `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` |
| 2026-06-04 | [#27240](https://github.com/sgl-project/sglang/pull/27240) | merged | [Docs] re-organize nemotron cookbook | `docs_new/docs.json`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Ultra.mdx`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` |
| 2026-06-11 | [#13918](https://github.com/sgl-project/sglang/pull/13918) | closed | [VLM] support qwen3-vl eagle infer | `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/llama_eagle3.py` |
| 2026-06-11 | [#17276](https://github.com/sgl-project/sglang/pull/17276) | closed | Add Qwen3VL Eagle3 Inference Support | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-06-18 | [#28567](https://github.com/sgl-project/sglang/pull/28567) | merged | Add get_parallel(): a structured accessor for parallel-topology state | `python/sglang/srt/models/apertus.py`, `python/sglang/srt/models/solar.py`, `python/sglang/srt/models/gpt_oss.py` |
| 2026-06-24 | [#28940](https://github.com/sgl-project/sglang/pull/28940) | merged | [VLM] Qwen3-VL / Moss-VL ViT preprocessing optimizations | `python/sglang/srt/models/qwen3_vl.py` |
| 2026-06-25 | [#29261](https://github.com/sgl-project/sglang/pull/29261) | merged | [Docs] Fix broken links in cookbook | `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V4.mdx`, `docs_new/cookbook/autoregressive/GLM/GLM-4.7.mdx`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` |

## 逐 PR diff 审计卡

### PR #2055 - Add support for Qwen2-VL-based embedding models

- 链接: https://github.com/sgl-project/sglang/pull/2055
- 状态/时间: merged / 2024-11-21
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_vl.py`；关联提交 `f6f713797bcb`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 4 个文件，+39/-12，可读 patch 114 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Add support for Qwen2-VL-based embedding models」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen2_vl.py`；技术摘要: 覆盖「Add support for Qwen2-VL-based embedding models」；主要实现面是 `python/sglang/srt/models/qwen2_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_vl.py` modified +12/-5 (17 lines); hunks: -44,6 +44,7; -559,6 +560,7 @@ def __init__(; symbols: __init__, _process_image_input, forward，涉及 `__init__, _process_image_input, forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_vl.py` modified +12/-5 (17 lines); hunks: -44,6 +44,7; -559,6 +560,7 @@ def __init__(; symbols: __init__, _process_image_input, forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_vl.py
@@ -44,6 +44,7 @@
+from sglang.srt.layers.pooler import Pooler, PoolingType
@@ -559,6 +560,7 @@ def __init__(
+        self.pooler = Pooler(pooling_type=PoolingType.LAST, normalize=True)
@@ -577,6 +579,7 @@ def forward(
+        get_embedding: bool = False,
@@ -599,8 +602,8 @@ def forward(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_vl.py` modified +12/-5
- 验证与风险: diff 自带测试面 `python/sglang/test/runners.py`, `test/srt/models/test_embedding_models.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #5003 - Support for Qwen2.5-VL Model in bitsandbytes Format

- 链接: https://github.com/sgl-project/sglang/pull/5003
- 状态/时间: merged / 2025-04-14
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py`；关联提交 `072df753546b`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 6 个文件，+375/-45，可读 patch 531 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Support for Qwen2.5-VL Model in bitsandbytes Format」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen2_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「Support for Qwen2.5-VL Model in bitsandbytes Format」；主要实现面是 `python/sglang/srt/models/qwen2_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_vl.py` modified +24/-23 (47 lines); hunks: -152,7 +152,7 @@ def __init__(; -351,7 +351,7 @@ def __init__(; symbols: __init__, dtype, device, forward，涉及 `__init__, dtype, device`；`python/sglang/srt/models/qwen2_5_vl.py` modified +24/-22 (46 lines); hunks: -141,7 +141,7 @@ def __init__(; -325,7 +325,7 @@ def get_window_index(self, grid_thw):; symbols: __init__, get_window_index, dtype, device，涉及 `__init__, get_window_index, dtype`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_vl.py` modified +24/-23 (47 lines); hunks: -152,7 +152,7 @@ def __init__(; -351,7 +351,7 @@ def __init__(; symbols: __init__, dtype, device, forward
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +24/-22 (46 lines); hunks: -141,7 +141,7 @@ def __init__(; -325,7 +325,7 @@ def get_window_index(self, grid_thw):; symbols: __init__, get_window_index, dtype, device
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_vl.py
@@ -152,7 +152,7 @@ def __init__(
-            use_qkv_parallel=False,
+            use_qkv_parallel=True,
@@ -351,7 +351,7 @@ def __init__(
-        return next(self.parameters()).dtype
+        return self.patch_embed.proj.weight.dtype
@@ -423,6 +423,25 @@ def forward(
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -141,7 +141,7 @@ def __init__(
-            use_qkv_parallel=False,
+            use_qkv_parallel=True,
@@ -325,7 +325,7 @@ def get_window_index(self, grid_thw):
-        return self.blocks[0].mlp.gate_proj.weight.dtype
+        return self.patch_embed.proj.weight.dtype
@@ -429,6 +429,25 @@ def forward(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_vl.py` modified +24/-23; `python/sglang/srt/models/qwen2_5_vl.py` modified +24/-22
- 验证与风险: diff 自带测试面 `test/srt/run_suite.py`, `test/srt/test_bnb.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #5349 - vlm: enable radix cache for qwen-vl models

- 链接: https://github.com/sgl-project/sglang/pull/5349
- 状态/时间: merged / 2025-04-24
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py`；关联提交 `c998d04b4692`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 26 个文件，+435/-337，可读 patch 1363 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「vlm: enable radix cache for qwen-vl models」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen2_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「vlm: enable radix cache for qwen-vl models」；主要实现面是 `python/sglang/srt/models/qwen2_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_vl.py` modified +3/-7 (10 lines); hunks: -42,7 +42,7; -490,15 +490,11 @@ def __init__(; symbols: __init__, pad_input_ids, get_image_feature，涉及 `__init__, pad_input_ids, get_image_feature`；`python/sglang/srt/models/qwen2_5_vl.py` modified +3/-6 (9 lines); hunks: -49,7 +49,7; -488,11 +488,8 @@ def __init__(; symbols: __init__, pad_input_ids, get_image_feature，涉及 `__init__, pad_input_ids, get_image_feature`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_vl.py` modified +3/-7 (10 lines); hunks: -42,7 +42,7; -490,15 +490,11 @@ def __init__(; symbols: __init__, pad_input_ids, get_image_feature
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +3/-6 (9 lines); hunks: -49,7 +49,7; -488,11 +488,8 @@ def __init__(; symbols: __init__, pad_input_ids, get_image_feature
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_vl.py
@@ -42,7 +42,7 @@
-    MultiModalityDataPaddingPatternTokenPairs,
+    MultiModalityDataPaddingPatternMultimodalTokens,
@@ -490,15 +490,11 @@ def __init__(
-    # Use grid_t * grid_w * grid_h to pad tokens for each image
-    # add replaced padding by unique image hash
-        im_start_id: int = mm_inputs.im_start_id
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -49,7 +49,7 @@
-    MultiModalityDataPaddingPatternTokenPairs,
+    MultiModalityDataPaddingPatternMultimodalTokens,
@@ -488,11 +488,8 @@ def __init__(
-        im_start_id: int = mm_inputs.im_start_id
-        im_end_id: int = mm_inputs.im_end_id
-        media_token_pairs = [(im_start_id, im_end_id)]
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_vl.py` modified +3/-7; `python/sglang/srt/models/qwen2_5_vl.py` modified +3/-6
- 验证与风险: diff 自带测试面 `python/sglang/test/runners.py`, `test/srt/run_suite.py`, `test/srt/test_vision_openai_server.py`, `test/srt/test_vlm_accuracy.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #5783 - Remove unused method `calculate_num_image_tokens` from qwen2_vl.py

- 链接: https://github.com/sgl-project/sglang/pull/5783
- 状态/时间: merged / 2025-05-01
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_vl.py`；关联提交 `e97e57e699e5`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+0/-12，可读 patch 19 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Remove unused method `calculate_num_image_tokens` from qwen2_vl.py」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/qwen2_vl.py`；技术摘要: 覆盖「Remove unused method `calculate_num_image_tokens` from qwen2_vl.py」；主要实现面是 `python/sglang/srt/models/qwen2_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_vl.py` modified +0/-12 (12 lines); hunks: -442,18 +442,6 @@ class Qwen2VLForConditionalGeneration(nn.Module):; symbols: Qwen2VLForConditionalGeneration, calculate_num_image_tokens, __init__，涉及 `Qwen2VLForConditionalGeneration, calculate_num_image_tokens, __init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_vl.py` modified +0/-12 (12 lines); hunks: -442,18 +442,6 @@ class Qwen2VLForConditionalGeneration(nn.Module):; symbols: Qwen2VLForConditionalGeneration, calculate_num_image_tokens, __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_vl.py
@@ -442,18 +442,6 @@ class Qwen2VLForConditionalGeneration(nn.Module):
-    def calculate_num_image_tokens(self, image_grid_thw: Tuple[int, int, int]):
-        processor = cached_get_processor(self.config._name_or_path)
-        grid_t, grid_h, grid_w = image_grid_thw
-        num_image_tokens = (
-            grid_t
-            * grid_h
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_vl.py` modified +0/-12
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen2_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #6136 - Support precomputed multimodal features for Qwen-VL and Gemma3 models.

- 链接: https://github.com/sgl-project/sglang/pull/6136
- 状态/时间: merged / 2025-05-16
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py`；关联提交 `f19a9204cdbd`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 14 个文件，+592/-125，可读 patch 1118 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Support precomputed multimodal features for Qwen-VL and Gemma3 models.」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py`；技术摘要: 覆盖「Support precomputed multimodal features for Qwen-VL and Gemma3 models.」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +6/-0 (6 lines); hunks: -497,6 +497,12 @@ def pad_input_ids(self, input_ids: List[int], mm_inputs: Mu...; symbols: pad_input_ids, get_image_feature，涉及 `pad_input_ids, get_image_feature`；`python/sglang/srt/models/qwen2_vl.py` modified +6/-0 (6 lines); hunks: -486,6 +486,12 @@ def pad_input_ids(self, input_ids: List[int], mm_inputs: Mu...; symbols: pad_input_ids, get_image_feature，涉及 `pad_input_ids, get_image_feature`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +6/-0 (6 lines); hunks: -497,6 +497,12 @@ def pad_input_ids(self, input_ids: List[int], mm_inputs: Mu...; symbols: pad_input_ids, get_image_feature
  - `python/sglang/srt/models/qwen2_vl.py` modified +6/-0 (6 lines); hunks: -486,6 +486,12 @@ def pad_input_ids(self, input_ids: List[int], mm_inputs: Mu...; symbols: pad_input_ids, get_image_feature
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -497,6 +497,12 @@ def pad_input_ids(self, input_ids: List[int], mm_inputs: MultimodalInputs):
+        if any(item.precomputed_features is not None for item in items):
+            if not all(item.precomputed_features is not None for item in items):
+                raise NotImplementedError(
+                    "MM inputs where only some items are precomputed."
+                )
+            return torch.concat([item.precomputed_features for item in items])
diff -- python/sglang/srt/models/qwen2_vl.py
@@ -486,6 +486,12 @@ def pad_input_ids(self, input_ids: List[int], mm_inputs: MultimodalInputs):
+        if any(item.precomputed_features is not None for item in items):
+            if not all(item.precomputed_features is not None for item in items):
+                raise NotImplementedError(
+                    "MM inputs where only some items are precomputed."
+                )
+            return torch.concat([item.precomputed_features for item in items])
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +6/-0; `python/sglang/srt/models/qwen2_vl.py` modified +6/-0
- 验证与风险: diff 自带测试面 `test/srt/test_skip_tokenizer_init.py`, `test/srt/test_vlm_accuracy.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #9014 - Fuse writing KV buffer into rope kernel (part 2: srt)

- 链接: https://github.com/sgl-project/sglang/pull/9014
- 状态/时间: merged / 2025-08-12
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 6 个文件，+65/-6，可读 patch 147 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Fuse writing KV buffer into rope kernel (part 2: srt)」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/gpt_oss.py`, `python/sglang/srt/layers/rotary_embedding.py`, `python/sglang/srt/entrypoints/engine.py`；技术摘要: 覆盖「Fuse writing KV buffer into rope kernel (part 2: srt)」；主要实现面是 `python/sglang/srt/models/gpt_oss.py`, `python/sglang/srt/layers/rotary_embedding.py`, `python/sglang/srt/entrypoints/engine.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/gpt_oss.py` modified +51/-2 (53 lines); hunks: -66,10 +66,15; -196,6 +201,32 @@ def forward_normal(; symbols: GptOssConfig, forward_normal, _enable_fused_set_kv_buffer, _create_fused_set_kv_buffer_arg，涉及 `GptOssConfig, forward_normal, _enable_fused_set_kv_buffer`；`python/sglang/srt/layers/rotary_embedding.py` modified +10/-0 (10 lines); hunks: -222,6 +222,7 @@ def forward_cuda(; -231,8 +232,17 @@ def forward_cuda(; symbols: forward_cuda，涉及 `forward_cuda`；`python/sglang/srt/entrypoints/engine.py` modified +1/-1 (2 lines); hunks: -655,7 +655,7 @@ def _set_envs_and_config(server_args: ServerArgs):; symbols: _set_envs_and_config，涉及 `_set_envs_and_config`；`.github/workflows/pr-test-pd-router.yml` modified +1/-1 (2 lines); hunks: -119,7 +119,7 @@ jobs:。
- 代码 diff 细节:
  - `python/sglang/srt/models/gpt_oss.py` modified +51/-2 (53 lines); hunks: -66,10 +66,15; -196,6 +201,32 @@ def forward_normal(; symbols: GptOssConfig, forward_normal, _enable_fused_set_kv_buffer, _create_fused_set_kv_buffer_arg
  - `python/sglang/srt/layers/rotary_embedding.py` modified +10/-0 (10 lines); hunks: -222,6 +222,7 @@ def forward_cuda(; -231,8 +232,17 @@ def forward_cuda(; symbols: forward_cuda
  - `python/sglang/srt/entrypoints/engine.py` modified +1/-1 (2 lines); hunks: -655,7 +655,7 @@ def _set_envs_and_config(server_args: ServerArgs):; symbols: _set_envs_and_config
  - `.github/workflows/pr-test-pd-router.yml` modified +1/-1 (2 lines); hunks: -119,7 +119,7 @@ jobs:
  - `docker/Dockerfile.gb200` modified +1/-1 (2 lines); hunks: -64,7 +64,7 @@ RUN python3 -m pip install --no-cache-dir --upgrade pip setupt...
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/gpt_oss.py
@@ -66,10 +66,15 @@
+_is_cuda = is_cuda()
+if _is_cuda:
+    from sgl_kernel import FusedSetKVBufferArg
@@ -196,6 +201,32 @@ def forward_normal(
+def _enable_fused_set_kv_buffer():
+    return _is_cuda
diff -- python/sglang/srt/layers/rotary_embedding.py
@@ -222,6 +222,7 @@ def forward_cuda(
+        fused_set_kv_buffer_arg=None,  # Optional[FusedSetKVBufferArg]
@@ -231,8 +232,17 @@ def forward_cuda(
+                # Compatible with old sgl-kernel
+                **(
+                    dict(fused_set_kv_buffer_arg=fused_set_kv_buffer_arg)
+                    if fused_set_kv_buffer_arg is not None
diff -- python/sglang/srt/entrypoints/engine.py
@@ -655,7 +655,7 @@ def _set_envs_and_config(server_args: ServerArgs):
```

- 已读文件:
  - runtime: `python/sglang/srt/models/gpt_oss.py` modified +51/-2; `python/sglang/srt/layers/rotary_embedding.py` modified +10/-0; `python/sglang/srt/entrypoints/engine.py` modified +1/-1; `python/pyproject.toml` modified +1/-1
  - ci: `.github/workflows/pr-test-pd-router.yml` modified +1/-1
  - other: `docker/Dockerfile.gb200` modified +1/-1
- 验证与风险: runtime 路径改动集中在 `python/pyproject.toml`, `python/sglang/srt/entrypoints/engine.py`, `python/sglang/srt/layers/rotary_embedding.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #8801 - Qwen2.5-VL eagle3 infer

- 链接: https://github.com/sgl-project/sglang/pull/8801
- 状态/时间: merged / 2025-09-08
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`；关联提交 `37d83c6e6d8a`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 9 个文件，+114/-5，可读 patch 260 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Qwen2.5-VL eagle3 infer」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「Qwen2.5-VL eagle3 infer」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +24/-1 (25 lines); hunks: -517,6 +517,9 @@ def __init__(; -587,9 +590,13 @@ def forward(; symbols: __init__, pad_input_ids, forward, load_weights，涉及 `__init__, pad_input_ids, forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +24/-1 (25 lines); hunks: -517,6 +517,9 @@ def __init__(; -587,9 +590,13 @@ def forward(; symbols: __init__, pad_input_ids, forward, load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -517,6 +517,9 @@ def __init__(
+        # For EAGLE3 support
+        self.capture_aux_hidden_states = False
@@ -587,9 +590,13 @@ def forward(
+        aux_hidden_states = None
+        if self.capture_aux_hidden_states:
+            hidden_states, aux_hidden_states = hidden_states
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +24/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/managers/mm_utils.py`, `python/sglang/srt/model_executor/cuda_graph_runner.py`, `python/sglang/srt/model_executor/forward_batch_info.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #10323 - model: support qwen3-vl series

- 链接: https://github.com/sgl-project/sglang/pull/10323
- 状态/时间: merged / 2025-09-23
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/configs/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；关联提交 `4f564b9e8378`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 7 个文件，+1898/-8，可读 patch 2006 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「model: support qwen3-vl series」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/configs/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「model: support qwen3-vl series」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/configs/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` added +787/-0 (787 lines); hunks: -0,0 +1,787; symbols: Qwen3_VisionMLP, __init__, forward, Qwen3VLVisionPatchEmbed，涉及 `Qwen3_VisionMLP, __init__, forward`；`python/sglang/srt/configs/qwen3_vl.py` added +586/-0 (586 lines); hunks: -0,0 +1,586; symbols: Qwen3VLVisionConfig, __init__, Qwen3VLTextConfig, to，涉及 `Qwen3VLVisionConfig, __init__, Qwen3VLTextConfig`；`python/sglang/srt/models/qwen3_vl_moe.py` added +471/-0 (471 lines); hunks: -0,0 +1,471; symbols: Qwen3MoeLLMModel, __init__, get_input_embeddings, get_image_feature，涉及 `Qwen3MoeLLMModel, __init__, get_input_embeddings`；`python/sglang/srt/multimodal/processors/qwen_vl.py` modified +8/-1 (9 lines); hunks: -12,6 +12,8; -209,7 +211,12 @@ async def preprocess_video(; symbols: preprocess_video, Qwen2_5VLImageProcessor, __init__，涉及 `preprocess_video, Qwen2_5VLImageProcessor, __init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` added +787/-0 (787 lines); hunks: -0,0 +1,787; symbols: Qwen3_VisionMLP, __init__, forward, Qwen3VLVisionPatchEmbed
  - `python/sglang/srt/configs/qwen3_vl.py` added +586/-0 (586 lines); hunks: -0,0 +1,586; symbols: Qwen3VLVisionConfig, __init__, Qwen3VLTextConfig, to
  - `python/sglang/srt/models/qwen3_vl_moe.py` added +471/-0 (471 lines); hunks: -0,0 +1,471; symbols: Qwen3MoeLLMModel, __init__, get_input_embeddings, get_image_feature
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +8/-1 (9 lines); hunks: -12,6 +12,8; -209,7 +211,12 @@ async def preprocess_video(; symbols: preprocess_video, Qwen2_5VLImageProcessor, __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -0,0 +1,787 @@
+# Copyright 2025 Qwen Team
+# Copyright 2025 SGLang Team
+# Licensed under the Apache License, Version 2.0 (the "License");
+# you may not use this file except in compliance with the License.
+# You may obtain a copy of the License at
+#
diff -- python/sglang/srt/configs/qwen3_vl.py
@@ -0,0 +1,586 @@
+from typing import Optional, Union
+from transformers import PretrainedConfig
+from transformers.modeling_rope_utils import rope_config_validation
+class Qwen3VLVisionConfig(PretrainedConfig):
+    model_type = "qwen3_vl"
+    base_config_key = "vision_config"
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -0,0 +1,471 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` added +787/-0; `python/sglang/srt/configs/qwen3_vl.py` added +586/-0; `python/sglang/srt/models/qwen3_vl_moe.py` added +471/-0; `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +8/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/configs/model_config.py`, `python/sglang/srt/configs/qwen3_vl.py`, `python/sglang/srt/layers/rotary_embedding.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #10749 - Fuse write kv buffer into rope for qwen3 moe & bailing moe

- 链接: https://github.com/sgl-project/sglang/pull/10749
- 状态/时间: merged / 2025-09-26
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 4 个文件，+105/-34，可读 patch 207 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Fuse write kv buffer into rope for qwen3 moe & bailing moe」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/utils.py`, `python/sglang/srt/models/gpt_oss.py`, `python/sglang/srt/models/bailing_moe.py`；技术摘要: 覆盖「Fuse write kv buffer into rope for qwen3 moe & bailing moe」；主要实现面是 `python/sglang/srt/models/utils.py`, `python/sglang/srt/models/gpt_oss.py`, `python/sglang/srt/models/bailing_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/utils.py` added +51/-0 (51 lines); hunks: -0,0 +1,51; symbols: enable_fused_set_kv_buffer, create_fused_set_kv_buffer_arg，涉及 `enable_fused_set_kv_buffer, create_fused_set_kv_buffer_arg`；`python/sglang/srt/models/gpt_oss.py` modified +7/-30 (37 lines); hunks: -66,6 +66,10; -193,33 +197,6 @@ def forward_normal(; symbols: forward_normal, _enable_fused_set_kv_buffer, _create_fused_set_kv_buffer_arg, GptOssAttention，涉及 `forward_normal, _enable_fused_set_kv_buffer, _create_fused_set_kv_buffer_arg`；`python/sglang/srt/models/bailing_moe.py` modified +25/-2 (27 lines); hunks: -72,6 +72,10; -555,8 +559,27 @@ def forward(; symbols: forward，涉及 `forward`；`python/sglang/srt/models/qwen3_moe.py` modified +22/-2 (24 lines); hunks: -60,6 +60,10; -412,15 +416,31 @@ def forward_prepare(; symbols: forward_prepare, forward_core，涉及 `forward_prepare, forward_core`。
- 代码 diff 细节:
  - `python/sglang/srt/models/utils.py` added +51/-0 (51 lines); hunks: -0,0 +1,51; symbols: enable_fused_set_kv_buffer, create_fused_set_kv_buffer_arg
  - `python/sglang/srt/models/gpt_oss.py` modified +7/-30 (37 lines); hunks: -66,6 +66,10; -193,33 +197,6 @@ def forward_normal(; symbols: forward_normal, _enable_fused_set_kv_buffer, _create_fused_set_kv_buffer_arg, GptOssAttention
  - `python/sglang/srt/models/bailing_moe.py` modified +25/-2 (27 lines); hunks: -72,6 +72,10; -555,8 +559,27 @@ def forward(; symbols: forward
  - `python/sglang/srt/models/qwen3_moe.py` modified +22/-2 (24 lines); hunks: -60,6 +60,10; -412,15 +416,31 @@ def forward_prepare(; symbols: forward_prepare, forward_core
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/utils.py
@@ -0,0 +1,51 @@
+# Copyright 2023-2025 SGLang Team
+# Licensed under the Apache License, Version 2.0 (the "License");
+# you may not use this file except in compliance with the License.
+# You may obtain a copy of the License at
+#
+#     http://www.apache.org/licenses/LICENSE-2.0
diff -- python/sglang/srt/models/gpt_oss.py
@@ -66,6 +66,10 @@
+from sglang.srt.models.utils import (
+    create_fused_set_kv_buffer_arg,
+    enable_fused_set_kv_buffer,
+)
@@ -193,33 +197,6 @@ def forward_normal(
-def _enable_fused_set_kv_buffer(forward_batch: ForwardBatch):
diff -- python/sglang/srt/models/bailing_moe.py
@@ -72,6 +72,10 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/models/utils.py` added +51/-0; `python/sglang/srt/models/gpt_oss.py` modified +7/-30; `python/sglang/srt/models/bailing_moe.py` modified +25/-2; `python/sglang/srt/models/qwen3_moe.py` modified +22/-2
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/bailing_moe.py`, `python/sglang/srt/models/gpt_oss.py`, `python/sglang/srt/models/qwen3_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #10985 - Quick Fix: fix Qwen3-VL launch failure caused by MRotaryEmbedding arg

- 链接: https://github.com/sgl-project/sglang/pull/10985
- 状态/时间: merged / 2025-10-01
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+14/-2，可读 patch 58 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Quick Fix: fix Qwen3-VL launch failure caused by MRotaryEmbedding arg」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_moe.py`, `python/sglang/srt/layers/rotary_embedding.py`；技术摘要: 覆盖「Quick Fix: fix Qwen3-VL launch failure caused by MRotaryEmbedding arg」；主要实现面是 `python/sglang/srt/models/qwen3_moe.py`, `python/sglang/srt/layers/rotary_embedding.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_moe.py` modified +10/-2 (12 lines); hunks: -51,7 +51,7; -358,6 +358,10 @@ def __init__(; symbols: __init__, forward_prepare, forward_core，涉及 `__init__, forward_prepare, forward_core`；`python/sglang/srt/layers/rotary_embedding.py` modified +4/-0 (4 lines); hunks: -1065,6 +1065,7 @@ def forward(; -1075,6 +1076,9 @@ def forward(; symbols: forward，涉及 `forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_moe.py` modified +10/-2 (12 lines); hunks: -51,7 +51,7; -358,6 +358,10 @@ def __init__(; symbols: __init__, forward_prepare, forward_core
  - `python/sglang/srt/layers/rotary_embedding.py` modified +4/-0 (4 lines); hunks: -1065,6 +1065,7 @@ def forward(; -1075,6 +1076,9 @@ def forward(; symbols: forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_moe.py
@@ -51,7 +51,7 @@
-from sglang.srt.layers.rotary_embedding import get_rope
+from sglang.srt.layers.rotary_embedding import MRotaryEmbedding, get_rope
@@ -358,6 +358,10 @@ def __init__(
+        self.compatible_with_fused_kv_buffer = (
+            False if isinstance(self.rotary_emb, MRotaryEmbedding) else True
+        )
diff -- python/sglang/srt/layers/rotary_embedding.py
@@ -1065,6 +1065,7 @@ def forward(
+        fused_set_kv_buffer_arg: Optional[FusedSetKVBufferArg] = None,
@@ -1075,6 +1076,9 @@ def forward(
+        assert (
+            fused_set_kv_buffer_arg is None
+        ), "save kv cache is not supported for MRotaryEmbedding."
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_moe.py` modified +10/-2; `python/sglang/srt/layers/rotary_embedding.py` modified +4/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/layers/rotary_embedding.py`, `python/sglang/srt/models/qwen3_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #11481 - [smol] [perf] Qwen3-VL in place op.

- 链接: https://github.com/sgl-project/sglang/pull/11481
- 状态/时间: merged / 2025-10-12
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`；关联提交 `be740acdb0ad`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+7/-11，可读 patch 55 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[smol] [perf] Qwen3-VL in place op.」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「[smol] [perf] Qwen3-VL in place op.」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +4/-7 (11 lines); hunks: -189,10 +189,10 @@ def forward(; -441,7 +441,7 @@ def forward(; symbols: forward，涉及 `forward`；`python/sglang/srt/models/qwen3_vl_moe.py` modified +3/-4 (7 lines); hunks: -114,7 +114,7 @@ def forward(; -130,9 +130,8 @@ def forward(; symbols: forward，涉及 `forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +4/-7 (11 lines); hunks: -189,10 +189,10 @@ def forward(; -441,7 +441,7 @@ def forward(; symbols: forward
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +3/-4 (7 lines); hunks: -114,7 +114,7 @@ def forward(; -130,9 +130,8 @@ def forward(; symbols: forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -189,10 +189,10 @@ def forward(
-        x = x + attn
+        x += attn
-        x = x + mlp
+        x += mlp
@@ -441,7 +441,7 @@ def forward(
-        x = x + pos_embeds
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -114,7 +114,7 @@ def forward(
-            layer_idx = layer_idx + self.start_layer
+            layer_idx += self.start_layer
@@ -130,9 +130,8 @@ def forward(
-                hidden_states = (
-                    hidden_states
-                    + input_deepstack_embeds[:, sep : sep + self.hidden_size]
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +4/-7; `python/sglang/srt/models/qwen3_vl_moe.py` modified +3/-4
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #11458 - [BugFix][Qwen3-VL]: fix cu_seqlens in qwen3-vl

- 链接: https://github.com/sgl-project/sglang/pull/11458
- 状态/时间: merged / 2025-10-15
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `b2c856692092`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+5/-3，可读 patch 19 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[BugFix][Qwen3-VL]: fix cu_seqlens in qwen3-vl」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[BugFix][Qwen3-VL]: fix cu_seqlens in qwen3-vl」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +5/-3 (8 lines); hunks: -452,13 +452,15 @@ def forward(; symbols: forward，涉及 `forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +5/-3 (8 lines); hunks: -452,13 +452,15 @@ def forward(; symbols: forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -452,13 +452,15 @@ def forward(
+        cu_seqlens = torch.repeat_interleave(
+            grid_thw[:, 1] * grid_thw[:, 2], grid_thw[:, 0]
+        ).cumsum(dim=0)
-                torch.tensor([0], device=grid_thw.device),
-                (grid_thw[:, 0] * grid_thw[:, 1] * grid_thw[:, 2]).cumsum(dim=0),
+                torch.zeros(1, dtype=torch.int32, device=cu_seqlens.device),
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +5/-3
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #10911 - model: qwen3-omni (thinker-only)

- 链接: https://github.com/sgl-project/sglang/pull/10911
- 状态/时间: merged / 2025-10-16
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/configs/qwen3_omni.py`, `python/sglang/srt/configs/qwen3_vl.py`, `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py` 等 6 个文件；关联提交 `86b04d25b3f6`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 16 个文件，+1947/-328，可读 patch 2837 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「model: qwen3-omni (thinker-only)」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/configs/qwen3_omni.py`, `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「model: qwen3-omni (thinker-only)」；主要实现面是 `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/configs/qwen3_omni.py`, `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_omni_moe.py` added +661/-0 (661 lines); hunks: -0,0 +1,661; symbols: Qwen3OmniMoeAudioEncoderLayer, __init__, forward, SinusoidsPositionEmbedding，涉及 `Qwen3OmniMoeAudioEncoderLayer, __init__, forward`；`python/sglang/srt/configs/qwen3_omni.py` added +613/-0 (613 lines); hunks: -0,0 +1,613; symbols: Qwen3OmniMoeAudioEncoderConfig, __init__, Qwen3OmniMoeVisionEncoderConfig, Qwen3OmniMoeTextConfig，涉及 `Qwen3OmniMoeAudioEncoderConfig, __init__, Qwen3OmniMoeVisionEncoderConfig`；`python/sglang/srt/models/qwen3_vl_moe.py` modified +53/-168 (221 lines); hunks: -14,41 +14,27; -60,28 +46,16 @@ class Qwen3MoeLLMModel(Qwen3MoeModel):; symbols: Qwen3MoeLLMModel, __init__, get_input_embeddings, get_image_feature，涉及 `Qwen3MoeLLMModel, __init__, get_input_embeddings`；`python/sglang/srt/models/qwen3_vl.py` modified +38/-24 (62 lines); hunks: -15,7 +15,7; -27,7 +27,11; symbols: forward, Qwen3_VisionPatchMerger, Qwen3VLMoeVisionPatchMerger, __init__，涉及 `forward, Qwen3_VisionPatchMerger, Qwen3VLMoeVisionPatchMerger`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_omni_moe.py` added +661/-0 (661 lines); hunks: -0,0 +1,661; symbols: Qwen3OmniMoeAudioEncoderLayer, __init__, forward, SinusoidsPositionEmbedding
  - `python/sglang/srt/configs/qwen3_omni.py` added +613/-0 (613 lines); hunks: -0,0 +1,613; symbols: Qwen3OmniMoeAudioEncoderConfig, __init__, Qwen3OmniMoeVisionEncoderConfig, Qwen3OmniMoeTextConfig
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +53/-168 (221 lines); hunks: -14,41 +14,27; -60,28 +46,16 @@ class Qwen3MoeLLMModel(Qwen3MoeModel):; symbols: Qwen3MoeLLMModel, __init__, get_input_embeddings, get_image_feature
  - `python/sglang/srt/models/qwen3_vl.py` modified +38/-24 (62 lines); hunks: -15,7 +15,7; -27,7 +27,11; symbols: forward, Qwen3_VisionPatchMerger, Qwen3VLMoeVisionPatchMerger, __init__
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +40/-6 (46 lines); hunks: -12,6 +12,7; -209,22 +210,31 @@ async def preprocess_video(; symbols: preprocess_video, Qwen2_5VLImageProcessor, QwenVLImageProcessor, __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_omni_moe.py
@@ -0,0 +1,661 @@
+# Copyright 2025 Qwen Team
+# Copyright 2025 SGLang Team
+# Licensed under the Apache License, Version 2.0 (the "License");
+# you may not use this file except in compliance with the License.
+# You may obtain a copy of the License at
+#
diff -- python/sglang/srt/configs/qwen3_omni.py
@@ -0,0 +1,613 @@
+from transformers import PretrainedConfig
+from transformers.configuration_utils import layer_type_validation
+from transformers.modeling_rope_utils import rope_config_validation
+from sglang.utils import logger
+class Qwen3OmniMoeAudioEncoderConfig(PretrainedConfig):
+    model_type = "qwen3_omni_moe_audio_encoder"
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -14,41 +14,27 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_omni_moe.py` added +661/-0; `python/sglang/srt/configs/qwen3_omni.py` added +613/-0; `python/sglang/srt/models/qwen3_vl_moe.py` modified +53/-168; `python/sglang/srt/models/qwen3_vl.py` modified +38/-24; `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +40/-6; `python/sglang/srt/configs/qwen3_vl.py` modified +0/-10
- 验证与风险: diff 自带测试面 `test/srt/test_vision_openai_server_a.py`, `test/srt/test_vision_openai_server_b.py`, `test/srt/test_vision_openai_server_common.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #11377 - [BugFix][Qwen3-VL]: add metadata for video in qwen3-vl

- 链接: https://github.com/sgl-project/sglang/pull/11377
- 状态/时间: merged / 2025-10-21
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/multimodal/processors/qwen_vl.py`；关联提交 `fde2decf8b59`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+26/-8，可读 patch 49 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[BugFix][Qwen3-VL]: add metadata for video in qwen3-vl」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「[BugFix][Qwen3-VL]: add metadata for video in qwen3-vl」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +26/-8 (34 lines); hunks: -214,7 +214,14 @@ async def preprocess_video(; -279,14 +286,25 @@ async def process_mm_data_async(; symbols: preprocess_video, process_mm_data_async，涉及 `preprocess_video, process_mm_data_async`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +26/-8 (34 lines); hunks: -214,7 +214,14 @@ async def preprocess_video(; -279,14 +286,25 @@ async def process_mm_data_async(; symbols: preprocess_video, process_mm_data_async
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -214,7 +214,14 @@ async def preprocess_video(
-    return video
+    video_metadata = {
+        "fps": video_fps,
+        "duration": total_frames / video_fps,
+        "total_num_frames": total_frames,
+        "frames_indices": idx,
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +26/-8
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #12261 - [BugFix][Qwen2.5-VL]: fix cu_seqlens in qwen2.5-vl

- 链接: https://github.com/sgl-project/sglang/pull/12261
- 状态/时间: open / 2025-10-28
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+5/-5，可读 patch 21 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[BugFix][Qwen2.5-VL]: fix cu_seqlens in qwen2.5-vl」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「[BugFix][Qwen2.5-VL]: fix cu_seqlens in qwen2.5-vl」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +5/-5 (10 lines); hunks: -430,15 +430,15 @@ def forward(; symbols: forward，涉及 `forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +5/-5 (10 lines); hunks: -430,15 +430,15 @@ def forward(; symbols: forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -430,15 +430,15 @@ def forward(
+        cu_seqlens = torch.repeat_interleave(
+            grid_thw[:, 1] * grid_thw[:, 2], grid_thw[:, 0]
+        ).cumsum(dim=0)
-                torch.tensor([0], device=x.device, dtype=torch.int32),
-                (grid_thw[:, 0] * grid_thw[:, 1] * grid_thw[:, 2])
-                .cumsum(dim=0)
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +5/-5
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen2_5_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #12703 - add qwen3-omni docs

- 链接: https://github.com/sgl-project/sglang/pull/12703
- 状态/时间: open / 2025-11-05
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+150/-0，可读 patch 158 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「add qwen3-omni docs」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `docs/basic_usage/qwen3_omni.md`, `docs/index.rst`；技术摘要: 覆盖「add qwen3-omni docs」；主要实现面是 `docs/basic_usage/qwen3_omni.md`, `docs/index.rst`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs/basic_usage/qwen3_omni.md` added +149/-0 (149 lines); hunks: -0,0 +1,149；`docs/index.rst` modified +1/-0 (1 lines); hunks: -31,6 +31,7 @@ Its core features include:。
- 代码 diff 细节:
  - `docs/basic_usage/qwen3_omni.md` added +149/-0 (149 lines); hunks: -0,0 +1,149
  - `docs/index.rst` modified +1/-0 (1 lines); hunks: -31,6 +31,7 @@ Its core features include:
- 关键代码摘录:

```diff
diff -- docs/basic_usage/qwen3_omni.md
@@ -0,0 +1,149 @@
+# Qwen3-Omni Usage
+[Qwen3-Omni](https://huggingface.co/collections/Qwen/qwen3-omni) is a natively end-to-end multilingual omni-modal foundation model. It processes text, images, audio, and video, an
+## Launch Qwen3-Omni with SGLang
+To serve Qwen3-Omni models on 4xH20 GPUs:
+'''bash
+python3 -m sglang.launch_server --model Qwen/Qwen3-Omni-30B-A3B-Instruct --tp 4
diff -- docs/index.rst
@@ -31,6 +31,7 @@ Its core features include:
+   basic_usage/qwen3_omni.md
```

- 已读文件:
  - docs: `docs/basic_usage/qwen3_omni.md` added +149/-0; `docs/index.rst` modified +1/-0
- 验证与风险: 该 PR 主要落在文档/示例 `docs/basic_usage/qwen3_omni.md`, `docs/index.rst`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

### PR #12240 - [VLM] Optimize qwen_vl preprocess_video

- 链接: https://github.com/sgl-project/sglang/pull/12240
- 状态/时间: merged / 2025-11-06
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/multimodal/processors/qwen_vl.py`；关联提交 `fd3034da7515`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+43/-10，可读 patch 131 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Optimize qwen_vl preprocess_video」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「[VLM] Optimize qwen_vl preprocess_video」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +43/-10 (53 lines); hunks: -2,8 +2,10; -175,19 +177,25 @@ async def preprocess_video(; symbols: preprocess_video, process_mm_data_async，涉及 `preprocess_video, process_mm_data_async`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +43/-10 (53 lines); hunks: -2,8 +2,10; -175,19 +177,25 @@ async def preprocess_video(; symbols: preprocess_video, process_mm_data_async
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -2,8 +2,10 @@
+import time
+import numpy as np
@@ -175,19 +177,25 @@ async def preprocess_video(
+    entry_time = time.perf_counter()
-    idx = torch.linspace(0, total_frames - 1, nframes).round().long().tolist()
-    video = vr.get_batch(idx).asnumpy()
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +43/-10
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #12554 - [Docs] Add docs for Qwen3-VL image and video support

- 链接: https://github.com/sgl-project/sglang/pull/12554
- 状态/时间: merged / 2025-11-10
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+131/-0，可读 patch 139 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Docs] Add docs for Qwen3-VL image and video support」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `docs/basic_usage/qwen3_vl.md`, `docs/index.rst`；技术摘要: 覆盖「[Docs] Add docs for Qwen3-VL image and video support」；主要实现面是 `docs/basic_usage/qwen3_vl.md`, `docs/index.rst`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs/basic_usage/qwen3_vl.md` added +130/-0 (130 lines); hunks: -0,0 +1,130；`docs/index.rst` modified +1/-0 (1 lines); hunks: -31,6 +31,7 @@ Its core features include:。
- 代码 diff 细节:
  - `docs/basic_usage/qwen3_vl.md` added +130/-0 (130 lines); hunks: -0,0 +1,130
  - `docs/index.rst` modified +1/-0 (1 lines); hunks: -31,6 +31,7 @@ Its core features include:
- 关键代码摘录:

```diff
diff -- docs/basic_usage/qwen3_vl.md
@@ -0,0 +1,130 @@
+# Qwen3-VL Usage
+[Qwen3-VL](https://huggingface.co/collections/Qwen/qwen3-vl)
+is Alibaba’s latest multimodal large language model with strong text, vision, and reasoning capabilities.
+SGLang supports Qwen3-VL Family of models with Image and Video input support.
+## Launch commands for SGLang
+Below are suggested launch commands tailored for different hardware / precision modes
diff -- docs/index.rst
@@ -31,6 +31,7 @@ Its core features include:
+   basic_usage/qwen3_vl.md
```

- 已读文件:
  - docs: `docs/basic_usage/qwen3_vl.md` added +130/-0; `docs/index.rst` modified +1/-0
- 验证与风险: 该 PR 主要落在文档/示例 `docs/basic_usage/qwen3_vl.md`, `docs/index.rst`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

### PR #12458 - fix: duplicate resize images logic of qwen-vl series models

- 链接: https://github.com/sgl-project/sglang/pull/12458
- 状态/时间: merged / 2025-11-12
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/multimodal/processors/qwen_vl.py`；关联提交 `ffeb28ba6fb7`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 3 个文件，+1/-67，可读 patch 136 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「fix: duplicate resize images logic of qwen-vl series models」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「fix: duplicate resize images logic of qwen-vl series models」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +0/-40 (40 lines); hunks: -1,4 +1,3; -79,26 +78,6 @@ def smart_resize(; symbols: smart_resize, resize_image, round_by_factor, floor_by_factor，涉及 `smart_resize, resize_image, round_by_factor`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +0/-40 (40 lines); hunks: -1,4 +1,3; -79,26 +78,6 @@ def smart_resize(; symbols: smart_resize, resize_image, round_by_factor, floor_by_factor
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -1,4 +1,3 @@
-import asyncio
@@ -79,26 +78,6 @@ def smart_resize(
-def resize_image(
-    image,
-    min_pixels: int = MIN_PIXELS,
-    max_pixels: int = MAX_PIXELS,
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +0/-40
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/dots_vlm.py`, `python/sglang/srt/multimodal/processors/points_v15_chat.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #13075 - [VLM] Support PP for Qwen2.5-VL

- 链接: https://github.com/sgl-project/sglang/pull/13075
- 状态/时间: merged / 2025-11-12
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`；关联提交 `706502ff6cff`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 3 个文件，+88/-54，可读 patch 244 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Support PP for Qwen2.5-VL」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「[VLM] Support PP for Qwen2.5-VL」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +44/-15 (59 lines); hunks: -40,6 +40,7; -50,13 +51,14; symbols: __init__, forward, load_weights，涉及 `__init__, forward, load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +44/-15 (59 lines); hunks: -40,6 +40,7; -50,13 +51,14; symbols: __init__, forward, load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -40,6 +40,7 @@
+from sglang.srt.distributed.parallel_state import get_pp_group
@@ -50,13 +51,14 @@
+from sglang.srt.layers.utils import PPMissingLayer, get_layer_id
-from sglang.srt.model_executor.forward_batch_info import ForwardBatch
+from sglang.srt.model_executor.forward_batch_info import ForwardBatch, PPProxyTensors
@@ -482,6 +484,7 @@ def __init__(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +44/-15
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/managers/mm_utils.py`, `python/sglang/srt/managers/scheduler.py`, `python/sglang/srt/models/qwen2_5_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #13126 - [VLM][feat] Support encoder DP for Qwen2.5-VL

- 链接: https://github.com/sgl-project/sglang/pull/13126
- 状态/时间: merged / 2025-11-18
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`；关联提交 `ac81db66c2d8`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 6 个文件，+595/-6，可读 patch 790 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM][feat] Support encoder DP for Qwen2.5-VL」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「[VLM][feat] Support encoder DP for Qwen2.5-VL」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +44/-2 (46 lines); hunks: -40,6 +40,10; -62,6 +66,8; symbols: __init__, forward，涉及 `__init__, forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +44/-2 (46 lines); hunks: -40,6 +40,10; -62,6 +66,8; symbols: __init__, forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -40,6 +40,10 @@
+from sglang.srt.distributed import (
+    get_tensor_model_parallel_rank,
+    get_tensor_model_parallel_world_size,
+)
@@ -62,6 +66,8 @@
+from sglang.srt.multimodal.mm_utils import run_dp_sharded_mrope_vision_model
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +44/-2
- 验证与风险: diff 自带测试面 `test/srt/nightly/test_encoder_dp.py`, `test/srt/run_suite.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #13055 - [VLM] Support Piecewise CUDA Graph for Qwen2.5-VL

- 链接: https://github.com/sgl-project/sglang/pull/13055
- 状态/时间: merged / 2025-11-20
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py`；关联提交 `af6bcadcf723`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 10 个文件，+710/-29，可读 patch 970 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Support Piecewise CUDA Graph for Qwen2.5-VL」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py`；技术摘要: 覆盖「[VLM] Support Piecewise CUDA Graph for Qwen2.5-VL」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen2_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +38/-7 (45 lines); hunks: -57,11 +57,12; -566,6 +567,25 @@ def get_video_feature(self, items: List[MultimodalDataItem]...; symbols: get_video_feature, post_process, get_input_embeddings, forward，涉及 `get_video_feature, post_process, get_input_embeddings`；`python/sglang/srt/models/qwen2_vl.py` modified +16/-7 (23 lines); hunks: -39,10 +39,7; -509,6 +506,7 @@ def forward(; symbols: forward，涉及 `forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +38/-7 (45 lines); hunks: -57,11 +57,12; -566,6 +567,25 @@ def get_video_feature(self, items: List[MultimodalDataItem]...; symbols: get_video_feature, post_process, get_input_embeddings, forward
  - `python/sglang/srt/models/qwen2_vl.py` modified +16/-7 (23 lines); hunks: -39,10 +39,7; -509,6 +506,7 @@ def forward(; symbols: forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -57,11 +57,12 @@
-from sglang.srt.managers.mm_utils import (
-    MultiModalityDataPaddingPatternMultimodalTokens,
-    general_mm_embed_routine,
+from sglang.srt.managers.mm_utils import MultiModalityDataPaddingPatternMultimodalTokens
+from sglang.srt.managers.schedule_batch import (
+    Modality,
diff -- python/sglang/srt/models/qwen2_vl.py
@@ -39,10 +39,7 @@
-from sglang.srt.managers.mm_utils import (
-    MultiModalityDataPaddingPatternMultimodalTokens,
-    general_mm_embed_routine,
-)
+from sglang.srt.managers.mm_utils import MultiModalityDataPaddingPatternMultimodalTokens
@@ -509,6 +506,7 @@ def forward(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +38/-7; `python/sglang/srt/models/qwen2_vl.py` modified +16/-7
- 验证与风险: diff 自带测试面 `test/srt/nightly/test_vlms_piecewise_cuda_graph.py`, `test/srt/run_suite.py`, `test/srt/test_piecewise_cuda_graph.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #13736 - [VLM] Replace torch.repeat_interleave with faster np.repeat for Qwen-VL series

- 链接: https://github.com/sgl-project/sglang/pull/13736
- 状态/时间: merged / 2025-11-22
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_vl.py`, `python/sglang/srt/models/qwen3_vl.py`；关联提交 `5625e32cae12`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+169/-13，可读 patch 229 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Replace torch.repeat_interleave with faster np.repeat for Qwen-VL series」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen2_vl.py`；技术摘要: 覆盖「[VLM] Replace torch.repeat_interleave with faster np.repeat for Qwen-VL series」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen2_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +2/-9 (11 lines); hunks: -46,6 +46,7; -434,15 +435,7 @@ def forward(; symbols: forward，涉及 `forward`；`python/sglang/srt/models/qwen2_vl.py` modified +2/-4 (6 lines); hunks: -44,6 +44,7; -387,10 +388,7 @@ def forward(; symbols: forward，涉及 `forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +2/-9 (11 lines); hunks: -46,6 +46,7; -434,15 +435,7 @@ def forward(; symbols: forward
  - `python/sglang/srt/models/qwen2_vl.py` modified +2/-4 (6 lines); hunks: -44,6 +44,7; -387,10 +388,7 @@ def forward(; symbols: forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -46,6 +46,7 @@
+from sglang.srt.models.utils import compute_cu_seqlens_from_grid_numpy
@@ -434,15 +435,7 @@ def forward(
-        cu_seqlens = torch.repeat_interleave(
-            grid_thw[:, 1] * grid_thw[:, 2], grid_thw[:, 0]
-        ).cumsum(dim=0)
-        cu_seqlens = torch.cat(
diff -- python/sglang/srt/models/qwen2_vl.py
@@ -44,6 +44,7 @@
+from sglang.srt.models.utils import compute_cu_seqlens_from_grid_numpy
@@ -387,10 +388,7 @@ def forward(
-        cu_seqlens = torch.repeat_interleave(
-            grid_thw[:, 1] * grid_thw[:, 2], grid_thw[:, 0]
-        ).cumsum(dim=0, dtype=torch.int32)
-        cu_seqlens = torch.cat([cu_seqlens.new_zeros(1), cu_seqlens])
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +2/-9; `python/sglang/srt/models/qwen2_vl.py` modified +2/-4
- 验证与风险: diff 自带测试面 `test/srt/ops/test_repeat_interleave.py`, `test/srt/run_suite.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #13983 - Support KTransformers for Qwen3-VL moe

- 链接: https://github.com/sgl-project/sglang/pull/13983
- 状态/时间: merged / 2025-11-26
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl_moe.py`；关联提交 `15ff6982b94f`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+9/-0，可读 patch 22 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Support KTransformers for Qwen3-VL moe」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「Support KTransformers for Qwen3-VL moe」；主要实现面是 `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl_moe.py` modified +9/-0 (9 lines); hunks: -22,6 +22,7; -326,5 +327,13 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights, get_model_config_for_expert_location，涉及 `load_weights, get_model_config_for_expert_location`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +9/-0 (9 lines); hunks: -22,6 +22,7; -326,5 +327,13 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights, get_model_config_for_expert_location
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -22,6 +22,7 @@
+from sglang.srt.eplb.expert_location import ModelConfigForExpertLocation
@@ -326,5 +327,13 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
+    @classmethod
+    def get_model_config_for_expert_location(cls, config):
+        return ModelConfigForExpertLocation(
+            num_layers=config.text_config.num_hidden_layers,
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl_moe.py` modified +9/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #13904 - [Bugfix] qwen2.5-vl spec decode accept_len low

- 链接: https://github.com/sgl-project/sglang/pull/13904
- 状态/时间: merged / 2025-11-28
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`；关联提交 `f6e37d3edb94`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-0，可读 patch 8 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Bugfix] qwen2.5-vl spec decode accept_len low」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「[Bugfix] qwen2.5-vl spec decode accept_len low」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +1/-0 (1 lines); hunks: -654,6 +654,7 @@ def forward(; symbols: forward，涉及 `forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +1/-0 (1 lines); hunks: -654,6 +654,7 @@ def forward(; symbols: forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -654,6 +654,7 @@ def forward(
+                    aux_hidden_states,
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen2_5_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #13724 - support qwen3_vl vision model dp

- 链接: https://github.com/sgl-project/sglang/pull/13724
- 状态/时间: merged / 2025-11-28
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `ea1e9f6b3c3d`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+50/-2，可读 patch 208 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「support qwen3_vl vision model dp」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「support qwen3_vl vision model dp」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +49/-2 (51 lines); hunks: -28,6 +28,10; -47,6 +51,8; symbols: __init__, forward，涉及 `__init__, forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +49/-2 (51 lines); hunks: -28,6 +28,10; -47,6 +51,8; symbols: __init__, forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -28,6 +28,10 @@
+from sglang.srt.distributed import (
+    get_tensor_model_parallel_rank,
+    get_tensor_model_parallel_world_size,
+)
@@ -47,6 +51,8 @@
+from sglang.srt.multimodal.mm_utils import run_dp_sharded_mrope_vision_model
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +49/-2
- 验证与风险: diff 自带测试面 `test/nightly/test_encoder_dp.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #14292 - [VLM] Introduce Cache for positional embedding ids for Qwen-VL family

- 链接: https://github.com/sgl-project/sglang/pull/14292
- 状态/时间: merged / 2025-12-04
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen3_vl.py`；关联提交 `b2b09f5f24b9`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 3 个文件，+48/-47，可读 patch 149 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Introduce Cache for positional embedding ids for Qwen-VL family」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[VLM] Introduce Cache for positional embedding ids for Qwen-VL family」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +5/-25 (30 lines); hunks: -69,7 +69,7; -246,7 +246,7 @@ def forward(self, x: torch.Tensor) -> torch.Tensor:; symbols: forward, Qwen2_5_VisionTransformer, __init__, device，涉及 `forward, Qwen2_5_VisionTransformer, __init__`；`python/sglang/srt/models/qwen3_vl.py` modified +5/-22 (27 lines); hunks: -50,7 +50,7; -257,7 +257,7 @@ def forward(self, x: torch.Tensor) -> torch.Tensor:; symbols: forward, Qwen3VLMoeVisionModel, __init__, device，涉及 `forward, Qwen3VLMoeVisionModel, __init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +5/-25 (30 lines); hunks: -69,7 +69,7; -246,7 +246,7 @@ def forward(self, x: torch.Tensor) -> torch.Tensor:; symbols: forward, Qwen2_5_VisionTransformer, __init__, device
  - `python/sglang/srt/models/qwen3_vl.py` modified +5/-22 (27 lines); hunks: -50,7 +50,7; -257,7 +257,7 @@ def forward(self, x: torch.Tensor) -> torch.Tensor:; symbols: forward, Qwen3VLMoeVisionModel, __init__, device
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -69,7 +69,7 @@
-from sglang.srt.models.utils import permute_inv
+from sglang.srt.models.utils import RotaryPosMixin, permute_inv
@@ -246,7 +246,7 @@ def forward(self, x: torch.Tensor) -> torch.Tensor:
-class Qwen2_5_VisionTransformer(nn.Module):
+class Qwen2_5_VisionTransformer(nn.Module, RotaryPosMixin):
@@ -362,30 +362,10 @@ def device(self) -> torch.device:
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -50,7 +50,7 @@
-from sglang.srt.models.utils import compute_cu_seqlens_from_grid_numpy
+from sglang.srt.models.utils import RotaryPosMixin, compute_cu_seqlens_from_grid_numpy
@@ -257,7 +257,7 @@ def forward(self, x: torch.Tensor) -> torch.Tensor:
-class Qwen3VLMoeVisionModel(nn.Module):
+class Qwen3VLMoeVisionModel(nn.Module, RotaryPosMixin):
@@ -339,26 +339,9 @@ def device(self) -> torch.device:
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +5/-25; `python/sglang/srt/models/qwen3_vl.py` modified +5/-22
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/utils.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #11791 - fix rmsnorm -> layernorm in qwen3 omni

- 链接: https://github.com/sgl-project/sglang/pull/11791
- 状态/时间: merged / 2025-12-06
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_omni_moe.py`；关联提交 `2ac5b9839508`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-2，可读 patch 17 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「fix rmsnorm -> layernorm in qwen3 omni」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_omni_moe.py`；技术摘要: 覆盖「fix rmsnorm -> layernorm in qwen3 omni」；主要实现面是 `python/sglang/srt/models/qwen3_omni_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_omni_moe.py` modified +1/-2 (3 lines); hunks: -31,7 +31,6; -318,7 +317,7 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_omni_moe.py` modified +1/-2 (3 lines); hunks: -31,7 +31,6; -318,7 +317,7 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_omni_moe.py
@@ -31,7 +31,6 @@
-from sglang.srt.layers.layernorm import RMSNorm
@@ -318,7 +317,7 @@ def __init__(
-        self.ln_q = RMSNorm(
+        self.ln_q = nn.LayerNorm(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_omni_moe.py` modified +1/-2
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_omni_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #14886 - Support qwen3-omni with DP Encoder

- 链接: https://github.com/sgl-project/sglang/pull/14886
- 状态/时间: open / 2025-12-11
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+32/-3，可读 patch 151 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Support qwen3-omni with DP Encoder」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `python/sglang/srt/models/qwen3_omni_moe.py`, `test/nightly/test_encoder_dp.py`；技术摘要: 覆盖「Support qwen3-omni with DP Encoder」；主要实现面是 `python/sglang/srt/models/qwen3_omni_moe.py`, `test/nightly/test_encoder_dp.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_omni_moe.py` modified +31/-3 (34 lines); hunks: -30,6 +30,10; -42,6 +46,7; symbols: __init__, _get_feat_extract_output_lengths, Qwen3OmniMoeAudioEncoder，涉及 `__init__, _get_feat_extract_output_lengths, Qwen3OmniMoeAudioEncoder`；`test/nightly/test_encoder_dp.py` modified +1/-0 (1 lines); hunks: -21,6 +21,7。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_omni_moe.py` modified +31/-3 (34 lines); hunks: -30,6 +30,10; -42,6 +46,7; symbols: __init__, _get_feat_extract_output_lengths, Qwen3OmniMoeAudioEncoder
  - `test/nightly/test_encoder_dp.py` modified +1/-0 (1 lines); hunks: -21,6 +21,7
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_omni_moe.py
@@ -30,6 +30,10 @@
+from sglang.srt.distributed import (
+    get_tensor_model_parallel_rank,
+    get_tensor_model_parallel_world_size,
+)
@@ -42,6 +46,7 @@
+from sglang.srt.server_args import get_global_server_args
diff -- test/nightly/test_encoder_dp.py
@@ -21,6 +21,7 @@
+    SimpleNamespace(model="Qwen/Qwen3-Omni-30B-A3B-Instruct", mmmu_accuracy=0.55),
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_omni_moe.py` modified +31/-3
  - tests: `test/nightly/test_encoder_dp.py` modified +1/-0
- 验证与风险: diff 自带测试面 `test/nightly/test_encoder_dp.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #14907 - [VLM] Support chunked vit attention

- 链接: https://github.com/sgl-project/sglang/pull/14907
- 状态/时间: merged / 2025-12-15
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+363/-8，可读 patch 413 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Support chunked vit attention」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/managers/mm_utils.py`；技术摘要: 覆盖「[VLM] Support chunked vit attention」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/managers/mm_utils.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +97/-8 (105 lines); hunks: -14,6 +14,7; -53,7 +54,7; symbols: get_image_feature, get_video_feature，涉及 `get_image_feature, get_video_feature`；`python/sglang/srt/managers/mm_utils.py` modified +266/-0 (266 lines); hunks: -41,6 +41,9; -414,6 +417,67 @@ def _get_precomputed_embedding(; symbols: init_feature_buffer, _get_precomputed_embedding, get_embedding_items_per_chunk_with_extra_padding, _get_chunked_prefill_embedding，涉及 `init_feature_buffer, _get_precomputed_embedding, get_embedding_items_per_chunk_with_extra_padding`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +97/-8 (105 lines); hunks: -14,6 +14,7; -53,7 +54,7; symbols: get_image_feature, get_video_feature
  - `python/sglang/srt/managers/mm_utils.py` modified +266/-0 (266 lines); hunks: -41,6 +41,9; -414,6 +417,67 @@ def _get_precomputed_embedding(; symbols: init_feature_buffer, _get_precomputed_embedding, get_embedding_items_per_chunk_with_extra_padding, _get_chunked_prefill_embedding
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -14,6 +14,7 @@
+import math
@@ -53,7 +54,7 @@
-from sglang.srt.utils import add_prefix
+from sglang.srt.utils import add_prefix, get_int_env_var
@@ -666,13 +667,101 @@ def get_image_feature(self, items: List[MultimodalDataItem]) -> torch.Tensor:
-        if self.use_data_parallel:
diff -- python/sglang/srt/managers/mm_utils.py
@@ -41,6 +41,9 @@
+_EXTRA_PRE_TOKENS = 0  # pre chunk extra token (0 for the moment)
+_EXTRA_POST_TOKENS = 0  # post chunk extra token (0 for the moment)
@@ -414,6 +417,67 @@ def _get_precomputed_embedding(
+def get_embedding_items_per_chunk_with_extra_padding(
+    embedding_items_per_req: List["MultimodalDataItem"],
+    extend_prefix_len: int,
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +97/-8; `python/sglang/srt/managers/mm_utils.py` modified +266/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/managers/mm_utils.py`, `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #12333 - [PP] Add pp support for Qwen3-VL

- 链接: https://github.com/sgl-project/sglang/pull/12333
- 状态/时间: merged / 2025-12-17
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/models/qwen3_vl.py`；关联提交 `45a959d3e971`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+119/-20，可读 patch 243 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[PP] Add pp support for Qwen3-VL」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_omni_moe.py`；技术摘要: 覆盖「[PP] Add pp support for Qwen3-VL」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_omni_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +53/-19 (72 lines); hunks: -32,11 +32,13; -599,6 +601,7 @@ def __init__(; symbols: __init__, forward, load_weights，涉及 `__init__, forward, load_weights`；`python/sglang/srt/models/qwen3_omni_moe.py` modified +4/-1 (5 lines); hunks: -614,7 +614,10 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +53/-19 (72 lines); hunks: -32,11 +32,13; -599,6 +601,7 @@ def __init__(; symbols: __init__, forward, load_weights
  - `python/sglang/srt/models/qwen3_omni_moe.py` modified +4/-1 (5 lines); hunks: -614,7 +614,10 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -32,11 +32,13 @@
+from sglang.srt.distributed.parallel_state import get_pp_group
+from sglang.srt.layers.utils import PPMissingLayer, get_layer_id
@@ -599,6 +601,7 @@ def __init__(
+        self.pp_group = get_pp_group()
@@ -626,19 +629,22 @@ def __init__(
-            if self.config.tie_word_embeddings:
diff -- python/sglang/srt/models/qwen3_omni_moe.py
@@ -614,7 +614,10 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
-                        param = params_dict[name_mapped]
+                        if name_mapped in params_dict.keys():
+                            param = params_dict[name_mapped]
+                        else:
+                            continue
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +53/-19; `python/sglang/srt/models/qwen3_omni_moe.py` modified +4/-1
- 验证与风险: diff 自带测试面 `python/sglang/test/test_utils.py`, `test/srt/test_pp_single_node.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #15138 - [bug fix][pp] fix weight load for qwen2.5-vl

- 链接: https://github.com/sgl-project/sglang/pull/15138
- 状态/时间: merged / 2025-12-17
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`；关联提交 `0071fe9c407a`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+10/-4，可读 patch 28 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[bug fix][pp] fix weight load for qwen2.5-vl」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「[bug fix][pp] fix weight load for qwen2.5-vl」；主要实现面是 `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen2_5_vl.py` modified +10/-4 (14 lines); hunks: -743,6 +743,14 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; -789,10 +797,8 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +10/-4 (14 lines); hunks: -743,6 +743,14 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; -789,10 +797,8 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -743,6 +743,14 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
+            if self.pp_group.is_last_rank and "model.embed_tokens.weight" in name:
+                if "lm_head.weight" in params_dict:
+                    lm_head_param = params_dict["lm_head.weight"]
+                    weight_loader = getattr(
+                        lm_head_param, "weight_loader", default_weight_loader
+                    )
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen2_5_vl.py` modified +10/-4
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen2_5_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #15205 - [VLM] Support cos sin cache for Qwen3-VL & GLM-4.1V

- 链接: https://github.com/sgl-project/sglang/pull/15205
- 状态/时间: merged / 2025-12-18
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `8fa3dc36c565`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 4 个文件，+100/-80，可读 patch 345 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Support cos sin cache for Qwen3-VL & GLM-4.1V」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[VLM] Support cos sin cache for Qwen3-VL & GLM-4.1V」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +41/-20 (61 lines); hunks: -24,9 +24,6; -39,6 +36,7; symbols: forward, __init__, dtype, device，涉及 `forward, __init__, dtype`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +41/-20 (61 lines); hunks: -24,9 +24,6; -39,6 +36,7; symbols: forward, __init__, dtype, device
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -24,9 +24,6 @@
-from transformers.models.qwen2_5_vl.modeling_qwen2_5_vl import (
-    Qwen2_5_VisionRotaryEmbedding,
-)
@@ -39,6 +36,7 @@
+from sglang.srt.layers.rotary_embedding import get_rope
@@ -188,14 +186,16 @@ def forward(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +41/-20
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/layers/attention/vision.py`, `python/sglang/srt/layers/rotary_embedding.py`, `python/sglang/srt/models/glm4v.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #15320 - [VLM] Support ViT Piecewise CUDA Graph for Qwen3-VL

- 链接: https://github.com/sgl-project/sglang/pull/15320
- 状态/时间: merged / 2025-12-20
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen2_5_vl.py`, `python/sglang/srt/models/qwen3_vl.py`；关联提交 `019517a35610`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 6 个文件，+233/-64，可读 patch 497 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Support ViT Piecewise CUDA Graph for Qwen3-VL」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py`；技术摘要: 覆盖「[VLM] Support ViT Piecewise CUDA Graph for Qwen3-VL」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen2_5_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +52/-1 (53 lines); hunks: -57,8 +57,9; -188,6 +189,7 @@ def forward(; symbols: forward, __init__, dtype，涉及 `forward, __init__, dtype`；`python/sglang/srt/models/qwen2_5_vl.py` modified +2/-3 (5 lines); hunks: -170,7 +170,6 @@ def forward(; -182,7 +181,7 @@ def forward(; symbols: forward，涉及 `forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +52/-1 (53 lines); hunks: -57,8 +57,9; -188,6 +189,7 @@ def forward(; symbols: forward, __init__, dtype
  - `python/sglang/srt/models/qwen2_5_vl.py` modified +2/-3 (5 lines); hunks: -170,7 +170,6 @@ def forward(; -182,7 +181,7 @@ def forward(; symbols: forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -57,8 +57,9 @@
+from sglang.srt.multimodal.vit_cuda_graph_runner import ViTCudaGraphRunner
-from sglang.srt.utils import add_prefix, get_int_env_var
+from sglang.srt.utils import add_prefix, get_bool_env_var, get_int_env_var
@@ -188,6 +189,7 @@ def forward(
+        output_ws: Optional[torch.Tensor] = None,
@@ -196,6 +198,7 @@ def forward(
diff -- python/sglang/srt/models/qwen2_5_vl.py
@@ -170,7 +170,6 @@ def forward(
-        ws = output_ws
@@ -182,7 +181,7 @@ def forward(
-            output_ws=ws,
+            output_ws=output_ws,
@@ -390,7 +389,7 @@ def forward(
-        if get_bool_env_var("SGLANG_VIT_ENABLE_CUDA_GRAPH") and self.tp_size == 1:
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +52/-1; `python/sglang/srt/models/qwen2_5_vl.py` modified +2/-3
- 验证与风险: diff 自带测试面 `test/manual/nightly/test_vlms_vit_cuda_graph.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #15570 - [GLM-ASR] GLM-ASR Support

- 链接: https://github.com/sgl-project/sglang/pull/15570
- 状态/时间: merged / 2025-12-23
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/glmasr.py`；关联提交 `82f1d6157f8e`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 4 个文件，+226/-1，可读 patch 250 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[GLM-ASR] GLM-ASR Support」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/glmasr.py`；技术摘要: 覆盖「[GLM-ASR] GLM-ASR Support」；主要实现面是 `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/glmasr.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/glmasr.py` added +171/-0 (171 lines); hunks: -0,0 +1,171; symbols: GlmasrForConditionalGeneration, __init__, pad_input_ids, get_audio_feature，涉及 `GlmasrForConditionalGeneration, __init__, pad_input_ids`；`python/sglang/srt/multimodal/processors/glmasr.py` added +53/-0 (53 lines); hunks: -0,0 +1,53; symbols: GlmasrProcessor, __init__, process_mm_data_async，涉及 `GlmasrProcessor, __init__, process_mm_data_async`。
- 代码 diff 细节:
  - `python/sglang/srt/models/glmasr.py` added +171/-0 (171 lines); hunks: -0,0 +1,171; symbols: GlmasrForConditionalGeneration, __init__, pad_input_ids, get_audio_feature
  - `python/sglang/srt/multimodal/processors/glmasr.py` added +53/-0 (53 lines); hunks: -0,0 +1,53; symbols: GlmasrProcessor, __init__, process_mm_data_async
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/glmasr.py
@@ -0,0 +1,171 @@
+# Copyright 2023-2025 SGLang Team
+# Licensed under the Apache License, Version 2.0 (the "License");
+# you may not use this file except in compliance with the License.
+# You may obtain a copy of the License at
+#
+#     http://www.apache.org/licenses/LICENSE-2.0
diff -- python/sglang/srt/multimodal/processors/glmasr.py
@@ -0,0 +1,53 @@
+import re
+from sglang.srt.models.glmasr import GlmasrForConditionalGeneration
+from sglang.srt.multimodal.processors.base_processor import (
+    BaseMultimodalProcessor,
+    MultimodalSpecialTokens,
+)
```

- 已读文件:
  - runtime: `python/sglang/srt/models/glmasr.py` added +171/-0; `python/sglang/srt/multimodal/processors/glmasr.py` added +53/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/configs/model_config.py`, `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/base_processor.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #15772 - Change GLM-ASR class name

- 链接: https://github.com/sgl-project/sglang/pull/15772
- 状态/时间: merged / 2025-12-25
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/glmasr.py`；关联提交 `f3ba71166262`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+19/-15，可读 patch 103 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Change GLM-ASR class name」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/glmasr.py`；技术摘要: 覆盖「Change GLM-ASR class name」；主要实现面是 `python/sglang/srt/models/glmasr.py`, `python/sglang/srt/multimodal/processors/glmasr.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/glmasr.py` modified +9/-9 (18 lines); hunks: -22,10 +22,10; -46,7 +46,7; symbols: GlmasrForConditionalGeneration, GlmAsrForConditionalGeneration, __init__，涉及 `GlmasrForConditionalGeneration, GlmAsrForConditionalGeneration, __init__`；`python/sglang/srt/multimodal/processors/glmasr.py` modified +3/-3 (6 lines); hunks: -1,14 +1,14; symbols: GlmasrProcessor, GlmAsrProcessor, __init__，涉及 `GlmasrProcessor, GlmAsrProcessor, __init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/glmasr.py` modified +9/-9 (18 lines); hunks: -22,10 +22,10; -46,7 +46,7; symbols: GlmasrForConditionalGeneration, GlmAsrForConditionalGeneration, __init__
  - `python/sglang/srt/multimodal/processors/glmasr.py` modified +3/-3 (6 lines); hunks: -1,14 +1,14; symbols: GlmasrProcessor, GlmAsrProcessor, __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/glmasr.py
@@ -22,10 +22,10 @@
-from transformers import GlmasrConfig, GlmasrEncoderConfig
+from transformers import GlmAsrConfig, GlmAsrEncoderConfig
-    GlmasrEncoder,
-    GlmasrMultiModalProjector,
+    GlmAsrEncoder,
+    GlmAsrMultiModalProjector,
diff -- python/sglang/srt/multimodal/processors/glmasr.py
@@ -1,14 +1,14 @@
-from sglang.srt.models.glmasr import GlmasrForConditionalGeneration
+from sglang.srt.models.glmasr import GlmAsrForConditionalGeneration
-class GlmasrProcessor(BaseMultimodalProcessor):
-    models = [GlmasrForConditionalGeneration]
+class GlmAsrProcessor(BaseMultimodalProcessor):
+    models = [GlmAsrForConditionalGeneration]
```

- 已读文件:
  - runtime: `python/sglang/srt/models/glmasr.py` modified +9/-9; `python/sglang/srt/multimodal/processors/glmasr.py` modified +3/-3
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/configs/model_config.py`, `python/sglang/srt/managers/schedule_batch.py`, `python/sglang/srt/models/glmasr.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #16491 - [Qwen3-VL][PP] Skip loading expert weights not on this rank

- 链接: https://github.com/sgl-project/sglang/pull/16491
- 状态/时间: open / 2026-01-05
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+3/-0，可读 patch 10 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Qwen3-VL][PP] Skip loading expert weights not on this rank」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「[Qwen3-VL][PP] Skip loading expert weights not on this rank」；主要实现面是 `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl_moe.py` modified +3/-0 (3 lines); hunks: -274,6 +274,9 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Te...; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +3/-0 (3 lines); hunks: -274,6 +274,9 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Te...; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -274,6 +274,9 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
+                    if name_mapped not in params_dict:
+                        # Expert weight not on this rank, will be skipped below
+                        continue
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl_moe.py` modified +3/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #16571 - [Feature] [ROCM] Support Add & LayerNorm fused for Qwen3-VL VIT

- 链接: https://github.com/sgl-project/sglang/pull/16571
- 状态/时间: open / 2026-01-06
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+87/-15，可读 patch 204 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Feature] [ROCM] Support Add & LayerNorm fused for Qwen3-VL VIT」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/layers/layernorm.py`；技术摘要: 覆盖「[Feature] [ROCM] Support Add & LayerNorm fused for Qwen3-VL VIT」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/layers/layernorm.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +60/-15 (75 lines); hunks: -42,6 +42,7; -72,7 +73,7; symbols: Qwen3_VisionMLP, __init__, forward, Qwen3VLMoeVisionPatchMerger，涉及 `Qwen3_VisionMLP, __init__, forward`；`python/sglang/srt/layers/layernorm.py` modified +27/-0 (27 lines); hunks: -67,6 +67,7; -367,6 +368,9 @@ def __init__(; symbols: __init__, forward_cuda, forward_cpu, forward_aiter，涉及 `__init__, forward_cuda, forward_cpu`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +60/-15 (75 lines); hunks: -42,6 +42,7; -72,7 +73,7; symbols: Qwen3_VisionMLP, __init__, forward, Qwen3VLMoeVisionPatchMerger
  - `python/sglang/srt/layers/layernorm.py` modified +27/-0 (27 lines); hunks: -67,6 +67,7; -367,6 +368,9 @@ def __init__(; symbols: __init__, forward_cuda, forward_cpu, forward_aiter
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -42,6 +42,7 @@
+from sglang.srt.layers.layernorm import LayerNorm
@@ -72,7 +73,7 @@
-from sglang.srt.utils import add_prefix, get_int_env_var, is_npu, round_up
+from sglang.srt.utils import add_prefix, get_int_env_var, is_hip, is_npu, round_up
@@ -86,6 +87,8 @@
+_is_hip = is_hip()
diff -- python/sglang/srt/layers/layernorm.py
@@ -67,6 +67,7 @@
+    from aiter import layer_norm, layernorm2d_fwd_with_add
@@ -367,6 +368,9 @@ def __init__(
+        if _use_aiter:
+            self._forward_method = self.forward_aiter
@@ -419,6 +423,29 @@ def forward_cpu(
+    def forward_aiter(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +60/-15; `python/sglang/srt/layers/layernorm.py` modified +27/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/layers/layernorm.py`, `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #16785 - [Bugfix] fix recompile in qwen3 vl

- 链接: https://github.com/sgl-project/sglang/pull/16785
- 状态/时间: open / 2026-01-09
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+113/-36，可读 patch 307 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Bugfix] fix recompile in qwen3 vl」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`, `python/sglang/srt/model_executor/piecewise_cuda_graph_runner.py`；技术摘要: 覆盖「[Bugfix] fix recompile in qwen3 vl」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/qwen3_vl_moe.py`, `python/sglang/srt/model_executor/piecewise_cuda_graph_runner.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +41/-18 (59 lines); hunks: -913,16 +913,37 @@ def __init__(; -963,7 +984,7 @@ def forward(; symbols: __init__, get_deepstack_embeds, forward，涉及 `__init__, get_deepstack_embeds, forward`；`python/sglang/srt/models/qwen3_vl_moe.py` modified +29/-8 (37 lines); hunks: -57,19 +57,40 @@ def __init__(; -109,7 +130,7 @@ def forward(; symbols: __init__, get_input_embeddings, get_deepstack_embeds, forward，涉及 `__init__, get_input_embeddings, get_deepstack_embeds`；`python/sglang/srt/model_executor/piecewise_cuda_graph_runner.py` modified +25/-1 (26 lines); hunks: -245,6 +245,18 @@ def __init__(self, model_runner: ModelRunner):; -392,6 +404,9 @@ def warmup_torch_compile(self, num_tokens: int):; symbols: __init__, warmup_torch_compile, _cache_loc_dtype, capture_one_batch_size，涉及 `__init__, warmup_torch_compile, _cache_loc_dtype`；`python/sglang/srt/managers/mm_utils.py` modified +13/-6 (19 lines); hunks: -919,6 +919,7 @@ def embed_mm_inputs(; -1019,12 +1020,16 @@ def embed_mm_inputs(; symbols: embed_mm_inputs, general_mm_embed_routine，涉及 `embed_mm_inputs, general_mm_embed_routine`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +41/-18 (59 lines); hunks: -913,16 +913,37 @@ def __init__(; -963,7 +984,7 @@ def forward(; symbols: __init__, get_deepstack_embeds, forward
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +29/-8 (37 lines); hunks: -57,19 +57,40 @@ def __init__(; -109,7 +130,7 @@ def forward(; symbols: __init__, get_input_embeddings, get_deepstack_embeds, forward
  - `python/sglang/srt/model_executor/piecewise_cuda_graph_runner.py` modified +25/-1 (26 lines); hunks: -245,6 +245,18 @@ def __init__(self, model_runner: ModelRunner):; -392,6 +404,9 @@ def warmup_torch_compile(self, num_tokens: int):; symbols: __init__, warmup_torch_compile, _cache_loc_dtype, capture_one_batch_size
  - `python/sglang/srt/managers/mm_utils.py` modified +13/-6 (19 lines); hunks: -919,6 +919,7 @@ def embed_mm_inputs(; -1019,12 +1020,16 @@ def embed_mm_inputs(; symbols: embed_mm_inputs, general_mm_embed_routine
  - `test/manual/nightly/test_vlms_piecewise_cuda_graph.py` modified +5/-3 (8 lines); hunks: -18,7 +18,9; -59,7 +61,7 @@ def run_mmmu_eval(; symbols: run_mmmu_eval, _run_vlm_mmmu_test
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -913,16 +913,37 @@ def __init__(
+        self.deepstack_embeds_buffer = None
-        self, layer_idx: int, input_deepstack_embeds: Optional[torch.Tensor]
+        self,
+        layer_idx: int,
+        input_deepstack_embeds: Optional[torch.Tensor],
+        seq_len: int,
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -57,19 +57,40 @@ def __init__(
+        self.deepstack_embeds_buffer = None
-        self, layer_idx: int, input_deepstack_embeds: Optional[torch.Tensor]
+        self,
+        layer_idx: int,
+        input_deepstack_embeds: Optional[torch.Tensor],
+        seq_len: int,
diff -- python/sglang/srt/model_executor/piecewise_cuda_graph_runner.py
@@ -245,6 +245,18 @@ def __init__(self, model_runner: ModelRunner):
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +41/-18; `python/sglang/srt/models/qwen3_vl_moe.py` modified +29/-8; `python/sglang/srt/model_executor/piecewise_cuda_graph_runner.py` modified +25/-1; `python/sglang/srt/managers/mm_utils.py` modified +13/-6
  - tests: `test/manual/nightly/test_vlms_piecewise_cuda_graph.py` modified +5/-3
- 验证与风险: diff 自带测试面 `test/manual/nightly/test_vlms_piecewise_cuda_graph.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #16996 - feat: Support 'use_audio_in_video' option for qwen3omnimoe model

- 链接: https://github.com/sgl-project/sglang/pull/16996
- 状态/时间: open / 2026-01-13
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 6 个文件，+129/-12，可读 patch 330 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「feat: Support 'use_audio_in_video' option for qwen3omnimoe model」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/entrypoints/openai/protocol.py`；技术摘要: 覆盖「feat: Support 'use_audio_in_video' option for qwen3omnimoe model」；主要实现面是 `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/entrypoints/openai/protocol.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/base_processor.py` modified +34/-3 (37 lines); hunks: -324,7 +324,22 @@ def process_mm_data(; -405,6 +420,7 @@ def _load_single_item(; symbols: process_mm_data, _load_single_item, submit_data_loading_tasks，涉及 `process_mm_data, _load_single_item, submit_data_loading_tasks`；`python/sglang/srt/multimodal/processors/qwen_vl.py` modified +25/-2 (27 lines); hunks: -151,6 +151,7 @@ async def preprocess_video(; -201,8 +202,16 @@ async def preprocess_video(; symbols: preprocess_video, __init__, process_mm_data_async，涉及 `preprocess_video, __init__, process_mm_data_async`；`python/sglang/srt/entrypoints/openai/protocol.py` modified +3/-0 (3 lines); hunks: -552,6 +552,8 @@ class ChatCompletionRequest(BaseModel):; -698,6 +700,7 @@ def get_param(param_name: str):; symbols: ChatCompletionRequest, get_param，涉及 `ChatCompletionRequest, get_param`；`python/sglang/srt/utils/common.py` modified +63/-7 (70 lines); hunks: -72,6 +72,7; -878,6 +879,43 @@ def load_audio(; symbols: load_audio, extract_audio_via_av, ImageData, get_image_bytes，涉及 `load_audio, extract_audio_via_av, ImageData`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/base_processor.py` modified +34/-3 (37 lines); hunks: -324,7 +324,22 @@ def process_mm_data(; -405,6 +420,7 @@ def _load_single_item(; symbols: process_mm_data, _load_single_item, submit_data_loading_tasks
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +25/-2 (27 lines); hunks: -151,6 +151,7 @@ async def preprocess_video(; -201,8 +202,16 @@ async def preprocess_video(; symbols: preprocess_video, __init__, process_mm_data_async
  - `python/sglang/srt/entrypoints/openai/protocol.py` modified +3/-0 (3 lines); hunks: -552,6 +552,8 @@ class ChatCompletionRequest(BaseModel):; -698,6 +700,7 @@ def get_param(param_name: str):; symbols: ChatCompletionRequest, get_param
  - `python/sglang/srt/utils/common.py` modified +63/-7 (70 lines); hunks: -72,6 +72,7; -878,6 +879,43 @@ def load_audio(; symbols: load_audio, extract_audio_via_av, ImageData, get_image_bytes
  - `python/sglang/srt/managers/io_struct.py` modified +3/-0 (3 lines); hunks: -273,6 +273,9 @@ class GenerateReqInput(BaseReq, APIServingTimingMixin):; symbols: GenerateReqInput, contains_mm_input
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/base_processor.py
@@ -324,7 +324,22 @@ def process_mm_data(
+        # For Qwen3_Omni: construct correct FPS and use_audio_in_video kwargs
+        if self._processor.__class__.__name__ == "Qwen3OmniMoeProcessor" and videos:
+            videos_kwargs = kwargs.get("videos_kwargs", {})
+            video_metadata = kwargs.get("video_metadata")
+            if video_metadata and "fps" not in videos_kwargs:
+                if isinstance(video_metadata, list):
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -151,6 +151,7 @@ async def preprocess_video(
+    duration = total_frames / video_fps if video_fps > 0 else 0
@@ -201,8 +202,16 @@ async def preprocess_video(
+    # Fix: correct fps from sampled video
+    if duration > 0:
+        effective_fps = round(nframes / duration, 1)
+    else:
diff -- python/sglang/srt/entrypoints/openai/protocol.py
@@ -552,6 +552,8 @@ class ChatCompletionRequest(BaseModel):
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/base_processor.py` modified +34/-3; `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +25/-2; `python/sglang/srt/entrypoints/openai/protocol.py` modified +3/-0; `python/sglang/srt/utils/common.py` modified +63/-7; `python/sglang/srt/managers/io_struct.py` modified +3/-0; `python/pyproject_npu.toml` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/pyproject_npu.toml`, `python/sglang/srt/entrypoints/openai/protocol.py`, `python/sglang/srt/managers/io_struct.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #17202 - [Feat] Accelerate qwen3vl by remove cpu op

- 链接: https://github.com/sgl-project/sglang/pull/17202
- 状态/时间: open / 2026-01-16
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+27/-9，可读 patch 56 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Feat] Accelerate qwen3vl by remove cpu op」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/layers/attention/vision.py`, `python/sglang/srt/managers/mm_utils.py`；技术摘要: 覆盖「[Feat] Accelerate qwen3vl by remove cpu op」；主要实现面是 `python/sglang/srt/layers/attention/vision.py`, `python/sglang/srt/managers/mm_utils.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/layers/attention/vision.py` modified +3/-3 (6 lines); hunks: -1005,9 +1005,9 @@ def forward(; symbols: forward，涉及 `forward`；`python/sglang/srt/managers/mm_utils.py` modified +24/-6 (30 lines); hunks: -1029,18 +1029,36 @@ def embed_mm_inputs(; symbols: embed_mm_inputs，涉及 `embed_mm_inputs`。
- 代码 diff 细节:
  - `python/sglang/srt/layers/attention/vision.py` modified +3/-3 (6 lines); hunks: -1005,9 +1005,9 @@ def forward(; symbols: forward
  - `python/sglang/srt/managers/mm_utils.py` modified +24/-6 (30 lines); hunks: -1029,18 +1029,36 @@ def embed_mm_inputs(; symbols: embed_mm_inputs
- 关键代码摘录:

```diff
diff -- python/sglang/srt/layers/attention/vision.py
@@ -1005,9 +1005,9 @@ def forward(
-            q = q.reshape(bsz * s, head, -1).contiguous()
-            k = k.reshape(bsz * s, kv_head, -1).contiguous()
-            v = v.reshape(bsz * s, kv_head, -1).contiguous()
+            q = q.reshape(bsz * s, head, -1)
+            k = k.reshape(bsz * s, kv_head, -1)
+            v = v.reshape(bsz * s, kv_head, -1)
diff -- python/sglang/srt/managers/mm_utils.py
@@ -1029,18 +1029,36 @@ def embed_mm_inputs(
+    # Use masked_scatter_ to completely avoid D2D synchronization
-        # in-place update
-        indices = torch.where(mask.squeeze(dim=-1))[0]
-        input_embeds[indices] = embedding.to(input_embeds.device, input_embeds.dtype)
+        mask_1d = mask.view(-1)
+        # Convert embedding to target device/dtype if needed
```

- 已读文件:
  - runtime: `python/sglang/srt/layers/attention/vision.py` modified +3/-3; `python/sglang/srt/managers/mm_utils.py` modified +24/-6
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/layers/attention/vision.py`, `python/sglang/srt/managers/mm_utils.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #16366 - Optimize Qwen3-VL video memory usage

- 链接: https://github.com/sgl-project/sglang/pull/16366
- 状态/时间: merged / 2026-01-22
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `0c2993eed03a`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+8/-0，可读 patch 19 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Optimize Qwen3-VL video memory usage」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「Optimize Qwen3-VL video memory usage」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +8/-0 (8 lines); hunks: -852,10 +852,18 @@ def get_image_feature(self, items: List[MultimodalDataItem...; symbols: get_image_feature, get_video_feature，涉及 `get_image_feature, get_video_feature`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +8/-0 (8 lines); hunks: -852,10 +852,18 @@ def get_image_feature(self, items: List[MultimodalDataItem...; symbols: get_image_feature, get_video_feature
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -852,10 +852,18 @@ def get_image_feature(self, items: List[MultimodalDataItem]) -> torch.Tensor:
+        for item in items:
+            item.feature = item.feature.to(self.visual.device)
+        # Memory optimization for item.feature:
+        # 1. item.feature is released when request finished
+        # 2. High concurrency may cause device OOM due to delayed release
+        # 3. Fix: Offload item.feature to CPU, move to device only when needed
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +8/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #17624 - [BUGFIX] Fix dp size > 1 for qwen3 vl model

- 链接: https://github.com/sgl-project/sglang/pull/17624
- 状态/时间: merged / 2026-01-30
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+48/-19，可读 patch 185 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[BUGFIX] Fix dp size > 1 for qwen3 vl model」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/mm_utils.py`, `python/sglang/srt/layers/linear.py`；技术摘要: 覆盖「[BUGFIX] Fix dp size > 1 for qwen3 vl model」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/mm_utils.py`, `python/sglang/srt/layers/linear.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +14/-13 (27 lines); hunks: -25,14 +25,15; -85,10 +86,8 @@ def __init__(; symbols: __init__，涉及 `__init__`；`python/sglang/srt/multimodal/mm_utils.py` modified +13/-3 (16 lines); hunks: -495,11 +495,19 @@ def run_dp_sharded_mrope_vision_model(; -611,7 +619,9 @@ def run_dp_sharded_mrope_vision_model(; symbols: run_dp_sharded_mrope_vision_model，涉及 `run_dp_sharded_mrope_vision_model`；`python/sglang/srt/layers/linear.py` modified +10/-2 (12 lines); hunks: -21,7 +21,10; -1262,6 +1265,7 @@ def __init__(; symbols: __init__, forward，涉及 `__init__, forward`；`python/sglang/srt/model_executor/forward_batch_info.py` modified +9/-1 (10 lines); hunks: -860,7 +860,15 @@ def _pad_inputs_to_size(self, model_runner: ModelRunner, nu...; symbols: _pad_inputs_to_size，涉及 `_pad_inputs_to_size`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +14/-13 (27 lines); hunks: -25,14 +25,15; -85,10 +86,8 @@ def __init__(; symbols: __init__
  - `python/sglang/srt/multimodal/mm_utils.py` modified +13/-3 (16 lines); hunks: -495,11 +495,19 @@ def run_dp_sharded_mrope_vision_model(; -611,7 +619,9 @@ def run_dp_sharded_mrope_vision_model(; symbols: run_dp_sharded_mrope_vision_model
  - `python/sglang/srt/layers/linear.py` modified +10/-2 (12 lines); hunks: -21,7 +21,10; -1262,6 +1265,7 @@ def __init__(; symbols: __init__, forward
  - `python/sglang/srt/model_executor/forward_batch_info.py` modified +9/-1 (10 lines); hunks: -860,7 +860,15 @@ def _pad_inputs_to_size(self, model_runner: ModelRunner, nu...; symbols: _pad_inputs_to_size
  - `python/sglang/srt/layers/attention/vision.py` modified +2/-0 (2 lines); hunks: -538,6 +538,7 @@ def __init__(; -640,6 +641,7 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -25,14 +25,15 @@
-from sglang.srt.distributed import (
-    get_tensor_model_parallel_rank,
-    get_tensor_model_parallel_world_size,
-)
+from sglang.srt.distributed import get_tensor_model_parallel_world_size
-from sglang.srt.layers.dp_attention import is_dp_attention_enabled
diff -- python/sglang/srt/multimodal/mm_utils.py
@@ -495,11 +495,19 @@ def run_dp_sharded_mrope_vision_model(
-    tp_size = get_tensor_model_parallel_world_size()
+    from sglang.srt.layers.dp_attention import (
+        get_attention_tp_group,
+        get_attention_tp_rank,
+        get_attention_tp_size,
+    )
diff -- python/sglang/srt/layers/linear.py
@@ -21,7 +21,10 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +14/-13; `python/sglang/srt/multimodal/mm_utils.py` modified +13/-3; `python/sglang/srt/layers/linear.py` modified +10/-2; `python/sglang/srt/model_executor/forward_batch_info.py` modified +9/-1; `python/sglang/srt/layers/attention/vision.py` modified +2/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/layers/attention/vision.py`, `python/sglang/srt/layers/linear.py`, `python/sglang/srt/model_executor/forward_batch_info.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #18024 - fix: correct weight loading prefix mapping for Qwen3-VL

- 链接: https://github.com/sgl-project/sglang/pull/18024
- 状态/时间: merged / 2026-02-02
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `522e13b4d2c1`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+7/-1，可读 patch 15 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「fix: correct weight loading prefix mapping for Qwen3-VL」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「fix: correct weight loading prefix mapping for Qwen3-VL」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +7/-1 (8 lines); hunks: -959,7 +959,13 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +7/-1 (8 lines); hunks: -959,7 +959,13 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -959,7 +959,13 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
-            if self.pp_group.is_last_rank and "model.embed_tokens.weight" in name:
+            # Only copy embed_tokens to lm_head when tie_word_embeddings=True
+            # For models with tie_word_embeddings=False (e.g. 8B), lm_head has independent weights
+            if (
+                self.pp_group.is_last_rank
+                and "model.embed_tokens.weight" in name
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +7/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #16781 - Refactor(qwen3-vl) optimize position encoding interpolation

- 链接: https://github.com/sgl-project/sglang/pull/16781
- 状态/时间: merged / 2026-02-05
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `6a4b81e2d9fc`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+126/-25，可读 patch 175 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Refactor(qwen3-vl) optimize position encoding interpolation」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「Refactor(qwen3-vl) optimize position encoding interpolation」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +123/-23 (146 lines); hunks: -19,6 +19,7; -396,31 +397,130 @@ def rot_pos_emb(; symbols: rot_pos_emb, fast_pos_embed_interpolate, _get_interpolation_indices, _calculate_indices_and_weights，涉及 `rot_pos_emb, fast_pos_embed_interpolate, _get_interpolation_indices`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +123/-23 (146 lines); hunks: -19,6 +19,7; -396,31 +397,130 @@ def rot_pos_emb(; symbols: rot_pos_emb, fast_pos_embed_interpolate, _get_interpolation_indices, _calculate_indices_and_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -19,6 +19,7 @@
+import numpy as np
@@ -396,31 +397,130 @@ def rot_pos_emb(
-    def fast_pos_embed_interpolate(self, grid_thw):
-        patch_pos_embeds_permute = []
-        m_size = self.spatial_merge_size
-        embeds = torch.arange(self.num_grid, device=self.pos_embed.weight.device)
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +123/-23
- 验证与风险: diff 自带测试面 `test/srt/test_embed_interpolate_unittest.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #18721 - [BUG] fix mm_enable_dp_encoder hang for Qwen3-VL models

- 链接: https://github.com/sgl-project/sglang/pull/18721
- 状态/时间: open / 2026-02-12
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+3/-1，可读 patch 18 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[BUG] fix mm_enable_dp_encoder hang for Qwen3-VL models」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/layers/vocab_parallel_embedding.py`, `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[BUG] fix mm_enable_dp_encoder hang for Qwen3-VL models」；主要实现面是 `python/sglang/srt/layers/vocab_parallel_embedding.py`, `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/layers/vocab_parallel_embedding.py` modified +2/-1 (3 lines); hunks: -224,7 +224,8 @@ def __init__(; symbols: __init__，涉及 `__init__`；`python/sglang/srt/models/qwen3_vl.py` modified +1/-0 (1 lines); hunks: -308,6 +308,7 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/layers/vocab_parallel_embedding.py` modified +2/-1 (3 lines); hunks: -224,7 +224,8 @@ def __init__(; symbols: __init__
  - `python/sglang/srt/models/qwen3_vl.py` modified +1/-0 (1 lines); hunks: -308,6 +308,7 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/layers/vocab_parallel_embedding.py
@@ -224,7 +224,8 @@ def __init__(
-            assert use_attn_tp_group is False
+            if use_attn_tp_group:
+                logger.warning("not in tp_mode, use_attn_tp_group will not work")
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -308,6 +308,7 @@ def __init__(
+                enable_tp=not get_global_server_args().mm_enable_dp_encoder,
```

- 已读文件:
  - runtime: `python/sglang/srt/layers/vocab_parallel_embedding.py` modified +2/-1; `python/sglang/srt/models/qwen3_vl.py` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/layers/vocab_parallel_embedding.py`, `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #18771 - Add Qwen3-Omni to Qwen MoE architecture handling in fused_moe_triton

- 链接: https://github.com/sgl-project/sglang/pull/18771
- 状态/时间: open / 2026-02-13
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-0，可读 patch 8 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Add Qwen3-Omni to Qwen MoE architecture handling in fused_moe_triton」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `benchmark/kernels/fused_moe_triton/common_utils.py`；技术摘要: 覆盖「Add Qwen3-Omni to Qwen MoE architecture handling in fused_moe_triton」；主要实现面是 `benchmark/kernels/fused_moe_triton/common_utils.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `benchmark/kernels/fused_moe_triton/common_utils.py` modified +1/-0 (1 lines); hunks: -67,6 +67,7 @@ def get_model_config(; symbols: get_model_config，涉及 `get_model_config`。
- 代码 diff 细节:
  - `benchmark/kernels/fused_moe_triton/common_utils.py` modified +1/-0 (1 lines); hunks: -67,6 +67,7 @@ def get_model_config(; symbols: get_model_config
- 关键代码摘录:

```diff
diff -- benchmark/kernels/fused_moe_triton/common_utils.py
@@ -67,6 +67,7 @@ def get_model_config(
+        "Qwen3OmniMoeForConditionalGeneration",
```

- 已读文件:
  - other: `benchmark/kernels/fused_moe_triton/common_utils.py` modified +1/-0
- 验证与风险: 未看到显式测试文件；下一次修改同一区域时需要补足模型加载、短文本生成和 parser/多模态输入的回归验证。

### PR #19003 - [VLM] Introduce FlashInfer CUDNN Prefill as ViT Backend

- 链接: https://github.com/sgl-project/sglang/pull/19003
- 状态/时间: merged / 2026-02-24
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 4 个文件，+678/-14，可读 patch 862 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Introduce FlashInfer CUDNN Prefill as ViT Backend」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/layers/attention/vision.py`, `test/manual/nightly/test_vlms_vit_flashinfer_cudnn.py`；技术摘要: 覆盖「[VLM] Introduce FlashInfer CUDNN Prefill as ViT Backend」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/layers/attention/vision.py`, `test/manual/nightly/test_vlms_vit_flashinfer_cudnn.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +259/-13 (272 lines); hunks: -30,7 +30,12; -66,15 +71,12; symbols: Qwen3_VisionMLP, __init__, forward，涉及 `Qwen3_VisionMLP, __init__, forward`；`python/sglang/srt/layers/attention/vision.py` modified +152/-0 (152 lines); hunks: -34,6 +34,7; -64,6 +65,24; symbols: SingletonCache, forward, VisionFlashInferAttention, __init__，涉及 `SingletonCache, forward, VisionFlashInferAttention`；`test/manual/nightly/test_vlms_vit_flashinfer_cudnn.py` added +258/-0 (258 lines); hunks: -0,0 +1,258; symbols: TestVLMViTFlashinferCudnn, setUpClass, run_mmmu_eval, _run_vlm_mmmu_test，涉及 `TestVLMViTFlashinferCudnn, setUpClass, run_mmmu_eval`；`python/sglang/srt/server_args.py` modified +9/-1 (10 lines); hunks: -3859,7 +3859,15 @@ def add_cli_args(parser: argparse.ArgumentParser):; symbols: add_cli_args，涉及 `add_cli_args`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +259/-13 (272 lines); hunks: -30,7 +30,12; -66,15 +71,12; symbols: Qwen3_VisionMLP, __init__, forward
  - `python/sglang/srt/layers/attention/vision.py` modified +152/-0 (152 lines); hunks: -34,6 +34,7; -64,6 +65,24; symbols: SingletonCache, forward, VisionFlashInferAttention, __init__
  - `test/manual/nightly/test_vlms_vit_flashinfer_cudnn.py` added +258/-0 (258 lines); hunks: -0,0 +1,258; symbols: TestVLMViTFlashinferCudnn, setUpClass, run_mmmu_eval, _run_vlm_mmmu_test
  - `python/sglang/srt/server_args.py` modified +9/-1 (10 lines); hunks: -3859,7 +3859,15 @@ def add_cli_args(parser: argparse.ArgumentParser):; symbols: add_cli_args
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -30,7 +30,12 @@
-from sglang.srt.layers.attention.vision import VisionAttention
+from sglang.srt.layers.attention.vision import (
+    BATCH_BUCKETS,
+    FLASHINFER_MAX_SEQLEN_BUCKETS,
+    FLASHINFER_WORKSPACE_SIZE_BYTES,
+    VisionAttention,
diff -- python/sglang/srt/layers/attention/vision.py
@@ -34,6 +34,7 @@
+    from flashinfer.prefill import cudnn_batch_prefill_with_kv_cache
@@ -64,6 +65,24 @@
+# === Vision Encoder === #
+FLASHINFER_WORKSPACE_SIZE_BYTES = 128 * 1024 * 1024
+# Batch buckets for cuDNN graph caching - graphs are cached per bucket size
+# This avoids creating a new graph for each unique batch size at runtime
diff -- test/manual/nightly/test_vlms_vit_flashinfer_cudnn.py
@@ -0,0 +1,258 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +259/-13; `python/sglang/srt/layers/attention/vision.py` modified +152/-0; `python/sglang/srt/server_args.py` modified +9/-1
  - tests: `test/manual/nightly/test_vlms_vit_flashinfer_cudnn.py` added +258/-0
- 验证与风险: diff 自带测试面 `test/manual/nightly/test_vlms_vit_flashinfer_cudnn.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #19333 - fix qwen3_vl visual module loading

- 链接: https://github.com/sgl-project/sglang/pull/19333
- 状态/时间: merged / 2026-02-27
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `d566816d838c`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-0，可读 patch 8 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「fix qwen3_vl visual module loading」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「fix qwen3_vl visual module loading」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +1/-0 (1 lines); hunks: -1357,6 +1357,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch....; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +1/-0 (1 lines); hunks: -1357,6 +1357,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch....; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -1357,6 +1357,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
+                    name = name.replace(r"model.visual.", r"visual.")
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #19693 - [NPU] Fix Qwen3-VL-8B Accuracy for NPU

- 链接: https://github.com/sgl-project/sglang/pull/19693
- 状态/时间: open / 2026-03-02
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 14 个文件，+199/-108，可读 patch 518 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[NPU] Fix Qwen3-VL-8B Accuracy for NPU」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/llama.py`, `python/sglang/srt/layers/rotary_embedding.py`；技术摘要: 覆盖「[NPU] Fix Qwen3-VL-8B Accuracy for NPU」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/llama.py`, `python/sglang/srt/layers/rotary_embedding.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +79/-20 (99 lines); hunks: -19,6 +19,7; -397,30 +398,89 @@ def rot_pos_emb(; symbols: rot_pos_emb, fast_pos_embed_interpolate, forward, Qwen3VLForConditionalGeneration，涉及 `rot_pos_emb, fast_pos_embed_interpolate, forward`；`python/sglang/srt/models/llama.py` modified +37/-4 (41 lines); hunks: -52,10 +52,14; -185,15 +189,44 @@ def __init__(; symbols: LlamaMLP, __init__, forward_prepare_native, forward_prepare_npu，涉及 `LlamaMLP, __init__, forward_prepare_native`；`python/sglang/srt/layers/rotary_embedding.py` modified +4/-3 (7 lines); hunks: -115,9 +115,10 @@ def __init__(; -294,8 +295,8 @@ def forward_npu(; symbols: __init__, forward_npu，涉及 `__init__, forward_npu`；`python/sglang/srt/models/qwen3.py` modified +4/-3 (7 lines); hunks: -161,12 +161,12 @@ def forward_prepare_npu(self, positions, hidden_states, fo...; -372,6 +372,7 @@ def __init__(; symbols: forward_prepare_npu, __init__，涉及 `forward_prepare_npu, __init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +79/-20 (99 lines); hunks: -19,6 +19,7; -397,30 +398,89 @@ def rot_pos_emb(; symbols: rot_pos_emb, fast_pos_embed_interpolate, forward, Qwen3VLForConditionalGeneration
  - `python/sglang/srt/models/llama.py` modified +37/-4 (41 lines); hunks: -52,10 +52,14; -185,15 +189,44 @@ def __init__(; symbols: LlamaMLP, __init__, forward_prepare_native, forward_prepare_npu
  - `python/sglang/srt/layers/rotary_embedding.py` modified +4/-3 (7 lines); hunks: -115,9 +115,10 @@ def __init__(; -294,8 +295,8 @@ def forward_npu(; symbols: __init__, forward_npu
  - `python/sglang/srt/models/qwen3.py` modified +4/-3 (7 lines); hunks: -161,12 +161,12 @@ def forward_prepare_npu(self, positions, hidden_states, fo...; -372,6 +372,7 @@ def __init__(; symbols: forward_prepare_npu, __init__
  - `python/sglang/srt/models/qwen3_moe.py` modified +3/-3 (6 lines); hunks: -523,12 +523,12 @@ def forward_prepare_npu(; symbols: forward_prepare_npu
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -19,6 +19,7 @@
+import numpy as np
@@ -397,30 +398,89 @@ def rot_pos_emb(
-        patch_pos_embeds_permute = []
-        m_size = self.spatial_merge_size
+        num_grid_per_side = int(self.num_position_embeddings**0.5)
-        embeds = torch.arange(self.num_grid, device=self.pos_embed.weight.device)
diff -- python/sglang/srt/models/llama.py
@@ -52,10 +52,14 @@
-from sglang.srt.utils import add_prefix, make_layers
+from sglang.srt.utils import add_prefix, is_npu, make_layers
+_is_npu = is_npu()
+if _is_npu:
+    from sgl_kernel_npu.norm.split_qkv_rmsnorm_rope import split_qkv_rmsnorm_rope
@@ -185,15 +189,44 @@ def __init__(
diff -- python/sglang/srt/layers/rotary_embedding.py
@@ -115,9 +115,10 @@ def __init__(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +79/-20; `python/sglang/srt/models/llama.py` modified +37/-4; `python/sglang/srt/layers/rotary_embedding.py` modified +4/-3; `python/sglang/srt/models/qwen3.py` modified +4/-3; `python/sglang/srt/models/qwen3_moe.py` modified +3/-3; `python/sglang/srt/layers/vocab_parallel_embedding.py` modified +3/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/environ.py`, `python/sglang/srt/hardware_backend/npu/attention/ascend_backend.py`, `python/sglang/srt/hardware_backend/npu/graph_runner/eagle_draft_npu_graph_runner.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #19291 - [Qwen3.5] Fix missing `quant_config` in `Qwen3VL`

- 链接: https://github.com/sgl-project/sglang/pull/19291
- 状态/时间: merged / 2026-03-02
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-0，可读 patch 8 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Qwen3.5] Fix missing `quant_config` in `Qwen3VL`」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[Qwen3.5] Fix missing `quant_config` in `Qwen3VL`」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +1/-0 (1 lines); hunks: -1025,6 +1025,7 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +1/-0 (1 lines); hunks: -1025,6 +1025,7 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -1025,6 +1025,7 @@ def __init__(
+        self.quant_config = quant_config
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #18185 - [Omni] Optimize AudioEncoder for Qwen3_Omni_Thinker

- 链接: https://github.com/sgl-project/sglang/pull/18185
- 状态/时间: merged / 2026-03-14
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_omni_moe.py`；关联提交 `22e67876d6aa`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+52/-28，可读 patch 130 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Omni] Optimize AudioEncoder for Qwen3_Omni_Thinker」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3_omni_moe.py`；技术摘要: 覆盖「[Omni] Optimize AudioEncoder for Qwen3_Omni_Thinker」；主要实现面是 `python/sglang/srt/models/qwen3_omni_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_omni_moe.py` modified +52/-28 (80 lines); hunks: -70,8 +70,18 @@ def __init__(; -98,9 +108,9 @@ def forward(; symbols: __init__, forward，涉及 `__init__, forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_omni_moe.py` modified +52/-28 (80 lines); hunks: -70,8 +70,18 @@ def __init__(; -98,9 +108,9 @@ def forward(; symbols: __init__, forward
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_omni_moe.py
@@ -70,8 +70,18 @@ def __init__(
-        self.fc1 = nn.Linear(self.embed_dim, config.encoder_ffn_dim)
-        self.fc2 = nn.Linear(config.encoder_ffn_dim, self.embed_dim)
+        self.fc1 = ColumnParallelLinear(
+            self.embed_dim,
+            config.encoder_ffn_dim,
+            bias=True,
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_omni_moe.py` modified +52/-28
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_omni_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #20788 - [DP encoder] Fix `pos_emb `layer TP issue when DP encoder enabled for Qwen3 VL

- 链接: https://github.com/sgl-project/sglang/pull/20788
- 状态/时间: merged / 2026-03-18
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-0，可读 patch 8 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[DP encoder] Fix `pos_emb `layer TP issue when DP encoder enabled for Qwen3 VL」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[DP encoder] Fix `pos_emb `layer TP issue when DP encoder enabled for Qwen3 VL」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +1/-0 (1 lines); hunks: -330,6 +330,7 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +1/-0 (1 lines); hunks: -330,6 +330,7 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -330,6 +330,7 @@ def __init__(
+                enable_tp=False if use_data_parallel else True,
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #20857 - add EVS support for Qwen3-VL

- 链接: https://github.com/sgl-project/sglang/pull/20857
- 状态/时间: open / 2026-03-18
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+151/-4，可读 patch 269 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「add EVS support for Qwen3-VL」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/layers/rotary_embedding/mrope_rope_index.py`, `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「add EVS support for Qwen3-VL」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/layers/rotary_embedding/mrope_rope_index.py`, `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +109/-0 (109 lines); hunks: -10,6 +10,7; -22,6 +23,9; symbols: __init__, _maybe_apply_qwen3_evs, get_mm_data, process_mm_data_async，涉及 `__init__, _maybe_apply_qwen3_evs, get_mm_data`；`python/sglang/srt/layers/rotary_embedding/mrope_rope_index.py` modified +20/-2 (22 lines); hunks: -121,6 +121,7 @@ def get_rope_index(; -134,13 +135,22 @@ def get_rope_index(; symbols: get_rope_index，涉及 `get_rope_index`；`python/sglang/srt/models/qwen3_vl.py` modified +10/-2 (12 lines); hunks: -69,6 +69,7; -1047,7 +1048,7 @@ def forward(; symbols: forward, Qwen3VLForConditionalGeneration, __init__，涉及 `forward, Qwen3VLForConditionalGeneration, __init__`；`python/sglang/srt/multimodal/evs/evs_processor.py` modified +10/-0 (10 lines); hunks: -65,6 +65,16 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +109/-0 (109 lines); hunks: -10,6 +10,7; -22,6 +23,9; symbols: __init__, _maybe_apply_qwen3_evs, get_mm_data, process_mm_data_async
  - `python/sglang/srt/layers/rotary_embedding/mrope_rope_index.py` modified +20/-2 (22 lines); hunks: -121,6 +121,7 @@ def get_rope_index(; -134,13 +135,22 @@ def get_rope_index(; symbols: get_rope_index
  - `python/sglang/srt/models/qwen3_vl.py` modified +10/-2 (12 lines); hunks: -69,6 +69,7; -1047,7 +1048,7 @@ def forward(; symbols: forward, Qwen3VLForConditionalGeneration, __init__
  - `python/sglang/srt/multimodal/evs/evs_processor.py` modified +10/-0 (10 lines); hunks: -65,6 +65,16 @@ def __init__(; symbols: __init__
  - `python/sglang/srt/configs/qwen3_vl.py` modified +2/-0 (2 lines); hunks: -244,6 +244,7 @@ def __init__(; -261,6 +262,7 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -10,6 +10,7 @@
+from sglang.srt.configs.qwen3_vl import Qwen3VLConfig
@@ -22,6 +23,9 @@
+from sglang.srt.multimodal.evs import EVSProcessor
+from sglang.srt.multimodal.evs.evs_core import tokens_per_frame
+from sglang.srt.multimodal.evs.evs_module import VideoEVSDataItem
@@ -250,6 +254,10 @@ def __init__(self, hf_config, server_args, _processor, *args, **kwargs):
diff -- python/sglang/srt/layers/rotary_embedding/mrope_rope_index.py
@@ -121,6 +121,7 @@ def get_rope_index(
+                    mm_token_id = image_token_id
@@ -134,13 +135,22 @@ def get_rope_index(
+                    mm_token_id = video_token_id
+                mm_token_count = 0
+                mm_cursor = ed
+                while (
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -69,6 +69,7 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +109/-0; `python/sglang/srt/layers/rotary_embedding/mrope_rope_index.py` modified +20/-2; `python/sglang/srt/models/qwen3_vl.py` modified +10/-2; `python/sglang/srt/multimodal/evs/evs_processor.py` modified +10/-0; `python/sglang/srt/configs/qwen3_vl.py` modified +2/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/configs/qwen3_vl.py`, `python/sglang/srt/layers/rotary_embedding/mrope_rope_index.py`, `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #20759 - [Bugfix] fix qwen3vl hang when --mm-enable-dp-encoder is enable

- 链接: https://github.com/sgl-project/sglang/pull/20759
- 状态/时间: merged / 2026-03-19
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+2/-2，可读 patch 11 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Bugfix] fix qwen3vl hang when --mm-enable-dp-encoder is enable」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[Bugfix] fix qwen3vl hang when --mm-enable-dp-encoder is enable」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +2/-2 (4 lines); hunks: -329,8 +329,8 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +2/-2 (4 lines); hunks: -329,8 +329,8 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -329,8 +329,8 @@ def __init__(
-                use_attn_tp_group=is_dp_attention_enabled(),
-                enable_tp=False if use_data_parallel else True,
+                enable_tp=not use_data_parallel,
+                use_attn_tp_group=is_dp_attention_enabled() and not use_data_parallel,
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +2/-2
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #21469 - [3/n] lora moe - Support Qwen3-VL-30B-A3B-Instruct

- 链接: https://github.com/sgl-project/sglang/pull/21469
- 状态/时间: merged / 2026-04-01
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl_moe.py`, `test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py`；关联提交 `cffc95edf455`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 3 个文件，+152/-235，可读 patch 397 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[3/n] lora moe - Support Qwen3-VL-30B-A3B-Instruct」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `python/sglang/srt/models/qwen3_vl_moe.py`, `test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py`；技术摘要: 覆盖「[3/n] lora moe - Support Qwen3-VL-30B-A3B-Instruct」；主要实现面是 `python/sglang/srt/models/qwen3_vl_moe.py`, `test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-2 (3 lines); hunks: -179,9 +179,8 @@ def __init__(; symbols: __init__, should_apply_lora，涉及 `__init__, should_apply_lora`；`test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py` added +151/-0 (151 lines); hunks: -0,0 +1,151; symbols: kl_v2, get_prompt_logprobs, TestLoRAQwen3VL_30B_A3B_Instruct_LogprobDiff, test_lora_qwen3_vl_30b_a3b_instruct_logprob_accuracy，涉及 `kl_v2, get_prompt_logprobs, TestLoRAQwen3VL_30B_A3B_Instruct_LogprobDiff`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-2 (3 lines); hunks: -179,9 +179,8 @@ def __init__(; symbols: __init__, should_apply_lora
  - `test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py` added +151/-0 (151 lines); hunks: -0,0 +1,151; symbols: kl_v2, get_prompt_logprobs, TestLoRAQwen3VL_30B_A3B_Instruct_LogprobDiff, test_lora_qwen3_vl_30b_a3b_instruct_logprob_accuracy
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -179,9 +179,8 @@ def __init__(
-    # Only allow LoRA on attention projections within text layers for MoE.
-        r"^model\.layers\.(\d+)\.self_attn\.(?:qkv_proj|o_proj)$"
+        r"^(?:model\.layers\.(\d+)\.(?:self_attn\.(?:qkv_proj|o_proj)|mlp\.experts)|lm_head|model\.embed_tokens)$"
diff -- test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py
@@ -0,0 +1,151 @@
+# Copyright 2023-2025 SGLang Team
+# Licensed under the Apache License, Version 2.0 (the "License");
+# you may not use this file except in compliance with the License.
+# You may obtain a copy of the License at
+#
+#     http://www.apache.org/licenses/LICENSE-2.0
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-2
  - tests: `test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py` added +151/-0
- 验证与风险: diff 自带测试面 `test/manual/lora/test_lora_qwen3_vl.py`, `test/registered/lora/test_lora_qwen3_vl_30b_a3b_instruct_logprob_diff.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #21458 - [AMD] Optimize Qwen3-VL decode - fuse QK-norm + 3D mRoPE + KV cache write

- 链接: https://github.com/sgl-project/sglang/pull/21458
- 状态/时间: merged / 2026-04-01
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+101/-3，可读 patch 152 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[AMD] Optimize Qwen3-VL decode - fuse QK-norm + 3D mRoPE + KV cache write」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3.py`；技术摘要: 覆盖「[AMD] Optimize Qwen3-VL decode - fuse QK-norm + 3D mRoPE + KV cache write」；主要实现面是 `python/sglang/srt/models/qwen3.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3.py` modified +101/-3 (104 lines); hunks: -19,6 +19,7; -30,13 +31,25; symbols: __init__, forward_prepare_native, forward_prepare_npu, forward_prepare_aiter_fused_mrope，涉及 `__init__, forward_prepare_native, forward_prepare_npu`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3.py` modified +101/-3 (104 lines); hunks: -19,6 +19,7; -30,13 +31,25; symbols: __init__, forward_prepare_native, forward_prepare_npu, forward_prepare_aiter_fused_mrope
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3.py
@@ -19,6 +19,7 @@
+from sglang.srt.layers.rotary_embedding.mrope import MRotaryEmbedding
@@ -30,13 +31,25 @@
-from sglang.srt.utils import add_prefix, is_cuda, is_npu
+from sglang.srt.utils import add_prefix, get_bool_env_var, is_cuda, is_hip, is_npu
+_is_hip = is_hip()
+_use_aiter = get_bool_env_var("SGLANG_USE_AITER") and _is_hip
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3.py` modified +101/-3
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #19135 - qwen3 vl skip layer id for pp

- 链接: https://github.com/sgl-project/sglang/pull/19135
- 状态/时间: merged / 2026-04-03
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+12/-0，可读 patch 26 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「qwen3 vl skip layer id for pp」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「qwen3 vl skip layer id for pp」；主要实现面是 `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl_moe.py` modified +12/-0 (12 lines); hunks: -26,6 +26,7; -232,6 +233,17 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +12/-0 (12 lines); hunks: -26,6 +26,7; -232,6 +233,17 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.T...; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -26,6 +26,7 @@
+from sglang.srt.layers.utils import get_layer_id
@@ -232,6 +233,17 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
+            layer_id = get_layer_id(name)
+            if (
+                "visual" not in name
+                and layer_id is not None
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl_moe.py` modified +12/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #22052 - [Fix] Enable precise embedding interpolation by default for Qwen3-VL

- 链接: https://github.com/sgl-project/sglang/pull/22052
- 状态/时间: open / 2026-04-03
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 3 个文件，+10/-11，可读 patch 57 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Fix] Enable precise embedding interpolation by default for Qwen3-VL」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/server_args.py`, `docs/advanced_features/server_arguments.md`；技术摘要: 覆盖「[Fix] Enable precise embedding interpolation by default for Qwen3-VL」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/server_args.py`, `docs/advanced_features/server_arguments.md`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +3/-7 (10 lines); hunks: -310,7 +310,7 @@ def __init__(; -524,12 +524,8 @@ def fast_pos_embed_interpolate_from_list(self, grid_thw):; symbols: __init__, fast_pos_embed_interpolate_from_list，涉及 `__init__, fast_pos_embed_interpolate_from_list`；`python/sglang/srt/server_args.py` modified +6/-3 (9 lines); hunks: -675,7 +675,7 @@ class ServerArgs:; -5732,9 +5732,12 @@ def add_cli_args(parser: argparse.ArgumentParser):; symbols: ServerArgs, add_cli_args，涉及 `ServerArgs, add_cli_args`；`docs/advanced_features/server_arguments.md` modified +1/-1 (2 lines); hunks: -469,7 +469,7 @@ Please consult the documentation below and [server_args.py](...。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +3/-7 (10 lines); hunks: -310,7 +310,7 @@ def __init__(; -524,12 +524,8 @@ def fast_pos_embed_interpolate_from_list(self, grid_thw):; symbols: __init__, fast_pos_embed_interpolate_from_list
  - `python/sglang/srt/server_args.py` modified +6/-3 (9 lines); hunks: -675,7 +675,7 @@ class ServerArgs:; -5732,9 +5732,12 @@ def add_cli_args(parser: argparse.ArgumentParser):; symbols: ServerArgs, add_cli_args
  - `docs/advanced_features/server_arguments.md` modified +1/-1 (2 lines); hunks: -469,7 +469,7 @@ Please consult the documentation below and [server_args.py](...
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -310,7 +310,7 @@ def __init__(
-            get_global_server_args().enable_precise_embedding_interpolation
+            not get_global_server_args().disable_precise_embedding_interpolation
@@ -524,12 +524,8 @@ def fast_pos_embed_interpolate_from_list(self, grid_thw):
-            h_idxs = torch.linspace(
-                0, num_grid_per_side - 1, h, dtype=torch.float32, device=self.device
-            )
diff -- python/sglang/srt/server_args.py
@@ -675,7 +675,7 @@ class ServerArgs:
-    enable_precise_embedding_interpolation: bool = False
+    disable_precise_embedding_interpolation: bool = False
@@ -5732,9 +5732,12 @@ def add_cli_args(parser: argparse.ArgumentParser):
-            "--enable-precise-embedding-interpolation",
+            "--disable-precise-embedding-interpolation",
-            help="Enable corner alignment for resize of embeddings grid to ensure more accurate(but slower) evaluation of interpolated embedding values.",
diff -- docs/advanced_features/server_arguments.md
@@ -469,7 +469,7 @@ Please consult the documentation below and [server_args.py](https://github.com/s
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +3/-7; `python/sglang/srt/server_args.py` modified +6/-3
  - docs: `docs/advanced_features/server_arguments.md` modified +1/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/server_args.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #22038 - [VLM] Chunk-aware ViT encoding with per-image cache and lazy device transfer

- 链接: https://github.com/sgl-project/sglang/pull/22038
- 状态/时间: merged / 2026-04-04
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 7 个文件，+167/-410，可读 patch 696 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Chunk-aware ViT encoding with per-image cache and lazy device transfer」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/mem_cache/multimodal_cache.py`, `python/sglang/srt/models/deepseek_vl2.py`；技术摘要: 覆盖「[VLM] Chunk-aware ViT encoding with per-image cache and lazy device transfer」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/mem_cache/multimodal_cache.py`, `python/sglang/srt/models/deepseek_vl2.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +10/-104 (114 lines); hunks: -15,7 +15,6; -73,7 +72,7; symbols: get_image_feature, get_video_feature，涉及 `get_image_feature, get_video_feature`；`python/sglang/srt/mem_cache/multimodal_cache.py` modified +7/-0 (7 lines); hunks: -120,6 +120,13 @@ def set(; symbols: set, get_single, has，涉及 `set, get_single, has`；`python/sglang/srt/models/deepseek_vl2.py` modified +1/-3 (4 lines); hunks: -270,9 +270,7 @@ def get_image_feature(self, items: List[MultimodalDataItem]):; symbols: get_image_feature，涉及 `get_image_feature`；`python/sglang/srt/models/phi4mm.py` modified +1/-1 (2 lines); hunks: -440,7 +440,7 @@ def get_audio_feature(self, items: List[MultimodalDataItem])...; symbols: get_audio_feature，涉及 `get_audio_feature`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +10/-104 (114 lines); hunks: -15,7 +15,6; -73,7 +72,7; symbols: get_image_feature, get_video_feature
  - `python/sglang/srt/mem_cache/multimodal_cache.py` modified +7/-0 (7 lines); hunks: -120,6 +120,13 @@ def set(; symbols: set, get_single, has
  - `python/sglang/srt/models/deepseek_vl2.py` modified +1/-3 (4 lines); hunks: -270,9 +270,7 @@ def get_image_feature(self, items: List[MultimodalDataItem]):; symbols: get_image_feature
  - `python/sglang/srt/models/phi4mm.py` modified +1/-1 (2 lines); hunks: -440,7 +440,7 @@ def get_audio_feature(self, items: List[MultimodalDataItem])...; symbols: get_audio_feature
  - `python/sglang/srt/models/step3_vl_10b.py` modified +1/-1 (2 lines); hunks: -484,7 +484,7 @@ def get_image_feature(self, items: List[MultimodalDataItem])...; symbols: get_image_feature
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -15,7 +15,6 @@
-import math
@@ -73,7 +72,7 @@
-from sglang.srt.utils import add_prefix, get_int_env_var, is_npu, round_up
+from sglang.srt.utils import add_prefix, is_npu, round_up
@@ -1167,114 +1166,21 @@ def get_image_feature(self, items: List[MultimodalDataItem]) -> torch.Tensor:
-        max_patches_per_call = get_int_env_var("SGLANG_VLM_MAX_PATCHES_PER_VIT", 0)
diff -- python/sglang/srt/mem_cache/multimodal_cache.py
@@ -120,6 +120,13 @@ def set(
+    def get_single(self, mm_hash: int) -> Optional[EmbeddingResult]:
+        """Get a single cached embedding by its hash (no combine_hashes)."""
+        embedding = self.mm_cache.get(mm_hash)
+        if embedding is not None:
+            self.mm_cache.move_to_end(mm_hash)
+        return embedding
diff -- python/sglang/srt/models/deepseek_vl2.py
@@ -270,9 +270,7 @@ def get_image_feature(self, items: List[MultimodalDataItem]):
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +10/-104; `python/sglang/srt/mem_cache/multimodal_cache.py` modified +7/-0; `python/sglang/srt/models/deepseek_vl2.py` modified +1/-3; `python/sglang/srt/models/phi4mm.py` modified +1/-1; `python/sglang/srt/models/step3_vl_10b.py` modified +1/-1; `python/sglang/srt/managers/mm_utils.py` modified +147/-286
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/managers/mm_utils.py`, `python/sglang/srt/managers/schedule_batch.py`, `python/sglang/srt/mem_cache/multimodal_cache.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #21849 - [VLM]: allow Qwen3.5 models for encoder disaggregation

- 链接: https://github.com/sgl-project/sglang/pull/21849
- 状态/时间: merged / 2026-04-06
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 4 个文件，+190/-3，可读 patch 230 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM]: allow Qwen3.5 models for encoder disaggregation」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`, `test/registered/distributed/test_epd_disaggregation.py`, `python/sglang/srt/disaggregation/encode_server.py`；技术摘要: 覆盖「[VLM]: allow Qwen3.5 models for encoder disaggregation」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`, `test/registered/distributed/test_epd_disaggregation.py`, `python/sglang/srt/disaggregation/encode_server.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +1/-1 (2 lines); hunks: -422,7 +422,7 @@ def get_mm_data(self, prompt, embeddings, **kwargs):; symbols: get_mm_data，涉及 `get_mm_data`；`test/registered/distributed/test_epd_disaggregation.py` modified +184/-0 (184 lines); hunks: -33,6 +33,7; -813,6 +814,189 @@ def test_mmmu(self):; symbols: test_mmmu, TestEPDDisaggregationQwen35, setUpClass, start_encode，涉及 `test_mmmu, TestEPDDisaggregationQwen35, setUpClass`；`python/sglang/srt/disaggregation/encode_server.py` modified +3/-2 (5 lines); hunks: -867,10 +867,11 @@ async def _process_mm_items(self, mm_items, modality):; symbols: _process_mm_items，涉及 `_process_mm_items`；`python/sglang/srt/server_args.py` modified +2/-0 (2 lines); hunks: -3326,6 +3326,8 @@ def _handle_encoder_disaggregation(self):; symbols: _handle_encoder_disaggregation，涉及 `_handle_encoder_disaggregation`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +1/-1 (2 lines); hunks: -422,7 +422,7 @@ def get_mm_data(self, prompt, embeddings, **kwargs):; symbols: get_mm_data
  - `test/registered/distributed/test_epd_disaggregation.py` modified +184/-0 (184 lines); hunks: -33,6 +33,7; -813,6 +814,189 @@ def test_mmmu(self):; symbols: test_mmmu, TestEPDDisaggregationQwen35, setUpClass, start_encode
  - `python/sglang/srt/disaggregation/encode_server.py` modified +3/-2 (5 lines); hunks: -867,10 +867,11 @@ async def _process_mm_items(self, mm_items, modality):; symbols: _process_mm_items
  - `python/sglang/srt/server_args.py` modified +2/-0 (2 lines); hunks: -3326,6 +3326,8 @@ def _handle_encoder_disaggregation(self):; symbols: _handle_encoder_disaggregation
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -422,7 +422,7 @@ def get_mm_data(self, prompt, embeddings, **kwargs):
-            self.model_type in ["qwen3_vl", "qwen3_vl_moe"]
+            self.model_type in ["qwen3_vl", "qwen3_vl_moe", "qwen3_5", "qwen3_5_moe"]
diff -- test/registered/distributed/test_epd_disaggregation.py
@@ -33,6 +33,7 @@
+QWEN35_27B_MODEL = "Qwen/Qwen3.5-27B"
@@ -813,6 +814,189 @@ def test_mmmu(self):
+@unittest.skipIf(
+    is_in_ci(),
+    "Qwen3.5 EPD image/video test runs locally only",
+)
diff -- python/sglang/srt/disaggregation/encode_server.py
@@ -867,10 +867,11 @@ async def _process_mm_items(self, mm_items, modality):
-                self.model_type in ["qwen3_vl", "qwen3_vl_moe"]
+                self.model_type
+                in ["qwen3_vl", "qwen3_vl_moe", "qwen3_5", "qwen3_5_moe"]
-                # For qwen3-vl models, we need to store the video timestamps
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +1/-1; `python/sglang/srt/disaggregation/encode_server.py` modified +3/-2; `python/sglang/srt/server_args.py` modified +2/-0
  - tests: `test/registered/distributed/test_epd_disaggregation.py` modified +184/-0
- 验证与风险: diff 自带测试面 `test/registered/distributed/test_epd_disaggregation.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #22073 - [Feature] Adding Qwen3-asr Model Support

- 链接: https://github.com/sgl-project/sglang/pull/22073
- 状态/时间: merged / 2026-04-07
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/configs/qwen3_asr.py`, `python/sglang/srt/models/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py`；关联提交 `f6e85676b578`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 10 个文件，+571/-11，可读 patch 689 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Feature] Adding Qwen3-asr Model Support」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_asr.py`, `python/sglang/srt/configs/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py`；技术摘要: 覆盖「[Feature] Adding Qwen3-asr Model Support」；主要实现面是 `python/sglang/srt/models/qwen3_asr.py`, `python/sglang/srt/configs/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_asr.py` added +199/-0 (199 lines); hunks: -0,0 +1,199; symbols: Qwen3ASRForConditionalGeneration, __init__, pad_input_ids, get_audio_feature，涉及 `Qwen3ASRForConditionalGeneration, __init__, pad_input_ids`；`python/sglang/srt/configs/qwen3_asr.py` added +172/-0 (172 lines); hunks: -0,0 +1,172; symbols: Qwen3ASRThinkerConfig, __init__, Qwen3ASRConfig, get_text_config，涉及 `Qwen3ASRThinkerConfig, __init__, Qwen3ASRConfig`；`python/sglang/srt/multimodal/processors/qwen3_asr.py` added +95/-0 (95 lines); hunks: -0,0 +1,95; symbols: Qwen3ASRMultimodalProcessor, __init__, _build_transcription_prompt, compute_mrope_positions，涉及 `Qwen3ASRMultimodalProcessor, __init__, _build_transcription_prompt`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_asr.py` added +199/-0 (199 lines); hunks: -0,0 +1,199; symbols: Qwen3ASRForConditionalGeneration, __init__, pad_input_ids, get_audio_feature
  - `python/sglang/srt/configs/qwen3_asr.py` added +172/-0 (172 lines); hunks: -0,0 +1,172; symbols: Qwen3ASRThinkerConfig, __init__, Qwen3ASRConfig, get_text_config
  - `python/sglang/srt/multimodal/processors/qwen3_asr.py` added +95/-0 (95 lines); hunks: -0,0 +1,95; symbols: Qwen3ASRMultimodalProcessor, __init__, _build_transcription_prompt, compute_mrope_positions
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_asr.py
@@ -0,0 +1,199 @@
+"""Qwen3-ASR model compatible with HuggingFace weights"""
+import logging
+from typing import Any, Iterable, List, Optional, Tuple
+import torch
+import torch.nn as nn
+from sglang.srt.configs.qwen3_asr import Qwen3ASRConfig
diff -- python/sglang/srt/configs/qwen3_asr.py
@@ -0,0 +1,172 @@
+import torch
+from transformers import (
+    AutoConfig,
+    AutoFeatureExtractor,
+    AutoTokenizer,
+    PretrainedConfig,
diff -- python/sglang/srt/multimodal/processors/qwen3_asr.py
@@ -0,0 +1,95 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_asr.py` added +199/-0; `python/sglang/srt/configs/qwen3_asr.py` added +172/-0; `python/sglang/srt/multimodal/processors/qwen3_asr.py` added +95/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/configs/__init__.py`, `python/sglang/srt/configs/model_config.py`, `python/sglang/srt/configs/qwen3_asr.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #22266 - [NPU] fix qwen3.5 video processor

- 链接: https://github.com/sgl-project/sglang/pull/22266
- 状态/时间: merged / 2026-04-08
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+177/-21，可读 patch 235 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[NPU] fix qwen3.5 video processor」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py`；技术摘要: 覆盖「[NPU] fix qwen3.5 video processor」；主要实现面是 `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py` modified +177/-21 (198 lines); hunks: -7,13 +7,62; -90,31 +139,16 @@ def _preprocess(; symbols: transform_patches_to_flatten, npu_wrapper_preprocess, _preprocess, npu_wrapper_video_preprocess，涉及 `transform_patches_to_flatten, npu_wrapper_preprocess, _preprocess`。
- 代码 diff 细节:
  - `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py` modified +177/-21 (198 lines); hunks: -7,13 +7,62; -90,31 +139,16 @@ def _preprocess(; symbols: transform_patches_to_flatten, npu_wrapper_preprocess, _preprocess, npu_wrapper_video_preprocess
- 关键代码摘录:

```diff
diff -- python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py
@@ -7,13 +7,62 @@
-from transformers.image_utils import SizeDict
+from transformers.image_utils import (
+    ChannelDimension,
+    PILImageResampling,
+    SizeDict,
+    get_image_size,
```

- 已读文件:
  - runtime: `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py` modified +177/-21
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #22181 - [refactor] [asr] Add transcription adapter for extensible ASR models support

- 链接: https://github.com/sgl-project/sglang/pull/22181
- 状态/时间: merged / 2026-04-08
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/configs/qwen3_asr.py`, `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py`, `test/manual/models/test_qwen3_asr.py`；关联提交 `a5ed507a1639`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 8 个文件，+473/-223，可读 patch 809 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[refactor] [asr] Add transcription adapter for extensible ASR models support」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `python/sglang/srt/configs/qwen3_asr.py`, `test/manual/models/test_qwen3_asr.py`, `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py`；技术摘要: 覆盖「[refactor] [asr] Add transcription adapter for extensible ASR models support」；主要实现面是 `python/sglang/srt/configs/qwen3_asr.py`, `test/manual/models/test_qwen3_asr.py`, `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/configs/qwen3_asr.py` modified +63/-67 (130 lines); hunks: -14,72 +14,6; -167,6 +101,68 @@ def __call__(self, text=None, audio=None, audio_kwargs=None...; symbols: Qwen3ASRThinkerConfig, __init__, Qwen3ASRConfig, get_text_config，涉及 `Qwen3ASRThinkerConfig, __init__, Qwen3ASRConfig`；`test/manual/models/test_qwen3_asr.py` added +118/-0 (118 lines); hunks: -0,0 +1,118; symbols: download_audio, TestQwen3ASRTranscription, setUpClass, tearDownClass，涉及 `download_audio, TestQwen3ASRTranscription, setUpClass`；`python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py` added +49/-0 (49 lines); hunks: -0,0 +1,49; symbols: Qwen3ASRAdapter, build_sampling_params, postprocess_text, build_verbose_response，涉及 `Qwen3ASRAdapter, build_sampling_params, postprocess_text`；`python/sglang/srt/multimodal/processors/qwen3_asr.py` modified +8/-5 (13 lines); hunks: -10,11 +10,13; -23,7 +25,7 @@ class Qwen3ASRMultimodalProcessor(BaseMultimodalProcessor):; symbols: Qwen3ASRMultimodalProcessor, __init__, _build_transcription_prompt，涉及 `Qwen3ASRMultimodalProcessor, __init__, _build_transcription_prompt`。
- 代码 diff 细节:
  - `python/sglang/srt/configs/qwen3_asr.py` modified +63/-67 (130 lines); hunks: -14,72 +14,6; -167,6 +101,68 @@ def __call__(self, text=None, audio=None, audio_kwargs=None...; symbols: Qwen3ASRThinkerConfig, __init__, Qwen3ASRConfig, get_text_config
  - `test/manual/models/test_qwen3_asr.py` added +118/-0 (118 lines); hunks: -0,0 +1,118; symbols: download_audio, TestQwen3ASRTranscription, setUpClass, tearDownClass
  - `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py` added +49/-0 (49 lines); hunks: -0,0 +1,49; symbols: Qwen3ASRAdapter, build_sampling_params, postprocess_text, build_verbose_response
  - `python/sglang/srt/multimodal/processors/qwen3_asr.py` modified +8/-5 (13 lines); hunks: -10,11 +10,13; -23,7 +25,7 @@ class Qwen3ASRMultimodalProcessor(BaseMultimodalProcessor):; symbols: Qwen3ASRMultimodalProcessor, __init__, _build_transcription_prompt
- 关键代码摘录:

```diff
diff -- python/sglang/srt/configs/qwen3_asr.py
@@ -14,72 +14,6 @@
-class Qwen3ASRThinkerConfig(PretrainedConfig):
-    model_type = "qwen3_asr_thinker"
-    sub_configs = {
-        "audio_config": Qwen3OmniMoeAudioEncoderConfig,
-    }
-    def __init__(
diff -- test/manual/models/test_qwen3_asr.py
@@ -0,0 +1,118 @@
+"""
+Test Qwen3-ASR model support in SGLang.
+Tests /v1/audio/transcriptions endpoint (OpenAI-compatible).
+Usage:
+    python test/manual/models/test_qwen3_asr.py
+"""
diff -- python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py
@@ -0,0 +1,49 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/configs/qwen3_asr.py` modified +63/-67; `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py` added +49/-0; `python/sglang/srt/multimodal/processors/qwen3_asr.py` modified +8/-5
  - tests: `test/manual/models/test_qwen3_asr.py` added +118/-0
- 验证与风险: diff 自带测试面 `test/manual/models/test_qwen3_asr.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #22230 - [Feature] Support eagle3 for qwen3-vl

- 链接: https://github.com/sgl-project/sglang/pull/22230
- 状态/时间: merged / 2026-04-09
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `a69be2e866fb`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+24/-0，可读 patch 51 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Feature] Support eagle3 for qwen3-vl」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[Feature] Support eagle3 for qwen3-vl」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +24/-0 (24 lines); hunks: -1130,6 +1130,9 @@ def __init__(; -1246,13 +1249,18 @@ def forward(; symbols: __init__, separate_deepstack_embeds, forward, load_weights，涉及 `__init__, separate_deepstack_embeds, forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +24/-0 (24 lines); hunks: -1130,6 +1130,9 @@ def __init__(; -1246,13 +1249,18 @@ def forward(; symbols: __init__, separate_deepstack_embeds, forward, load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -1130,6 +1130,9 @@ def __init__(
+        # For EAGLE3 support
+        self.capture_aux_hidden_states = False
@@ -1246,13 +1249,18 @@ def forward(
+        aux_hidden_states = None
+        if self.capture_aux_hidden_states:
+            hidden_states, aux_hidden_states = hidden_states
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +24/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #22089 - [Feature] Add chunk-based streaming ASR for Qwen3-ASR

- 链接: https://github.com/sgl-project/sglang/pull/22089
- 状态/时间: merged / 2026-04-09
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py`；关联提交 `8b991d98a12c`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+263/-2，可读 patch 325 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Feature] Add chunk-based streaming ASR for Qwen3-ASR」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py`；技术摘要: 覆盖「[Feature] Add chunk-based streaming ASR for Qwen3-ASR」；主要实现面是 `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py`, `python/sglang/srt/multimodal/processors/qwen3_asr.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py` modified +20/-0 (20 lines); hunks: -9,12 +9,32; symbols: Qwen3ASRAdapter, supports_chunked_streaming, chunked_streaming_config, prompt_template，涉及 `Qwen3ASRAdapter, supports_chunked_streaming, chunked_streaming_config`；`python/sglang/srt/multimodal/processors/qwen3_asr.py` modified +2/-2 (4 lines); hunks: -12,7 +12,7; -47,7 +47,7 @@ def _build_transcription_prompt(self, input_text: Union[str, l...; symbols: _build_transcription_prompt, compute_mrope_positions，涉及 `_build_transcription_prompt, compute_mrope_positions`。
- 代码 diff 细节:
  - `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py` modified +20/-0 (20 lines); hunks: -9,12 +9,32; symbols: Qwen3ASRAdapter, supports_chunked_streaming, chunked_streaming_config, prompt_template
  - `python/sglang/srt/multimodal/processors/qwen3_asr.py` modified +2/-2 (4 lines); hunks: -12,7 +12,7; -47,7 +47,7 @@ def _build_transcription_prompt(self, input_text: Union[str, l...; symbols: _build_transcription_prompt, compute_mrope_positions
- 关键代码摘录:

```diff
diff -- python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py
@@ -9,12 +9,32 @@
+from sglang.srt.multimodal.processors.qwen3_asr import DEFAULT_ASR_PROMPT
+    @property
+    def supports_chunked_streaming(self) -> bool:
+        return True
+    @property
+    def chunked_streaming_config(self) -> dict:
diff -- python/sglang/srt/multimodal/processors/qwen3_asr.py
@@ -12,7 +12,7 @@
-_DEFAULT_ASR_PROMPT = (
+DEFAULT_ASR_PROMPT = (
@@ -47,7 +47,7 @@ def _build_transcription_prompt(self, input_text: Union[str, list]) -> str:
-            return _DEFAULT_ASR_PROMPT
+            return DEFAULT_ASR_PROMPT
```

- 已读文件:
  - runtime: `python/sglang/srt/entrypoints/openai/transcription_adapters/qwen3_asr.py` modified +20/-0; `python/sglang/srt/multimodal/processors/qwen3_asr.py` modified +2/-2
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/entrypoints/openai/serving_transcription.py`, `python/sglang/srt/entrypoints/openai/streaming_asr.py`, `python/sglang/srt/entrypoints/openai/transcription_adapters/base.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #22839 - fix(config): Add from_dict() for Qwen3VL config classes

- 链接: https://github.com/sgl-project/sglang/pull/22839
- 状态/时间: open / 2026-04-15
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+306/-0，可读 patch 389 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「fix(config): Add from_dict() for Qwen3VL config classes」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `test/registered/unit/configs/test_qwen3_vl_config.py`, `python/sglang/srt/configs/qwen3_5.py`, `python/sglang/srt/configs/qwen3_vl.py`；技术摘要: 覆盖「fix(config): Add from_dict() for Qwen3VL config classes」；主要实现面是 `test/registered/unit/configs/test_qwen3_vl_config.py`, `python/sglang/srt/configs/qwen3_5.py`, `python/sglang/srt/configs/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `test/registered/unit/configs/test_qwen3_vl_config.py` added +198/-0 (198 lines); hunks: -0,0 +1,198; symbols: TestQwen3VLConfigFromDict, test_qwen3vl_config_dict_conversion, test_qwen3vl_config_with_object, test_qwen3vl_moe_config_dict_conversion，涉及 `TestQwen3VLConfigFromDict, test_qwen3vl_config_dict_conversion, test_qwen3vl_config_with_object`；`python/sglang/srt/configs/qwen3_5.py` modified +71/-0 (71 lines); hunks: -78,6 +78,17 @@ class Qwen3_5Config(PretrainedConfig):; -112,6 +123,55 @@ class Qwen3_5MoeVisionConfig(Qwen3_5VisionConfig):; symbols: Qwen3_5Config, from_dict, __init__, Qwen3_5MoeVisionConfig，涉及 `Qwen3_5Config, from_dict, __init__`；`python/sglang/srt/configs/qwen3_vl.py` modified +30/-0 (30 lines); hunks: -236,6 +236,17 @@ class Qwen3VLConfig(PretrainedConfig):; -251,11 +262,15 @@ def __init__(; symbols: Qwen3VLConfig, from_dict, __init__, Qwen3VLMoeConfig，涉及 `Qwen3VLConfig, from_dict, __init__`；`python/sglang/srt/configs/__init__.py` modified +3/-0 (3 lines); hunks: -25,6 +25,7; -65,4 +66,6。
- 代码 diff 细节:
  - `test/registered/unit/configs/test_qwen3_vl_config.py` added +198/-0 (198 lines); hunks: -0,0 +1,198; symbols: TestQwen3VLConfigFromDict, test_qwen3vl_config_dict_conversion, test_qwen3vl_config_with_object, test_qwen3vl_moe_config_dict_conversion
  - `python/sglang/srt/configs/qwen3_5.py` modified +71/-0 (71 lines); hunks: -78,6 +78,17 @@ class Qwen3_5Config(PretrainedConfig):; -112,6 +123,55 @@ class Qwen3_5MoeVisionConfig(Qwen3_5VisionConfig):; symbols: Qwen3_5Config, from_dict, __init__, Qwen3_5MoeVisionConfig
  - `python/sglang/srt/configs/qwen3_vl.py` modified +30/-0 (30 lines); hunks: -236,6 +236,17 @@ class Qwen3VLConfig(PretrainedConfig):; -251,11 +262,15 @@ def __init__(; symbols: Qwen3VLConfig, from_dict, __init__, Qwen3VLMoeConfig
  - `python/sglang/srt/configs/__init__.py` modified +3/-0 (3 lines); hunks: -25,6 +25,7; -65,4 +66,6
  - `python/sglang/srt/utils/hf_transformers_utils.py` modified +4/-0 (4 lines); hunks: -87,6 +87,8; -121,6 +123,8
- 关键代码摘录:

```diff
diff -- test/registered/unit/configs/test_qwen3_vl_config.py
@@ -0,0 +1,198 @@
+"""Unit tests for qwen3_vl and qwen3_5 config from_dict() handling.
+This tests the fix for transformers 5.5.0 compatibility where nested
+vision_config and text_config dicts need to be converted to config objects.
+"""
+import json
+import unittest
diff -- python/sglang/srt/configs/qwen3_5.py
@@ -78,6 +78,17 @@ class Qwen3_5Config(PretrainedConfig):
+    @classmethod
+    def from_dict(cls, config_dict, **kwargs):
+        config = super().from_dict(config_dict, **kwargs)
+        if isinstance(getattr(config, "vision_config", None), dict):
+            config.vision_config = cls.sub_configs["vision_config"](
+                **config.vision_config
diff -- python/sglang/srt/configs/qwen3_vl.py
@@ -236,6 +236,17 @@ class Qwen3VLConfig(PretrainedConfig):
```

- 已读文件:
  - tests: `test/registered/unit/configs/test_qwen3_vl_config.py` added +198/-0
  - runtime: `python/sglang/srt/configs/qwen3_5.py` modified +71/-0; `python/sglang/srt/configs/qwen3_vl.py` modified +30/-0; `python/sglang/srt/configs/__init__.py` modified +3/-0; `python/sglang/srt/utils/hf_transformers_utils.py` modified +4/-0
- 验证与风险: diff 自带测试面 `test/registered/unit/configs/test_qwen3_vl_config.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #23115 - fix: guard self.model access in Qwen3VLMoeForConditionalGeneration.load_weights

- 链接: https://github.com/sgl-project/sglang/pull/23115
- 状态/时间: open / 2026-04-18
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-0，可读 patch 8 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「fix: guard self.model access in Qwen3VLMoeForConditionalGeneration.load_weights」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「fix: guard self.model access in Qwen3VLMoeForConditionalGeneration.load_weights」；主要实现面是 `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0 (1 lines); hunks: -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Te...; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0 (1 lines); hunks: -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Te...; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
+                and hasattr(self, "model")
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #22431 - Fix Qwen3.5 video processing when passing video_data in "processor_output" format

- 链接: https://github.com/sgl-project/sglang/pull/22431
- 状态/时间: merged / 2026-04-18
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-1，可读 patch 9 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Fix Qwen3.5 video processing when passing video_data in "processor_output" format」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「Fix Qwen3.5 video processing when passing video_data in "processor_output" format」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +1/-1 (2 lines); hunks: -162,7 +162,7 @@ async def preprocess_video(; symbols: preprocess_video，涉及 `preprocess_video`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +1/-1 (2 lines); hunks: -162,7 +162,7 @@ async def preprocess_video(; symbols: preprocess_video
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -162,7 +162,7 @@ async def preprocess_video(
-        return vr
+        return vr, None
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +1/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #23304 - [Bugfix] Fix Qwen3-VL rope config compatibility

- 链接: https://github.com/sgl-project/sglang/pull/23304
- 状态/时间: closed / 2026-04-21
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-10，可读 patch 18 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Bugfix] Fix Qwen3-VL rope config compatibility」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3.py`；技术摘要: 覆盖「[Bugfix] Fix Qwen3-VL rope config compatibility」；主要实现面是 `python/sglang/srt/models/qwen3.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3.py` modified +1/-10 (11 lines); hunks: -316,16 +316,7 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3.py` modified +1/-10 (11 lines); hunks: -316,16 +316,7 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3.py
@@ -316,16 +316,7 @@ def __init__(
-        if (
-            hasattr(config, "rope_parameters")
-            and config.rope_parameters
-            and "rope_theta" in config.rope_parameters
-        ):
-            rope_theta = config.rope_parameters["rope_theta"]
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3.py` modified +1/-10
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #23907 - [Docs] add Nemotron 3 Nano Omni cookbook

- 链接: https://github.com/sgl-project/sglang/pull/23907
- 状态/时间: merged / 2026-04-28
- 反查来源: `git log --name-only -- <model-files>` 反查到 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx`；关联提交 `ad785a229911`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+746/-1，可读 patch 771 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Docs] add Nemotron 3 Nano Omni cookbook」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx`；技术摘要: 覆盖「[Docs] add Nemotron 3 Nano Omni cookbook」；主要实现面是 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` added +542/-0 (542 lines); hunks: -0,0 +1,542；`docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` added +200/-0 (200 lines); hunks: -0,0 +1,200。
- 代码 diff 细节:
  - `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` added +542/-0 (542 lines); hunks: -0,0 +1,542
  - `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` added +200/-0 (200 lines); hunks: -0,0 +1,200
- 关键代码摘录:

```diff
diff -- docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx
@@ -0,0 +1,542 @@
+---
+title: Nemotron 3 Nano Omni
+metatags:
+    description: "Deploy NVIDIA Nemotron 3 Nano Omni multimodal MoE model with SGLang - text, image, video, and audio inputs with reasoning and tool calling."
+tag:
+    NEW
diff -- docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx
@@ -0,0 +1,200 @@
+export const Nemotron3NanoOmniDeployment = () => {
+  const MODEL_PATHS = {
+    reasoning: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning',
+    bf16: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-BF16',
+    fp8: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-FP8',
+    nvfp4: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-NVFP4',
```

- 已读文件:
  - docs: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` added +542/-0; `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` added +200/-0
- 验证与风险: 该 PR 主要落在文档/示例 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/cookbook/autoregressive/intro.mdx`, `docs_new/cookbook/intro copy.mdx`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

### PR #23968 - [Docs] update Docker image for Nemotron 3 Nano Omni

- 链接: https://github.com/sgl-project/sglang/pull/23968
- 状态/时间: merged / 2026-04-28
- 反查来源: `git log --name-only -- <model-files>` 反查到 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；关联提交 `387c932dfc88`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-1，可读 patch 9 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Docs] update Docker image for Nemotron 3 Nano Omni」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；技术摘要: 覆盖「[Docs] update Docker image for Nemotron 3 Nano Omni」；主要实现面是 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +1/-1 (2 lines); hunks: -52,7 +52,7 @@ pip install sglang。
- 代码 diff 细节:
  - `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +1/-1 (2 lines); hunks: -52,7 +52,7 @@ pip install sglang
- 关键代码摘录:

```diff
diff -- docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx
@@ -52,7 +52,7 @@ pip install sglang
-docker pull lmsysorg/sglang:nightly
+docker pull lmsysorg/sglang:dev-cu13-nemotronh-nano-omni-reasoning-v3
```

- 已读文件:
  - docs: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +1/-1
- 验证与风险: 该 PR 主要落在文档/示例 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

### PR #24163 - Revert "[ci] split stage-c-test-4-gpu-b200 to enable a low-disk runner pool"

- 链接: https://github.com/sgl-project/sglang/pull/24163
- 状态/时间: merged / 2026-04-30
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 17 个文件，+29/-99，可读 patch 290 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Revert "[ci] split stage-c-test-4-gpu-b200 to enable a low-disk runner pool"」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `.github/workflows/pr-test.yml`, `scripts/ci/utils/slash_command_handler.py`, `test/registered/4-gpu-models/test_gpt_oss_4gpu.py`；技术摘要: 覆盖「Revert "[ci] split stage-c-test-4-gpu-b200 to enable a low-disk runner pool"」；主要实现面是 `.github/workflows/pr-test.yml`, `scripts/ci/utils/slash_command_handler.py`, `test/registered/4-gpu-models/test_gpt_oss_4gpu.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `.github/workflows/pr-test.yml` modified +15/-82 (97 lines); hunks: -101,7 +101,6 @@ jobs:; -283,10 +282,8 @@ jobs:；`scripts/ci/utils/slash_command_handler.py` modified +0/-2 (2 lines); hunks: -303,7 +303,6 @@ def handle_rerun_stage(; -486,7 +485,6 @@ def handle_rerun_stage(; symbols: handle_rerun_stage，涉及 `handle_rerun_stage`；`test/registered/4-gpu-models/test_gpt_oss_4gpu.py` modified +1/-1 (2 lines); hunks: -4,7 +4,7; symbols: TestGptOss4Gpu，涉及 `TestGptOss4Gpu`；`test/registered/4-gpu-models/test_nvidia_nemotron_3_super_nvfp4.py` modified +1/-1 (2 lines); hunks: -11,7 +11,7。
- 代码 diff 细节:
  - `.github/workflows/pr-test.yml` modified +15/-82 (97 lines); hunks: -101,7 +101,6 @@ jobs:; -283,10 +282,8 @@ jobs:
  - `scripts/ci/utils/slash_command_handler.py` modified +0/-2 (2 lines); hunks: -303,7 +303,6 @@ def handle_rerun_stage(; -486,7 +485,6 @@ def handle_rerun_stage(; symbols: handle_rerun_stage
  - `test/registered/4-gpu-models/test_gpt_oss_4gpu.py` modified +1/-1 (2 lines); hunks: -4,7 +4,7; symbols: TestGptOss4Gpu
  - `test/registered/4-gpu-models/test_nvidia_nemotron_3_super_nvfp4.py` modified +1/-1 (2 lines); hunks: -11,7 +11,7
  - `test/registered/4-gpu-models/test_qwen35_fp4_mtp_v2.py` modified +1/-1 (2 lines); hunks: -15,7 +15,7
- 关键代码摘录:

```diff
diff -- .github/workflows/pr-test.yml
@@ -101,7 +101,6 @@ jobs:
-      b200_low_disk_runner: ${{ steps.set-runner.outputs.b200_low_disk_runner }}
@@ -283,10 +282,8 @@ jobs:
-            echo "b200_low_disk_runner=4-gpu-b200-kernel-low-disk" >> $GITHUB_OUTPUT
-            echo "b200_low_disk_runner=4-gpu-b200-low-disk" >> $GITHUB_OUTPUT
@@ -337,20 +334,19 @@ jobs:
-            echo "| Component            | Changed |"
diff -- scripts/ci/utils/slash_command_handler.py
@@ -303,7 +303,6 @@ def handle_rerun_stage(
-        "stage-c-test-4-gpu-b200-small",
@@ -486,7 +485,6 @@ def handle_rerun_stage(
-    "stage-c-test-4-gpu-b200-small": "4-gpu-b200-low-disk",
diff -- test/registered/4-gpu-models/test_gpt_oss_4gpu.py
@@ -4,7 +4,7 @@
-register_cuda_ci(est_time=584, suite="stage-c-test-4-gpu-b200-small")
+register_cuda_ci(est_time=740, suite="stage-c-test-4-gpu-b200")
diff -- test/registered/4-gpu-models/test_nvidia_nemotron_3_super_nvfp4.py
```

- 已读文件:
  - ci: `.github/workflows/pr-test.yml` modified +15/-82
  - other: `scripts/ci/utils/slash_command_handler.py` modified +0/-2
  - tests: `test/registered/4-gpu-models/test_gpt_oss_4gpu.py` modified +1/-1; `test/registered/4-gpu-models/test_nvidia_nemotron_3_super_nvfp4.py` modified +1/-1; `test/registered/4-gpu-models/test_qwen35_fp4_mtp_v2.py` modified +1/-1; `test/registered/4-gpu-models/test_qwen35_fp4_triton.py` modified +1/-1; `test/registered/lora/test_lora_gpt_oss_20b_logprob_diff.py` modified +1/-1; `test/registered/lora/test_lora_nemotron_3_super_120b_a12b_logprob_diff.py` modified +1/-1
- 验证与风险: diff 自带测试面 `test/registered/4-gpu-models/test_gpt_oss_4gpu.py`, `test/registered/4-gpu-models/test_nvidia_nemotron_3_super_nvfp4.py`, `test/registered/4-gpu-models/test_qwen35_fp4_mtp_v2.py`, `test/registered/4-gpu-models/test_qwen35_fp4_triton.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #23998 - update Nemotron3 Nano Omni cookbook benchmarks

- 链接: https://github.com/sgl-project/sglang/pull/23998
- 状态/时间: merged / 2026-05-05
- 反查来源: `git log --name-only -- <model-files>` 反查到 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；关联提交 `83b48fd5237a`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+119/-4，可读 patch 165 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「update Nemotron3 Nano Omni cookbook benchmarks」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；技术摘要: 覆盖「update Nemotron3 Nano Omni cookbook benchmarks」；主要实现面是 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +119/-4 (123 lines); hunks: -478,7 +478,7 @@ Nemotron 3 Nano Omni achieves **9x higher throughput** than...; -492,6 +492,7 @@ sglang serve \。
- 代码 diff 细节:
  - `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +119/-4 (123 lines); hunks: -478,7 +478,7 @@ Nemotron 3 Nano Omni achieves **9x higher throughput** than...; -492,6 +492,7 @@ sglang serve \
- 关键代码摘录:

```diff
diff -- docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx
@@ -478,7 +478,7 @@ Nemotron 3 Nano Omni achieves **9x higher throughput** than other open omni mode
-- Hardware: H100 (4×)
+- Hardware: B200 (8×)
@@ -492,6 +492,7 @@ sglang serve \
+  --attention-backend flashinfer \
@@ -510,12 +511,52 @@ python3 -m sglang.bench_serving \
-### 5.3 Accuracy Benchmark
```

- 已读文件:
  - docs: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +119/-4
- 验证与风险: 该 PR 主要落在文档/示例 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

### PR #24875 - Support Intern-S2-Preview

- 链接: https://github.com/sgl-project/sglang/pull/24875
- 状态/时间: merged / 2026-05-10
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 11 个文件，+64/-2，可读 patch 201 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Support Intern-S2-Preview」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/configs/interns2preview.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/models/interns2preview.py`；技术摘要: 覆盖「Support Intern-S2-Preview」；主要实现面是 `python/sglang/srt/configs/interns2preview.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/models/interns2preview.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/configs/interns2preview.py` added +23/-0 (23 lines); hunks: -0,0 +1,23; symbols: InternS2PreviewVisionConfig, __init__, InternS2PreviewConfig，涉及 `InternS2PreviewVisionConfig, __init__, InternS2PreviewConfig`；`python/sglang/srt/multimodal/processors/qwen_vl.py` modified +11/-1 (12 lines); hunks: -17,6 +17,7; -246,6 +247,7 @@ class QwenVLImageProcessor(SGLangBaseProcessor):; symbols: QwenVLImageProcessor, get_mm_data, process_mm_data_async，涉及 `QwenVLImageProcessor, get_mm_data, process_mm_data_async`；`python/sglang/srt/models/interns2preview.py` added +9/-0 (9 lines); hunks: -0,0 +1,9; symbols: InternS2PreviewForConditionalGeneration，涉及 `InternS2PreviewForConditionalGeneration`；`python/sglang/srt/configs/__init__.py` modified +2/-0 (2 lines); hunks: -8,6 +8,7; -55,6 +56,7。
- 代码 diff 细节:
  - `python/sglang/srt/configs/interns2preview.py` added +23/-0 (23 lines); hunks: -0,0 +1,23; symbols: InternS2PreviewVisionConfig, __init__, InternS2PreviewConfig
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +11/-1 (12 lines); hunks: -17,6 +17,7; -246,6 +247,7 @@ class QwenVLImageProcessor(SGLangBaseProcessor):; symbols: QwenVLImageProcessor, get_mm_data, process_mm_data_async
  - `python/sglang/srt/models/interns2preview.py` added +9/-0 (9 lines); hunks: -0,0 +1,9; symbols: InternS2PreviewForConditionalGeneration
  - `python/sglang/srt/configs/__init__.py` modified +2/-0 (2 lines); hunks: -8,6 +8,7; -55,6 +56,7
  - `python/sglang/srt/configs/model_config.py` modified +2/-0 (2 lines); hunks: -466,6 +466,7 @@ def _config_draft_model(self):; -1521,6 +1522,7 @@ def is_generation_model(model_architectures: List[str], is...; symbols: _config_draft_model, is_generation_model
- 关键代码摘录:

```diff
diff -- python/sglang/srt/configs/interns2preview.py
@@ -0,0 +1,23 @@
+from sglang.srt.configs.qwen3_5 import (
+    Qwen3_5MoeConfig,
+    Qwen3_5MoeTextConfig,
+    Qwen3_5MoeVisionConfig,
+)
+class InternS2PreviewVisionConfig(Qwen3_5MoeVisionConfig):
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -17,6 +17,7 @@
+from sglang.srt.models.interns2preview import InternS2PreviewForConditionalGeneration
@@ -246,6 +247,7 @@ class QwenVLImageProcessor(SGLangBaseProcessor):
+        InternS2PreviewForConditionalGeneration,
@@ -419,7 +421,14 @@ def get_mm_data(self, prompt, embeddings, **kwargs):
-            self.model_type in ["qwen3_vl", "qwen3_vl_moe", "qwen3_5", "qwen3_5_moe"]
+            self.model_type
diff -- python/sglang/srt/models/interns2preview.py
@@ -0,0 +1,9 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/configs/interns2preview.py` added +23/-0; `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +11/-1; `python/sglang/srt/models/interns2preview.py` added +9/-0; `python/sglang/srt/configs/__init__.py` modified +2/-0; `python/sglang/srt/configs/model_config.py` modified +2/-0; `python/sglang/srt/model_executor/model_runner.py` modified +2/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/configs/__init__.py`, `python/sglang/srt/configs/interns2preview.py`, `python/sglang/srt/configs/model_config.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #24187 - [Fix] Qwen3-ASR config: set thinker_config before super().__init__

- 链接: https://github.com/sgl-project/sglang/pull/24187
- 状态/时间: merged / 2026-05-12
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/configs/qwen3_asr.py`；关联提交 `0f3932c05540`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-1，可读 patch 16 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Fix] Qwen3-ASR config: set thinker_config before super().__init__」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/configs/qwen3_asr.py`；技术摘要: 覆盖「[Fix] Qwen3-ASR config: set thinker_config before super().__init__」；主要实现面是 `python/sglang/srt/configs/qwen3_asr.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/configs/qwen3_asr.py` modified +1/-1 (2 lines); hunks: -148,7 +148,6 @@ class Qwen3ASRConfig(PretrainedConfig):; -159,6 +158,7 @@ def __init__(self, thinker_config=None, **kwargs):; symbols: Qwen3ASRConfig, __init__, get_text_config，涉及 `Qwen3ASRConfig, __init__, get_text_config`。
- 代码 diff 细节:
  - `python/sglang/srt/configs/qwen3_asr.py` modified +1/-1 (2 lines); hunks: -148,7 +148,6 @@ class Qwen3ASRConfig(PretrainedConfig):; -159,6 +158,7 @@ def __init__(self, thinker_config=None, **kwargs):; symbols: Qwen3ASRConfig, __init__, get_text_config
- 关键代码摘录:

```diff
diff -- python/sglang/srt/configs/qwen3_asr.py
@@ -148,7 +148,6 @@ class Qwen3ASRConfig(PretrainedConfig):
-        super().__init__(**kwargs)
@@ -159,6 +158,7 @@ def __init__(self, thinker_config=None, **kwargs):
+        super().__init__(**kwargs)
```

- 已读文件:
  - runtime: `python/sglang/srt/configs/qwen3_asr.py` modified +1/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/configs/qwen3_asr.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #25197 - ci: decouple stage and runner for cuda registry

- 链接: https://github.com/sgl-project/sglang/pull/25197
- 状态/时间: merged / 2026-05-14
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 261 个文件，+388/-293，可读 patch 2625 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「ci: decouple stage and runner for cuda registry」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `test/registered/layers/test_fla_layernorm_guard.py`, `test/registered/models/test_dummy_grok_models.py`, `test/registered/models/test_ministral3_models.py`；技术摘要: 覆盖「ci: decouple stage and runner for cuda registry」；主要实现面是 `test/registered/layers/test_fla_layernorm_guard.py`, `test/registered/models/test_dummy_grok_models.py`, `test/registered/models/test_ministral3_models.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `test/registered/layers/test_fla_layernorm_guard.py` modified +2/-1 (3 lines); hunks: -19,7 +19,8；`test/registered/models/test_dummy_grok_models.py` modified +2/-1 (3 lines); hunks: -5,7 +5,8；`test/registered/models/test_ministral3_models.py` modified +2/-1 (3 lines); hunks: -8,7 +8,8；`test/registered/models/test_ministral4_models.py` modified +2/-1 (3 lines); hunks: -8,7 +8,8。
- 代码 diff 细节:
  - `test/registered/layers/test_fla_layernorm_guard.py` modified +2/-1 (3 lines); hunks: -19,7 +19,8
  - `test/registered/models/test_dummy_grok_models.py` modified +2/-1 (3 lines); hunks: -5,7 +5,8
  - `test/registered/models/test_ministral3_models.py` modified +2/-1 (3 lines); hunks: -8,7 +8,8
  - `test/registered/models/test_ministral4_models.py` modified +2/-1 (3 lines); hunks: -8,7 +8,8
  - `test/registered/models/test_nvidia_nemotron_3_nano.py` modified +2/-1 (3 lines); hunks: -6,7 +6,8
- 关键代码摘录:

```diff
diff -- test/registered/layers/test_fla_layernorm_guard.py
@@ -19,7 +19,8 @@
-    suite="stage-b-test-2-gpu-large",
+    stage="stage-b",
+    runner_config="2-gpu-large",
diff -- test/registered/models/test_dummy_grok_models.py
@@ -5,7 +5,8 @@
-    suite="stage-b-test-2-gpu-large",
+    stage="stage-b",
+    runner_config="2-gpu-large",
diff -- test/registered/models/test_ministral3_models.py
@@ -8,7 +8,8 @@
-    suite="stage-b-test-1-gpu-small",
+    stage="stage-b",
+    runner_config="1-gpu-small",
diff -- test/registered/models/test_ministral4_models.py
@@ -8,7 +8,8 @@
-    suite="stage-b-test-2-gpu-large",
```

- 已读文件:
  - tests: `test/registered/layers/test_fla_layernorm_guard.py` modified +2/-1; `test/registered/models/test_dummy_grok_models.py` modified +2/-1; `test/registered/models/test_ministral3_models.py` modified +2/-1; `test/registered/models/test_ministral4_models.py` modified +2/-1; `test/registered/models/test_nvidia_nemotron_3_nano.py` modified +2/-1; `test/registered/layers/mamba/test_causal_conv1d.py` modified +1/-1
- 验证与风险: diff 自带测试面 `python/sglang/test/ci/ci_register.py`, `test/registered/4-gpu-models/test_deepseek_v3_cutedsl_4gpu.py`, `test/registered/4-gpu-models/test_gpt_oss_4gpu.py`, `test/registered/4-gpu-models/test_nvidia_nemotron_3_super_nvfp4.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #25203 - ci: B200 conditional split + LPT_SLOP removal (stage-c partition 8→3)

- 链接: https://github.com/sgl-project/sglang/pull/25203
- 状态/时间: merged / 2026-05-14
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 19 个文件，+33/-34，可读 patch 209 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「ci: B200 conditional split + LPT_SLOP removal (stage-c partition 8→3)」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `scripts/ci/utils/compute_partitions.py`, `test/registered/lora/test_lora_gpt_oss_20b_logprob_diff.py`, `test/registered/lora/test_lora_nemotron_3_super_120b_a12b_logprob_diff.py`；技术摘要: 覆盖「ci: B200 conditional split + LPT_SLOP removal (stage-c partition 8→3)」；主要实现面是 `scripts/ci/utils/compute_partitions.py`, `test/registered/lora/test_lora_gpt_oss_20b_logprob_diff.py`, `test/registered/lora/test_lora_nemotron_3_super_120b_a12b_logprob_diff.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `scripts/ci/utils/compute_partitions.py` modified +9/-10 (19 lines); hunks: -39,15 +39,13; -97,10 +95,11 @@ def compute_partitions(tests, full_parallel=False):; symbols: compute_partitions，涉及 `compute_partitions`；`test/registered/lora/test_lora_gpt_oss_20b_logprob_diff.py` modified +3/-3 (6 lines); hunks: -35,9 +35,9；`test/registered/lora/test_lora_nemotron_3_super_120b_a12b_logprob_diff.py` modified +3/-3 (6 lines); hunks: -35,9 +35,9；`test/registered/lora/test_lora_qwen3_30b_a3b_instruct_2507_logprob_diff.py` modified +3/-3 (6 lines); hunks: -35,9 +35,9。
- 代码 diff 细节:
  - `scripts/ci/utils/compute_partitions.py` modified +9/-10 (19 lines); hunks: -39,15 +39,13; -97,10 +95,11 @@ def compute_partitions(tests, full_parallel=False):; symbols: compute_partitions
  - `test/registered/lora/test_lora_gpt_oss_20b_logprob_diff.py` modified +3/-3 (6 lines); hunks: -35,9 +35,9
  - `test/registered/lora/test_lora_nemotron_3_super_120b_a12b_logprob_diff.py` modified +3/-3 (6 lines); hunks: -35,9 +35,9
  - `test/registered/lora/test_lora_qwen3_30b_a3b_instruct_2507_logprob_diff.py` modified +3/-3 (6 lines); hunks: -35,9 +35,9
  - `test/registered/4-gpu-models/test_gpt_oss_4gpu.py` modified +1/-1 (2 lines); hunks: -4,7 +4,7; symbols: TestGptOss4Gpu
- 关键代码摘录:

```diff
diff -- scripts/ci/utils/compute_partitions.py
@@ -39,15 +39,13 @@
-# Per-partition wall-clock target + ceiling. Single knob for the whole
-# pipeline. ~17 min avg under perfect LPT (TARGET / LPT_SLOP), ~22 min under
-# worst-case LPT 4/3 imbalance, fail-fast above 30 min.
+# Per-partition wall-clock target. ~20 min avg naive; worst-case LPT 4/3
+# imbalance is ~27 min, still below the 30-min job-level timeout that acts
+# as the real safety net. No LPT slop applied — we lean on the runtime
diff -- test/registered/lora/test_lora_gpt_oss_20b_logprob_diff.py
@@ -35,9 +35,9 @@
-    est_time=300,
-    stage="stage-c",
-    runner_config="4-gpu-b200",
+    est_time=90,
+    suite="nightly-4-gpu-b200",
+    nightly=True,
diff -- test/registered/lora/test_lora_nemotron_3_super_120b_a12b_logprob_diff.py
@@ -35,9 +35,9 @@
```

- 已读文件:
  - other: `scripts/ci/utils/compute_partitions.py` modified +9/-10
  - tests: `test/registered/lora/test_lora_gpt_oss_20b_logprob_diff.py` modified +3/-3; `test/registered/lora/test_lora_nemotron_3_super_120b_a12b_logprob_diff.py` modified +3/-3; `test/registered/lora/test_lora_qwen3_30b_a3b_instruct_2507_logprob_diff.py` modified +3/-3; `test/registered/4-gpu-models/test_gpt_oss_4gpu.py` modified +1/-1; `test/registered/4-gpu-models/test_nvidia_nemotron_3_super_nvfp4.py` modified +1/-1; `test/registered/4-gpu-models/test_qwen35_fp4_mtp_v2.py` modified +1/-1
- 验证与风险: diff 自带测试面 `test/registered/4-gpu-models/test_gpt_oss_4gpu.py`, `test/registered/4-gpu-models/test_nvidia_nemotron_3_super_nvfp4.py`, `test/registered/4-gpu-models/test_qwen35_fp4_mtp_v2.py`, `test/registered/4-gpu-models/test_qwen35_models.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #25130 - [NPU]Bugfix:Set default values for npu_wrapper_preprocess parameters

- 链接: https://github.com/sgl-project/sglang/pull/25130
- 状态/时间: merged / 2026-05-14
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+12/-17，可读 patch 96 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[NPU]Bugfix:Set default values for npu_wrapper_preprocess parameters」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py`, `python/sglang/srt/hardware_backend/npu/attention/ascend_gdn_backend.py`；技术摘要: 覆盖「[NPU]Bugfix:Set default values for npu_wrapper_preprocess parameters」；主要实现面是 `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py`, `python/sglang/srt/hardware_backend/npu/attention/ascend_gdn_backend.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py` modified +11/-16 (27 lines); hunks: -1,12 +1,7; -63,16 +58,16 @@ def transform_patches_to_flatten(; symbols: transform_patches_to_flatten, npu_wrapper_preprocess, _preprocess，涉及 `transform_patches_to_flatten, npu_wrapper_preprocess, _preprocess`；`python/sglang/srt/hardware_backend/npu/attention/ascend_gdn_backend.py` modified +1/-1 (2 lines); hunks: -414,7 +414,7 @@ def fused_recurrent_gated_delta_rule_update(; symbols: fused_recurrent_gated_delta_rule_update，涉及 `fused_recurrent_gated_delta_rule_update`。
- 代码 diff 细节:
  - `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py` modified +11/-16 (27 lines); hunks: -1,12 +1,7; -63,16 +58,16 @@ def transform_patches_to_flatten(; symbols: transform_patches_to_flatten, npu_wrapper_preprocess, _preprocess
  - `python/sglang/srt/hardware_backend/npu/attention/ascend_gdn_backend.py` modified +1/-1 (2 lines); hunks: -414,7 +414,7 @@ def fused_recurrent_gated_delta_rule_update(; symbols: fused_recurrent_gated_delta_rule_update
- 关键代码摘录:

```diff
diff -- python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py
@@ -1,12 +1,7 @@
-from typing import Optional
-from transformers.image_processing_utils_fast import (
-    group_images_by_shape,
-    reorder_images,
-)
+from transformers.image_transforms import group_images_by_shape, reorder_images
diff -- python/sglang/srt/hardware_backend/npu/attention/ascend_gdn_backend.py
@@ -414,7 +414,7 @@ def fused_recurrent_gated_delta_rule_update(
-            num_accept_tokens=num_accept_tokens,
+            num_accepted_tokens=num_accept_tokens,
```

- 已读文件:
  - runtime: `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py` modified +11/-16; `python/sglang/srt/hardware_backend/npu/attention/ascend_gdn_backend.py` modified +1/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/hardware_backend/npu/attention/ascend_gdn_backend.py`, `python/sglang/srt/hardware_backend/npu/modules/qwen_vl_processor.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #25420 - [CI] Rename basic CI `stage-a/b/c` -> `base-a/b/c` for symmetry with extra CI

- 链接: https://github.com/sgl-project/sglang/pull/25420
- 状态/时间: merged / 2026-05-16
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 473 个文件，+746/-747，可读 patch 5614 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[CI] Rename basic CI `stage-a/b/c` -> `base-a/b/c` for symmetry with extra CI」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `.github/workflows/pr-test-multimodal-gen.yml`, `test/registered/bench_fn/test_bench_serving_reasoning_stream.py`, `test/registered/function_call/test_kimik2_detector.py`；技术摘要: 覆盖「[CI] Rename basic CI `stage-a/b/c` -> `base-a/b/c` for symmetry with extra CI」；主要实现面是 `.github/workflows/pr-test-multimodal-gen.yml`, `test/registered/bench_fn/test_bench_serving_reasoning_stream.py`, `test/registered/function_call/test_kimik2_detector.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `.github/workflows/pr-test-multimodal-gen.yml` modified +7/-7 (14 lines); hunks: -31,7 +31,7 @@ on:; -42,7 +42,7 @@ env:；`test/registered/bench_fn/test_bench_serving_reasoning_stream.py` modified +1/-1 (2 lines); hunks: -24,7 +24,7; symbols: _free_port，涉及 `_free_port`；`test/registered/function_call/test_kimik2_detector.py` modified +1/-1 (2 lines); hunks: -11,7 +11,7; symbols: _make_tool，涉及 `_make_tool`；`test/registered/layers/mamba/test_causal_conv1d.py` modified +1/-1 (2 lines); hunks: -2,7 +2,7。
- 代码 diff 细节:
  - `.github/workflows/pr-test-multimodal-gen.yml` modified +7/-7 (14 lines); hunks: -31,7 +31,7 @@ on:; -42,7 +42,7 @@ env:
  - `test/registered/bench_fn/test_bench_serving_reasoning_stream.py` modified +1/-1 (2 lines); hunks: -24,7 +24,7; symbols: _free_port
  - `test/registered/function_call/test_kimik2_detector.py` modified +1/-1 (2 lines); hunks: -11,7 +11,7; symbols: _make_tool
  - `test/registered/layers/mamba/test_causal_conv1d.py` modified +1/-1 (2 lines); hunks: -2,7 +2,7
  - `test/registered/layers/mamba/test_mamba2_mixer.py` modified +1/-1 (2 lines); hunks: -18,7 +18,7
- 关键代码摘录:

```diff
diff -- .github/workflows/pr-test-multimodal-gen.yml
@@ -31,7 +31,7 @@ on:
-      skip_stage_health_check:
+      skip_pr_test_health_check:
@@ -42,7 +42,7 @@ env:
-  SKIP_STAGE_HEALTH_CHECK: ${{ inputs.skip_stage_health_check == 'true' }}
+  SKIP_PR_TEST_HEALTH_CHECK: ${{ inputs.skip_pr_test_health_check == 'true' }}
@@ -90,7 +90,7 @@ jobs:
diff -- test/registered/bench_fn/test_bench_serving_reasoning_stream.py
@@ -24,7 +24,7 @@
-register_cpu_ci(est_time=10, suite="stage-a-test-cpu")
+register_cpu_ci(est_time=10, suite="base-a-test-cpu")
diff -- test/registered/function_call/test_kimik2_detector.py
@@ -11,7 +11,7 @@
-register_cpu_ci(5, "stage-a-test-cpu")
+register_cpu_ci(5, "base-a-test-cpu")
diff -- test/registered/layers/mamba/test_causal_conv1d.py
@@ -2,7 +2,7 @@
```

- 已读文件:
  - runtime: `.github/workflows/pr-test-multimodal-gen.yml` modified +7/-7
  - tests: `test/registered/bench_fn/test_bench_serving_reasoning_stream.py` modified +1/-1; `test/registered/function_call/test_kimik2_detector.py` modified +1/-1; `test/registered/layers/mamba/test_causal_conv1d.py` modified +1/-1; `test/registered/layers/mamba/test_mamba2_mixer.py` modified +1/-1; `test/registered/layers/mamba/test_mamba_ssm.py` modified +1/-1; `test/registered/layers/mamba/test_mamba_ssm_ssd.py` modified +1/-1
- 验证与风险: diff 自带测试面 `python/sglang/jit_kernel/tests/deepseek_v4/test_c128_v2.py`, `python/sglang/jit_kernel/tests/deepseek_v4/test_c4_v2.py`, `python/sglang/jit_kernel/tests/test_activation.py`, `python/sglang/jit_kernel/tests/test_add_constant.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #25759 - [BugFix][EPD]Fix Qwen3VLMoe encoder-only AttributeError

- 链接: https://github.com/sgl-project/sglang/pull/25759
- 状态/时间: merged / 2026-05-21
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-0，可读 patch 8 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[BugFix][EPD]Fix Qwen3VLMoe encoder-only AttributeError」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「[BugFix][EPD]Fix Qwen3VLMoe encoder-only AttributeError」；主要实现面是 `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0 (1 lines); hunks: -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Te...; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0 (1 lines); hunks: -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Te...; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
+                and hasattr(self, "model")
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #24751 - fix(mm): make multimodal data loading non-blocking to prevent health check stalls

- 链接: https://github.com/sgl-project/sglang/pull/24751
- 状态/时间: merged / 2026-05-22
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 35 个文件，+45/-44，可读 patch 401 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「fix(mm): make multimodal data loading non-blocking to prevent health check stalls」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/internvl.py`, `python/sglang/srt/multimodal/processors/minicpm.py`；技术摘要: 覆盖「fix(mm): make multimodal data loading non-blocking to prevent health check stalls」；主要实现面是 `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/internvl.py`, `python/sglang/srt/multimodal/processors/minicpm.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/base_processor.py` modified +8/-7 (15 lines); hunks: -1,3 +1,4; -729,7 +730,7 @@ def _process_loaded_mm_data(self, modality, raw_data, result):; symbols: _process_loaded_mm_data, load_mm_data，涉及 `_process_loaded_mm_data, load_mm_data`；`python/sglang/srt/multimodal/processors/internvl.py` modified +3/-3 (6 lines); hunks: -310,7 +310,7 @@ async def _process_special_format(; -423,7 +423,7 @@ async def process_qwen_mm_data_async(; symbols: _process_special_format, process_qwen_mm_data_async, process_internlm2_mm_data_async，涉及 `_process_special_format, process_qwen_mm_data_async, process_internlm2_mm_data_async`；`python/sglang/srt/multimodal/processors/minicpm.py` modified +2/-2 (4 lines); hunks: -118,7 +118,7 @@ async def _process_special_format(; -190,7 +190,7 @@ async def process_mm_data_async(; symbols: _process_special_format, process_mm_data_async，涉及 `_process_special_format, process_mm_data_async`；`python/sglang/srt/multimodal/processors/clip.py` modified +1/-1 (2 lines); hunks: -20,7 +20,7 @@ def __init__(self, hf_config, server_args, _processor, *args,...; symbols: __init__, process_mm_data_async，涉及 `__init__, process_mm_data_async`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/base_processor.py` modified +8/-7 (15 lines); hunks: -1,3 +1,4; -729,7 +730,7 @@ def _process_loaded_mm_data(self, modality, raw_data, result):; symbols: _process_loaded_mm_data, load_mm_data
  - `python/sglang/srt/multimodal/processors/internvl.py` modified +3/-3 (6 lines); hunks: -310,7 +310,7 @@ async def _process_special_format(; -423,7 +423,7 @@ async def process_qwen_mm_data_async(; symbols: _process_special_format, process_qwen_mm_data_async, process_internlm2_mm_data_async
  - `python/sglang/srt/multimodal/processors/minicpm.py` modified +2/-2 (4 lines); hunks: -118,7 +118,7 @@ async def _process_special_format(; -190,7 +190,7 @@ async def process_mm_data_async(; symbols: _process_special_format, process_mm_data_async
  - `python/sglang/srt/multimodal/processors/clip.py` modified +1/-1 (2 lines); hunks: -20,7 +20,7 @@ def __init__(self, hf_config, server_args, _processor, *args,...; symbols: __init__, process_mm_data_async
  - `python/sglang/srt/multimodal/processors/deepseek_ocr.py` modified +1/-1 (2 lines); hunks: -29,7 +29,7 @@ def __init__(self, hf_config, server_args, _processor, *args,...; symbols: __init__, process_mm_data_async
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/base_processor.py
@@ -1,3 +1,4 @@
+import asyncio
@@ -729,7 +730,7 @@ def _process_loaded_mm_data(self, modality, raw_data, result):
-    def load_mm_data(
+    async def load_mm_data(
@@ -772,7 +773,7 @@ def load_mm_data(
-            return self.legacy_load_mm_data(
diff -- python/sglang/srt/multimodal/processors/internvl.py
@@ -310,7 +310,7 @@ async def _process_special_format(
-            base_output = self.load_mm_data(
+            base_output = await self.load_mm_data(
@@ -423,7 +423,7 @@ async def process_qwen_mm_data_async(
-        base_output = self.load_mm_data(
+        base_output = await self.load_mm_data(
@@ -644,7 +644,7 @@ async def process_internlm2_mm_data_async(
diff -- python/sglang/srt/multimodal/processors/minicpm.py
@@ -118,7 +118,7 @@ async def _process_special_format(
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/base_processor.py` modified +8/-7; `python/sglang/srt/multimodal/processors/internvl.py` modified +3/-3; `python/sglang/srt/multimodal/processors/minicpm.py` modified +2/-2; `python/sglang/srt/multimodal/processors/clip.py` modified +1/-1; `python/sglang/srt/multimodal/processors/deepseek_ocr.py` modified +1/-1; `python/sglang/srt/multimodal/processors/deepseek_vl_v2.py` modified +1/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/clip.py`, `python/sglang/srt/multimodal/processors/deepseek_ocr.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #23220 - Bugfix: Qwen3-VL-MoE adapt encoder_only

- 链接: https://github.com/sgl-project/sglang/pull/23220
- 状态/时间: merged / 2026-05-22
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+1/-0，可读 patch 8 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Bugfix: Qwen3-VL-MoE adapt encoder_only」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/models/qwen3_vl_moe.py`；技术摘要: 覆盖「Bugfix: Qwen3-VL-MoE adapt encoder_only」；主要实现面是 `python/sglang/srt/models/qwen3_vl_moe.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0 (1 lines); hunks: -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Te...; symbols: load_weights，涉及 `load_weights`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0 (1 lines); hunks: -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Te...; symbols: load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl_moe.py
@@ -235,6 +235,7 @@ def load_weights(self, weights: Iterable[Tuple[str, torch.Tensor]]):
+                and hasattr(self, "model")
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl_moe.py` modified +1/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl_moe.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #24144 - [BugFix][EPD] adapt for qwen3.5-mtp & del duplicated logs

- 链接: https://github.com/sgl-project/sglang/pull/24144
- 状态/时间: merged / 2026-05-23
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+2/-1，可读 patch 24 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[BugFix][EPD] adapt for qwen3.5-mtp & del duplicated logs」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「[BugFix][EPD] adapt for qwen3.5-mtp & del duplicated logs」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +2/-1 (3 lines); hunks: -24,6 +24,7; -247,6 +248,7 @@ class QwenVLImageProcessor(SGLangBaseProcessor):; symbols: QwenVLImageProcessor, get_mm_data，涉及 `QwenVLImageProcessor, get_mm_data`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +2/-1 (3 lines); hunks: -24,6 +24,7; -247,6 +248,7 @@ class QwenVLImageProcessor(SGLangBaseProcessor):; symbols: QwenVLImageProcessor, get_mm_data
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -24,6 +24,7 @@
+from sglang.srt.models.qwen3_5_mtp import Qwen3_5ForCausalLMMTP
@@ -247,6 +248,7 @@ class QwenVLImageProcessor(SGLangBaseProcessor):
+        Qwen3_5ForCausalLMMTP,
@@ -475,7 +477,6 @@ def get_mm_data(self, prompt, embeddings, **kwargs):
-            logger.info(f"Get embedding slice for {modality}, num_tokens={num_tokens}")
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +2/-1
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #26116 - [VLM] Reuse Qwen pretokenized ids

- 链接: https://github.com/sgl-project/sglang/pull/26116
- 状态/时间: merged / 2026-05-23
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/multimodal/processors/qwen_vl.py`；关联提交 `19b60a4f9e14`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+110/-24，可读 patch 197 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Reuse Qwen pretokenized ids」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「[VLM] Reuse Qwen pretokenized ids」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +86/-24 (110 lines); hunks: -398,6 +398,42 @@ def compute_mrope_positions(self, input_ids, mm_items):; -560,6 +596,27 @@ async def process_mm_data_async(; symbols: compute_mrope_positions, _get_processor_output_value, _get_precomputed_mrope_from_output, get_mm_data，涉及 `compute_mrope_positions, _get_processor_output_value, _get_precomputed_mrope_from_output`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +86/-24 (110 lines); hunks: -398,6 +398,42 @@ def compute_mrope_positions(self, input_ids, mm_items):; -560,6 +596,27 @@ async def process_mm_data_async(; symbols: compute_mrope_positions, _get_processor_output_value, _get_precomputed_mrope_from_output, get_mm_data
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -398,6 +398,42 @@ def compute_mrope_positions(self, input_ids, mm_items):
+    # TODO: consider moving it to SGLangBaseProcessor
+    @staticmethod
+    def _get_processor_output_value(ret, key):
+        """get value with key from returned value of processor"""
+        if ret is None:
+            return None
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +86/-24
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/managers/schedule_batch.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #26100 - [VLM] adopt simplified get_rope_index for image-only requests

- 链接: https://github.com/sgl-project/sglang/pull/26100
- 状态/时间: merged / 2026-05-24
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+120/-3，可读 patch 152 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] adopt simplified get_rope_index for image-only requests」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「[VLM] adopt simplified get_rope_index for image-only requests」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +120/-3 (123 lines); hunks: -2,7 +2,7; -436,6 +436,110 @@ def _get_precomputed_mrope_from_output(self, ret):; symbols: _get_precomputed_mrope_from_output, _as_grid_batch, _compute_image_only_mrope_positions_from_offsets, get_mm_data，涉及 `_get_precomputed_mrope_from_output, _as_grid_batch, _compute_image_only_mrope_positions_from_offsets`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +120/-3 (123 lines); hunks: -2,7 +2,7; -436,6 +436,110 @@ def _get_precomputed_mrope_from_output(self, ret):; symbols: _get_precomputed_mrope_from_output, _as_grid_batch, _compute_image_only_mrope_positions_from_offsets, get_mm_data
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -2,7 +2,7 @@
-from typing import List, Union
+from typing import List, Optional, Union
@@ -436,6 +436,110 @@ def _get_precomputed_mrope_from_output(self, ret):
+    @staticmethod
+    def _as_grid_batch(value):
+        if value is None:
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +120/-3
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #26101 - [VLM] accept precomputed multimodal metadata

- 链接: https://github.com/sgl-project/sglang/pull/26101
- 状态/时间: merged / 2026-05-24
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+69/-33，可读 patch 170 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] accept precomputed multimodal metadata」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「[VLM] accept precomputed multimodal metadata」；主要实现面是 `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/base_processor.py` modified +63/-12 (75 lines); hunks: -1080,28 +1080,53 @@ def collect_mm_items_from_processor_output(; -1115,6 +1140,30 @@ def collect_mm_items_from_processor_output(; symbols: collect_mm_items_from_processor_output, _process_and_collect_mm_items, process_and_combine_mm_data，涉及 `collect_mm_items_from_processor_output, _process_and_collect_mm_items, process_and_combine_mm_data`；`python/sglang/srt/multimodal/processors/qwen_vl.py` modified +6/-21 (27 lines); hunks: -400,20 +400,13 @@ def compute_mrope_positions(self, input_ids, mm_items):; -430,9 +423,7 @@ def _get_precomputed_mrope_from_output(self, ret):; symbols: compute_mrope_positions, _get_processor_output_value, _get_precomputed_mrope_from_output, process_mm_data_async，涉及 `compute_mrope_positions, _get_processor_output_value, _get_precomputed_mrope_from_output`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/base_processor.py` modified +63/-12 (75 lines); hunks: -1080,28 +1080,53 @@ def collect_mm_items_from_processor_output(; -1115,6 +1140,30 @@ def collect_mm_items_from_processor_output(; symbols: collect_mm_items_from_processor_output, _process_and_collect_mm_items, process_and_combine_mm_data
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +6/-21 (27 lines); hunks: -400,20 +400,13 @@ def compute_mrope_positions(self, input_ids, mm_items):; -430,9 +423,7 @@ def _get_precomputed_mrope_from_output(self, ret):; symbols: compute_mrope_positions, _get_processor_output_value, _get_precomputed_mrope_from_output, process_mm_data_async
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/base_processor.py
@@ -1080,28 +1080,53 @@ def collect_mm_items_from_processor_output(
-        Create mm_items from processor output. Initially creates one item per modality;
-        these are later split into per-image/video items by get_new_expanded_mm_items.
+        Create mm_items from processor output.
-        Note that the data_dict can be passed via offline engine api
+        Initially creates one item per modality; these are later split into per-image/video items by get_new_expanded_mm_items.
+        Note that the data_dict can be hf processor output, or passed via offline engine api
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -400,20 +400,13 @@ def compute_mrope_positions(self, input_ids, mm_items):
-    # TODO: consider moving it to SGLangBaseProcessor
-        """get value with key from returned value of processor"""
-        if hasattr(ret, "get"):
-            value = ret.get(key)
-            if value is not None:
-                return value
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/base_processor.py` modified +63/-12; `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +6/-21
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/base_processor.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #26167 - [VLM] feat: replace small H2D calls with a single one for qwen-vl

- 链接: https://github.com/sgl-project/sglang/pull/26167
- 状态/时间: merged / 2026-05-24
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；关联提交 `64475965015f`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 3 个文件，+48/-44，可读 patch 187 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] feat: replace small H2D calls with a single one for qwen-vl」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「[VLM] feat: replace small H2D calls with a single one for qwen-vl」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +2/-2 (4 lines); hunks: -756,7 +756,7 @@ def forward(; -938,7 +938,7 @@ def _prepare_graph_inputs(self, x: torch.Tensor, grid_thw: t...; symbols: forward, _prepare_graph_inputs，涉及 `forward, _prepare_graph_inputs`；`python/sglang/srt/multimodal/processors/qwen_vl.py` modified +0/-2 (2 lines); hunks: -293,7 +293,6 @@ def build_input_ids_with_timestamps(; -312,7 +311,6 @@ def build_input_ids_with_timestamps(; symbols: build_input_ids_with_timestamps，涉及 `build_input_ids_with_timestamps`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +2/-2 (4 lines); hunks: -756,7 +756,7 @@ def forward(; -938,7 +938,7 @@ def _prepare_graph_inputs(self, x: torch.Tensor, grid_thw: t...; symbols: forward, _prepare_graph_inputs
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +0/-2 (2 lines); hunks: -293,7 +293,6 @@ def build_input_ids_with_timestamps(; -312,7 +311,6 @@ def build_input_ids_with_timestamps(; symbols: build_input_ids_with_timestamps
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -756,7 +756,7 @@ def forward(
-        x = x.to(device=self.device, dtype=self.dtype)
+        x = x.to(device=self.device, dtype=self.dtype, non_blocking=True)
@@ -938,7 +938,7 @@ def _prepare_graph_inputs(self, x: torch.Tensor, grid_thw: torch.Tensor) -> tupl
-        x = x.to(device=self.device, dtype=self.dtype)
+        x = x.to(device=self.device, dtype=self.dtype, non_blocking=True)
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -293,7 +293,6 @@ def build_input_ids_with_timestamps(
-        audio_token_id = getattr(self, "audio_token_id", None)
@@ -312,7 +311,6 @@ def build_input_ids_with_timestamps(
-        model_type = getattr(self, "model_type", None)
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +2/-2; `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +0/-2
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/managers/mm_utils.py`, `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #23469 - [NPU] adapt the Qwen3-ASR model for deployment on NPU

- 链接: https://github.com/sgl-project/sglang/pull/23469
- 状态/时间: closed / 2026-05-24
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+18/-0，可读 patch 25 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[NPU] adapt the Qwen3-ASR model for deployment on NPU」；模型线: Qwen VLM/Omni/ASR；类别: 模型实现调整；主要 diff: `python/sglang/srt/utils/common.py`；技术摘要: 覆盖「[NPU] adapt the Qwen3-ASR model for deployment on NPU」；主要实现面是 `python/sglang/srt/utils/common.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/utils/common.py` modified +18/-0 (18 lines); hunks: -740,6 +740,24 @@ def load_audio(; symbols: load_audio，涉及 `load_audio`。
- 代码 diff 细节:
  - `python/sglang/srt/utils/common.py` modified +18/-0 (18 lines); hunks: -740,6 +740,24 @@ def load_audio(; symbols: load_audio
- 关键代码摘录:

```diff
diff -- python/sglang/srt/utils/common.py
@@ -740,6 +740,24 @@ def load_audio(
+    if is_npu():
+        import soundfile as sf
+        if isinstance(source, bytes):
+            audio, original_sr = sf.read(BytesIO(source))
+        else:
+            audio, original_sr = sf.read(source)
```

- 已读文件:
  - runtime: `python/sglang/srt/utils/common.py` modified +18/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/utils/common.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #26094 - [VLM] fix: fix only the grids from last split mm item is collected for qwen-vl

- 链接: https://github.com/sgl-project/sglang/pull/26094
- 状态/时间: merged / 2026-05-25
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/multimodal/processors/qwen_vl.py`；关联提交 `72c1582d4ef4`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+47/-19，可读 patch 102 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] fix: fix only the grids from last split mm item is collected for qwen-vl」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `python/sglang/srt/multimodal/processors/qwen_vl.py`；技术摘要: 覆盖「[VLM] fix: fix only the grids from last split mm item is collected for qwen-vl」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +47/-19 (66 lines); hunks: -374,13 +374,12 @@ def build_input_ids_with_timestamps(; -529,6 +528,32 @@ def _compute_image_only_mrope_positions_from_offsets(; symbols: build_input_ids_with_timestamps, compute_mrope_positions, _compute_image_only_mrope_positions_from_offsets, _concat_mm_item_grid，涉及 `build_input_ids_with_timestamps, compute_mrope_positions, _compute_image_only_mrope_positions_from_offsets`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +47/-19 (66 lines); hunks: -374,13 +374,12 @@ def build_input_ids_with_timestamps(; -529,6 +528,32 @@ def _compute_image_only_mrope_positions_from_offsets(; symbols: build_input_ids_with_timestamps, compute_mrope_positions, _compute_image_only_mrope_positions_from_offsets, _concat_mm_item_grid
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -374,13 +374,12 @@ def build_input_ids_with_timestamps(
-        image_grid_thw = None
-        video_grid_thw = None
-        for item in mm_items:
-            if "image_grid_thw" in item.model_specific_data:
-                image_grid_thw = item.model_specific_data["image_grid_thw"]
-            if "video_grid_thw" in item.model_specific_data:
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +47/-19
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/multimodal/processors/qwen_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #19242 - [feat] feat: add Qwen3-ASR support like whisper

- 链接: https://github.com/sgl-project/sglang/pull/19242
- 状态/时间: closed / 2026-05-25
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 5 个文件，+475/-0，可读 patch 519 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[feat] feat: add Qwen3-ASR support like whisper」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/multimodal/processors/qwen3_asr.py`, `python/sglang/srt/configs/qwen3_asr.py`, `python/sglang/srt/configs/__init__.py`；技术摘要: 覆盖「[feat] feat: add Qwen3-ASR support like whisper」；主要实现面是 `python/sglang/srt/multimodal/processors/qwen3_asr.py`, `python/sglang/srt/configs/qwen3_asr.py`, `python/sglang/srt/configs/__init__.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/multimodal/processors/qwen3_asr.py` added +252/-0 (252 lines); hunks: -0,0 +1,252; symbols: Qwen3ASRMultimodalProcessor, __init__, _get_feature_extractor, _compute_audio_output_length，涉及 `Qwen3ASRMultimodalProcessor, __init__, _get_feature_extractor`；`python/sglang/srt/configs/qwen3_asr.py` added +217/-0 (217 lines); hunks: -0,0 +1,217; symbols: Qwen3ASRHFProcessor, __init__, from_pretrained, Qwen3ASRAudioEncoderConfig，涉及 `Qwen3ASRHFProcessor, __init__, from_pretrained`；`python/sglang/srt/configs/__init__.py` modified +2/-0 (2 lines); hunks: -22,6 +22,7; -47,6 +48,7；`python/sglang/srt/configs/model_config.py` modified +2/-0 (2 lines); hunks: -1259,6 +1259,7 @@ def is_generation_model(model_architectures: List[str], is...; -1299,6 +1300,7 @@ def is_image_gen_model(model_architectures: List[str]):; symbols: is_generation_model, is_image_gen_model, is_audio_model，涉及 `is_generation_model, is_image_gen_model, is_audio_model`。
- 代码 diff 细节:
  - `python/sglang/srt/multimodal/processors/qwen3_asr.py` added +252/-0 (252 lines); hunks: -0,0 +1,252; symbols: Qwen3ASRMultimodalProcessor, __init__, _get_feature_extractor, _compute_audio_output_length
  - `python/sglang/srt/configs/qwen3_asr.py` added +217/-0 (217 lines); hunks: -0,0 +1,217; symbols: Qwen3ASRHFProcessor, __init__, from_pretrained, Qwen3ASRAudioEncoderConfig
  - `python/sglang/srt/configs/__init__.py` modified +2/-0 (2 lines); hunks: -22,6 +22,7; -47,6 +48,7
  - `python/sglang/srt/configs/model_config.py` modified +2/-0 (2 lines); hunks: -1259,6 +1259,7 @@ def is_generation_model(model_architectures: List[str], is...; -1299,6 +1300,7 @@ def is_image_gen_model(model_architectures: List[str]):; symbols: is_generation_model, is_image_gen_model, is_audio_model
  - `python/sglang/srt/utils/hf_transformers_utils.py` modified +2/-0 (2 lines); hunks: -64,6 +64,7; -104,6 +105,7
- 关键代码摘录:

```diff
diff -- python/sglang/srt/multimodal/processors/qwen3_asr.py
@@ -0,0 +1,252 @@
+import logging
+import re
+from typing import Any, Dict, List, Optional
+import torch
+from sglang.srt.managers.schedule_batch import Modality, MultimodalDataItem
+from sglang.srt.models.qwen3_asr import (
diff -- python/sglang/srt/configs/qwen3_asr.py
@@ -0,0 +1,217 @@
+"""
+Copy from [configuration_qwen3_asr.py](https://github.com/QwenLM/Qwen3-ASR/blob/main/qwen_asr/core/transformers_backend/configuration_qwen3_asr.py)
+and add some typing.
++ Qwen3ASRAudioEncoderConfig
++ Qwen3ASRConfig
++ Qwen3ASRTextConfig
diff -- python/sglang/srt/configs/__init__.py
@@ -22,6 +22,7 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/multimodal/processors/qwen3_asr.py` added +252/-0; `python/sglang/srt/configs/qwen3_asr.py` added +217/-0; `python/sglang/srt/configs/__init__.py` modified +2/-0; `python/sglang/srt/configs/model_config.py` modified +2/-0; `python/sglang/srt/utils/hf_transformers_utils.py` modified +2/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/configs/__init__.py`, `python/sglang/srt/configs/model_config.py`, `python/sglang/srt/configs/qwen3_asr.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #12662 - [CPU] Add support for Qwen3-vl and Qwen3-omni

- 链接: https://github.com/sgl-project/sglang/pull/12662
- 状态/时间: merged / 2026-05-27
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`；关联提交 `87c3171aaa55`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 8 个文件，+250/-35，可读 patch 545 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[CPU] Add support for Qwen3-vl and Qwen3-omni」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[CPU] Add support for Qwen3-vl and Qwen3-omni」；主要实现面是 `python/sglang/srt/models/qwen3_omni_moe.py`, `python/sglang/srt/multimodal/processors/qwen_vl.py`, `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_omni_moe.py` modified +62/-13 (75 lines); hunks: -31,8 +31,15; -43,7 +50,26; symbols: get_head_dim_and_projection_size, Qwen3OmniMoeAudioEncoderLayer, __init__, _get_feat_extract_output_lengths，涉及 `get_head_dim_and_projection_size, Qwen3OmniMoeAudioEncoderLayer, __init__`；`python/sglang/srt/multimodal/processors/qwen_vl.py` modified +18/-0 (18 lines); hunks: -34,6 +34,7; -59,6 +60,23; symbols: smart_resize，涉及 `smart_resize`；`python/sglang/srt/models/qwen3_vl.py` modified +7/-2 (9 lines); hunks: -348,8 +348,13 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_omni_moe.py` modified +62/-13 (75 lines); hunks: -31,8 +31,15; -43,7 +50,26; symbols: get_head_dim_and_projection_size, Qwen3OmniMoeAudioEncoderLayer, __init__, _get_feat_extract_output_lengths
  - `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +18/-0 (18 lines); hunks: -34,6 +34,7; -59,6 +60,23; symbols: smart_resize
  - `python/sglang/srt/models/qwen3_vl.py` modified +7/-2 (9 lines); hunks: -348,8 +348,13 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_omni_moe.py
@@ -31,8 +31,15 @@
+from sglang.srt.distributed import (
+    get_tensor_model_parallel_world_size,
+)
-from sglang.srt.layers.linear import ColumnParallelLinear, RowParallelLinear
+from sglang.srt.layers.linear import (
+    ColumnParallelLinear,
diff -- python/sglang/srt/multimodal/processors/qwen_vl.py
@@ -34,6 +34,7 @@
+from sglang.srt.utils import cpu_has_amx_support, is_cpu
@@ -59,6 +60,23 @@
+_is_cpu_amx_available = cpu_has_amx_support()
+_is_cpu = is_cpu()
+if _is_cpu and _is_cpu_amx_available:
+    try:
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -348,8 +348,13 @@ def __init__(
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_omni_moe.py` modified +62/-13; `python/sglang/srt/multimodal/processors/qwen_vl.py` modified +18/-0; `python/sglang/srt/models/qwen3_vl.py` modified +7/-2
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/layers/amx_utils.py`, `python/sglang/srt/layers/attention/vision.py`, `python/sglang/srt/layers/conv.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #22848 - [Feature] WebSocket streaming audio input for ASR

- 链接: https://github.com/sgl-project/sglang/pull/22848
- 状态/时间: merged / 2026-05-27
- 反查来源: `git log --name-only -- <model-files>` 反查到 `test/manual/models/test_qwen3_asr.py`；关联提交 `a95b4e2e09eb`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 11 个文件，+1707/-49，可读 patch 1980 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Feature] WebSocket streaming audio input for ASR」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `test/manual/models/test_qwen3_asr.py`；技术摘要: 覆盖「[Feature] WebSocket streaming audio input for ASR」；主要实现面是 `test/manual/models/test_qwen3_asr.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `test/manual/models/test_qwen3_asr.py` modified +547/-3 (550 lines); hunks: -1,17 +1,31; -29,8 +43,83; symbols: _normalize_for_wer, _wer, download_audio, _pcm16_from_audio_bytes，涉及 `_normalize_for_wer, _wer, download_audio`。
- 代码 diff 细节:
  - `test/manual/models/test_qwen3_asr.py` modified +547/-3 (550 lines); hunks: -1,17 +1,31; -29,8 +43,83; symbols: _normalize_for_wer, _wer, download_audio, _pcm16_from_audio_bytes
- 关键代码摘录:

```diff
diff -- test/manual/models/test_qwen3_asr.py
@@ -1,17 +1,31 @@
-Tests /v1/audio/transcriptions endpoint (OpenAI-compatible).
+Tests /v1/audio/transcriptions (HTTP) and /v1/realtime (OpenAI Realtime
+transcription WebSocket).
+import asyncio
+import base64
+import json
```

- 已读文件:
  - tests: `test/manual/models/test_qwen3_asr.py` modified +547/-3
- 验证与风险: diff 自带测试面 `test/manual/models/test_qwen3_asr.py`, `test/registered/unit/entrypoints/openai/test_serving_transcription.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #25813 - docs(cookbook): port popular model usage guides into cookbook pages

- 链接: https://github.com/sgl-project/sglang/pull/25813
- 状态/时间: merged / 2026-06-02
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 47 个文件，+1262/-2154，可读 patch 4187 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「docs(cookbook): port popular model usage guides into cookbook pages」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `docs_new/docs/basic_usage/deepseek_v32.mdx`, `docs_new/docs/basic_usage/deepseek_v3.mdx`, `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V3_2.mdx`；技术摘要: 覆盖「docs(cookbook): port popular model usage guides into cookbook pages」；主要实现面是 `docs_new/docs/basic_usage/deepseek_v32.mdx`, `docs_new/docs/basic_usage/deepseek_v3.mdx`, `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V3_2.mdx`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs_new/docs/basic_usage/deepseek_v32.mdx` removed +0/-601 (601 lines); hunks: -1,601 +0,0；`docs_new/docs/basic_usage/deepseek_v3.mdx` removed +0/-375 (375 lines); hunks: -1,375 +0,0；`docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V3_2.mdx` modified +244/-3 (247 lines); hunks: -24,6 +24,27 @@ SGLang offers multiple installation methods. You can choose t...; -37,7 +58,18 @@ import { DeepSeekV32Deployment } from "/src/snippets/autoregr...；`docs_new/cookbook/autoregressive/GLM/GLM-4.6V.mdx` modified +156/-26 (182 lines); hunks: -10,7 +10,7 @@ GLM-4.6V series model includes two versions: GLM-4.6V (106B),...; -70,14 +70,56 @@ import { GLM46VDeployment } from "/src/snippets/autoregressi...; symbols: image_to_base64，涉及 `image_to_base64`。
- 代码 diff 细节:
  - `docs_new/docs/basic_usage/deepseek_v32.mdx` removed +0/-601 (601 lines); hunks: -1,601 +0,0
  - `docs_new/docs/basic_usage/deepseek_v3.mdx` removed +0/-375 (375 lines); hunks: -1,375 +0,0
  - `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V3_2.mdx` modified +244/-3 (247 lines); hunks: -24,6 +24,27 @@ SGLang offers multiple installation methods. You can choose t...; -37,7 +58,18 @@ import { DeepSeekV32Deployment } from "/src/snippets/autoregr...
  - `docs_new/cookbook/autoregressive/GLM/GLM-4.6V.mdx` modified +156/-26 (182 lines); hunks: -10,7 +10,7 @@ GLM-4.6V series model includes two versions: GLM-4.6V (106B),...; -70,14 +70,56 @@ import { GLM46VDeployment } from "/src/snippets/autoregressi...; symbols: image_to_base64
  - `docs_new/docs/basic_usage/gpt_oss.mdx` removed +0/-181 (181 lines); hunks: -1,181 +0,0
- 关键代码摘录:

```diff
diff -- docs_new/docs/basic_usage/deepseek_v32.mdx
@@ -1,601 +0,0 @@
-title: "DeepSeek V3.2/GLM-5 Usage"
-metatags:
-    description: "Deploy DeepSeek V3.2/GLM-5 with SGLang: DeepSeek Sparse Attention (DSA), long-context optimization, MTP speculative decoding, function calling. Supports H200, B2
-DeepSeek-V3.2 model family equips DeepSeek-V3.1-Terminus with DeepSeek Sparse Attention (DSA) through continued training. With DSA, a fine-grained sparse attention mechanism power
-Note: This document is originally written for the usage of [DeepSeek-V3.2-Exp](https://huggingface.co/deepseek-ai/DeepSeek-V3.2-Exp) model. The usage of [DeepSeek-V3.2](https://hu
-## Installation
diff -- docs_new/docs/basic_usage/deepseek_v3.mdx
@@ -1,375 +0,0 @@
-title: "DeepSeek V3/V3.1/R1 Usage"
-metatags:
-    description: "Deploy DeepSeek V3/R1 with SGLang: MLA optimization, FP8 quantization, multi-node TP, DP attention, MTP speculative decoding. Supports H200, B200, MI300X, A100."
-SGLang provides many optimizations specifically designed for the DeepSeek models, making it the inference engine recommended by the official [DeepSeek team](https://github.com/dee
-This document outlines current optimizations for DeepSeek.
-For an overview of the implemented features see the completed [Roadmap](https://github.com/sgl-project/sglang/issues/2591).
diff -- docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V3_2.mdx
@@ -24,6 +24,27 @@ SGLang offers multiple installation methods. You can choose the most suitable in
```

- 已读文件:
  - docs: `docs_new/docs/basic_usage/deepseek_v32.mdx` removed +0/-601; `docs_new/docs/basic_usage/deepseek_v3.mdx` removed +0/-375; `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V3_2.mdx` modified +244/-3; `docs_new/cookbook/autoregressive/GLM/GLM-4.6V.mdx` modified +156/-26; `docs_new/docs/basic_usage/gpt_oss.mdx` removed +0/-181; `docs_new/docs/basic_usage/glmv.mdx` removed +0/-139
- 验证与风险: 该 PR 主要落在文档/示例 `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-OCR-2.mdx`, `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-OCR.mdx`, `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-R1.mdx`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

### PR #25198 - [Docs] Update Nemotron3-Nano-Omni cookbook to reflect new model paths

- 链接: https://github.com/sgl-project/sglang/pull/25198
- 状态/时间: merged / 2026-06-03
- 反查来源: `git log --name-only -- <model-files>` 反查到 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx`；关联提交 `8980eb82de90`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+25/-28，可读 patch 194 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Docs] Update Nemotron3-Nano-Omni cookbook to reflect new model paths」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx`；技术摘要: 覆盖「[Docs] Update Nemotron3-Nano-Omni cookbook to reflect new model paths」；主要实现面是 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +20/-21 (41 lines); hunks: -30,10 +30,9 @@ Architecture and key features:; -76,7 +75,7 @@ This section provides a progressive guide from quick deploymen...；`docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` modified +5/-7 (12 lines); hunks: -1,18 +1,16; -77,7 +75,7 @@ export const Nemotron3NanoOmniDeployment = () => {。
- 代码 diff 细节:
  - `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +20/-21 (41 lines); hunks: -30,10 +30,9 @@ Architecture and key features:; -76,7 +75,7 @@ This section provides a progressive guide from quick deploymen...
  - `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` modified +5/-7 (12 lines); hunks: -1,18 +1,16; -77,7 +75,7 @@ export const Nemotron3NanoOmniDeployment = () => {
- 关键代码摘录:

```diff
diff -- docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx
@@ -30,10 +30,9 @@ Architecture and key features:
-- [`nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning`](https://huggingface.co/nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning)
-- [`nvidia/Nemotron-3-Nano-Omni-30B-A3B-BF16`](https://huggingface.co/nvidia/Nemotron-3-Nano-Omni-30B-A3B-BF16)
-- [`nvidia/Nemotron-3-Nano-Omni-30B-A3B-FP8`](https://huggingface.co/nvidia/Nemotron-3-Nano-Omni-30B-A3B-FP8)
-- [`nvidia/Nemotron-3-Nano-Omni-30B-A3B-NVFP4`](https://huggingface.co/nvidia/Nemotron-3-Nano-Omni-30B-A3B-NVFP4)
+- [`nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning-BF16`](https://huggingface.co/nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning-BF16)
+- [`nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning-FP8`](https://huggingface.co/nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning-FP8)
diff -- docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx
@@ -1,18 +1,16 @@
-    reasoning: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning',
-    bf16: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-BF16',
-    fp8: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-FP8',
-    nvfp4: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-NVFP4',
+    bf16: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning-BF16',
+    fp8: 'nvidia/Nemotron-3-Nano-Omni-30B-A3B-Reasoning-FP8',
```

- 已读文件:
  - docs: `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +20/-21; `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx` modified +5/-7
- 验证与风险: 该 PR 主要落在文档/示例 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/src/snippets/autoregressive/nemotron3-nano-omni-deployment.jsx`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

### PR #27240 - [Docs] re-organize nemotron cookbook

- 链接: https://github.com/sgl-project/sglang/pull/27240
- 状态/时间: merged / 2026-06-04
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 4 个文件，+4/-7，可读 patch 40 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Docs] re-organize nemotron cookbook」；模型线: Qwen VLM/Omni/ASR；类别: 文档/测试/CI；主要 diff: `docs_new/docs.json`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Ultra.mdx`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；技术摘要: 覆盖「[Docs] re-organize nemotron cookbook」；主要实现面是 `docs_new/docs.json`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Ultra.mdx`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs_new/docs.json` modified +2/-2 (4 lines); hunks: -1005,10 +1005,10；`docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Ultra.mdx` modified +1/-2 (3 lines); hunks: -1,7 +1,6；`docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +0/-2 (2 lines); hunks: -2,8 +2,6；`docs_new/cookbook/autoregressive/intro.mdx` modified +1/-1 (2 lines); hunks: -58,7 +58,7 @@ metatags:。
- 代码 diff 细节:
  - `docs_new/docs.json` modified +2/-2 (4 lines); hunks: -1005,10 +1005,10
  - `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Ultra.mdx` modified +1/-2 (3 lines); hunks: -1,7 +1,6
  - `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +0/-2 (2 lines); hunks: -2,8 +2,6
  - `docs_new/cookbook/autoregressive/intro.mdx` modified +1/-1 (2 lines); hunks: -58,7 +58,7 @@ metatags:
- 关键代码摘录:

```diff
diff -- docs_new/docs.json
@@ -1005,10 +1005,10 @@
+                      "cookbook/autoregressive/NVIDIA/Nemotron3-Ultra",
-                      "cookbook/autoregressive/NVIDIA/Nemotron3-Super",
-                      "cookbook/autoregressive/NVIDIA/Nemotron3-Ultra"
+                      "cookbook/autoregressive/NVIDIA/Nemotron3-Super"
diff -- docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Ultra.mdx
@@ -1,7 +1,6 @@
-metatags:
-    description: "Deploy NVIDIA Nemotron3-Ultra with SGLang - 550B hybrid MoE model (55B active) with 1M context window, BF16/NVFP4 support, built for long-running autonomous agen
+description: "Deploy NVIDIA Nemotron3-Ultra with SGLang - 550B hybrid MoE model (55B active) with 1M context window, BF16/NVFP4 support, built for long-running autonomous agents."
diff -- docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx
@@ -2,8 +2,6 @@
-tag:
-    NEW
diff -- docs_new/cookbook/autoregressive/intro.mdx
@@ -58,7 +58,7 @@ metatags:
-    href="/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni"
```

- 已读文件:
  - docs: `docs_new/docs.json` modified +2/-2; `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Ultra.mdx` modified +1/-2; `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +0/-2; `docs_new/cookbook/autoregressive/intro.mdx` modified +1/-1
- 验证与风险: 该 PR 主要落在文档/示例 `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Ultra.mdx`, `docs_new/cookbook/autoregressive/intro.mdx`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

### PR #13918 - [VLM] support qwen3-vl eagle infer

- 链接: https://github.com/sgl-project/sglang/pull/13918
- 状态/时间: closed / 2026-06-11
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 2 个文件，+30/-3，可读 patch 63 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] support qwen3-vl eagle infer」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/llama_eagle3.py`；技术摘要: 覆盖「[VLM] support qwen3-vl eagle infer」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`, `python/sglang/srt/models/llama_eagle3.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +23/-1 (24 lines); hunks: -624,6 +624,9 @@ def __init__(; -711,9 +714,13 @@ def forward(; symbols: __init__, separate_deepstack_embeds, forward, load_weights，涉及 `__init__, separate_deepstack_embeds, forward`；`python/sglang/srt/models/llama_eagle3.py` modified +7/-2 (9 lines); hunks: -116,9 +116,14 @@ def __init__(; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +23/-1 (24 lines); hunks: -624,6 +624,9 @@ def __init__(; -711,9 +714,13 @@ def forward(; symbols: __init__, separate_deepstack_embeds, forward, load_weights
  - `python/sglang/srt/models/llama_eagle3.py` modified +7/-2 (9 lines); hunks: -116,9 +116,14 @@ def __init__(; symbols: __init__
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -624,6 +624,9 @@ def __init__(
+        # For EAGLE3 support
+        self.capture_aux_hidden_states = False
@@ -711,9 +714,13 @@ def forward(
+        aux_hidden_states = None
+        if self.capture_aux_hidden_states:
+            hidden_states, aux_hidden_states = hidden_states
diff -- python/sglang/srt/models/llama_eagle3.py
@@ -116,9 +116,14 @@ def __init__(
-        # fix rope_scaling for qwen2.5-vl
+        # fix rope_scaling for qwen2.5-vl/qwen3-vl
-            config.rope_scaling["rope_type"] = "default"
+            rope_scaling = config.rope_scaling
+            self.mrope_interleaved = rope_scaling.setdefault("mrope_interleaved", False)
+            if not self.mrope_interleaved:
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +23/-1; `python/sglang/srt/models/llama_eagle3.py` modified +7/-2
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/llama_eagle3.py`, `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #17276 - Add Qwen3VL Eagle3 Inference Support

- 链接: https://github.com/sgl-project/sglang/pull/17276
- 状态/时间: closed / 2026-06-11
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 1 个文件，+35/-0，可读 patch 62 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Add Qwen3VL Eagle3 Inference Support」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「Add Qwen3VL Eagle3 Inference Support」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +35/-0 (35 lines); hunks: -733,6 +733,9 @@ def __init__(; -920,13 +923,18 @@ def forward(; symbols: __init__, separate_deepstack_embeds, forward, load_weights，涉及 `__init__, separate_deepstack_embeds, forward`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +35/-0 (35 lines); hunks: -733,6 +733,9 @@ def __init__(; -920,13 +923,18 @@ def forward(; symbols: __init__, separate_deepstack_embeds, forward, load_weights
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -733,6 +733,9 @@ def __init__(
+        # For EAGLE3 support
+        self.capture_aux_hidden_states = False
@@ -920,13 +923,18 @@ def forward(
+        aux_hidden_states = None
+        if self.capture_aux_hidden_states:
+            hidden_states, aux_hidden_states = hidden_states
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +35/-0
- 验证与风险: runtime 路径改动集中在 `python/sglang/srt/models/qwen3_vl.py`；风险点是权重加载、并行切分、attention/MoE 后端和 parser 输出，需要至少做一次真实 checkpoint 或等价 mock smoke。

### PR #28567 - Add get_parallel(): a structured accessor for parallel-topology state

- 链接: https://github.com/sgl-project/sglang/pull/28567
- 状态/时间: merged / 2026-06-18
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 184 个文件，+1865/-1727，可读 patch 8932 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「Add get_parallel(): a structured accessor for parallel-topology state」；模型线: Qwen VLM/Omni/ASR；类别: 模型支持/运行时入口；主要 diff: `python/sglang/srt/models/apertus.py`, `python/sglang/srt/models/solar.py`, `python/sglang/srt/models/gpt_oss.py`；技术摘要: 覆盖「Add get_parallel(): a structured accessor for parallel-topology state」；主要实现面是 `python/sglang/srt/models/apertus.py`, `python/sglang/srt/models/solar.py`, `python/sglang/srt/models/gpt_oss.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/apertus.py` modified +686/-687 (1373 lines); hunks: -1,687 +1,686; symbols: ApertusMLP, __init__, forward, ApertusAttention，涉及 `ApertusMLP, __init__, forward`；`python/sglang/srt/models/solar.py` modified +28/-27 (55 lines); hunks: -1,37 +1,14; -54,6 +31,30; symbols: __init__, forward, load_kv_cache_scales，涉及 `__init__, forward, load_kv_cache_scales`；`python/sglang/srt/models/gpt_oss.py` modified +17/-24 (41 lines); hunks: -28,21 +28,13; -76,6 +68,7; symbols: _resolve_moe_input_pad_multiple, __init__，涉及 `_resolve_moe_input_pad_multiple, __init__`；`python/sglang/srt/models/deepseek_v2.py` modified +14/-23 (37 lines); hunks: -47,9 +47,7; -72,12 +70,6; symbols: __init__，涉及 `__init__`。
- 代码 diff 细节:
  - `python/sglang/srt/models/apertus.py` modified +686/-687 (1373 lines); hunks: -1,687 +1,686; symbols: ApertusMLP, __init__, forward, ApertusAttention
  - `python/sglang/srt/models/solar.py` modified +28/-27 (55 lines); hunks: -1,37 +1,14; -54,6 +31,30; symbols: __init__, forward, load_kv_cache_scales
  - `python/sglang/srt/models/gpt_oss.py` modified +17/-24 (41 lines); hunks: -28,21 +28,13; -76,6 +68,7; symbols: _resolve_moe_input_pad_multiple, __init__
  - `python/sglang/srt/models/deepseek_v2.py` modified +14/-23 (37 lines); hunks: -47,9 +47,7; -72,12 +70,6; symbols: __init__
  - `python/sglang/srt/layers/communicator.py` modified +13/-19 (32 lines); hunks: -23,8 +23,6; -44,12 +42,7; symbols: apply_aiter_all_reduce_fusion, init_context, should_fuse_mlp_allreduce_with_next_layer, is_same_group_size
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/apertus.py
@@ -1,687 +1,686 @@
-# SPDX-License-Identifier: Apache-2.0
-# SPDX-FileCopyrightText: Copyright contributors to the vLLM project
-# Copyright 2025 The SwissAI Initiative
-# Copyright 2023-2024 SGLang Team
-# Licensed under the Apache License, Version 2.0 (the "License");
-# you may not use this file except in compliance with the License.
diff -- python/sglang/srt/models/solar.py
@@ -1,37 +1,14 @@
-# Adapted from
-# https://github.com/huggingface/transformers/blob/v4.28.0/src/transformers/models/llama/modeling_llama.py
-# Copyright 2023 The vLLM team.
-# Copyright 2022 EleutherAI and the HuggingFace Inc. team. All rights reserved.
-#
-# This code is based on EleutherAI's GPT-NeoX library and the GPT-NeoX
diff -- python/sglang/srt/models/gpt_oss.py
@@ -28,21 +28,13 @@
```

- 已读文件:
  - runtime: `python/sglang/srt/models/apertus.py` modified +686/-687; `python/sglang/srt/models/solar.py` modified +28/-27; `python/sglang/srt/models/gpt_oss.py` modified +17/-24; `python/sglang/srt/models/deepseek_v2.py` modified +14/-23; `python/sglang/srt/layers/communicator.py` modified +13/-19; `python/sglang/srt/models/qwen3_moe.py` modified +12/-18
- 验证与风险: diff 自带测试面 `python/sglang/test/kits/attention_unittest/attention_methods/dense_attention.py`, `python/sglang/test/kits/attention_unittest/attention_methods/dsa_attention.py`, `python/sglang/test/kits/attention_unittest/attention_methods/dsv4_attention.py`, `python/sglang/test/kits/attention_unittest/attention_methods/dual_chunk_attention.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #28940 - [VLM] Qwen3-VL / Moss-VL ViT preprocessing optimizations

- 链接: https://github.com/sgl-project/sglang/pull/28940
- 状态/时间: merged / 2026-06-24
- 反查来源: `git log --name-only -- <model-files>` 反查到 `python/sglang/srt/models/qwen3_vl.py`；关联提交 `0df796473b76`；保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 6 个文件，+476/-10，可读 patch 558 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[VLM] Qwen3-VL / Moss-VL ViT preprocessing optimizations」；模型线: Qwen VLM/Omni/ASR；类别: 性能/后端优化；主要 diff: `python/sglang/srt/models/qwen3_vl.py`；技术摘要: 覆盖「[VLM] Qwen3-VL / Moss-VL ViT preprocessing optimizations」；主要实现面是 `python/sglang/srt/models/qwen3_vl.py`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `python/sglang/srt/models/qwen3_vl.py` modified +141/-2 (143 lines); hunks: -94,6 +94,10; -597,6 +601,131 @@ def fast_pos_embed_interpolate_from_list(self, grid_thw):; symbols: Qwen3_VisionMLP, fast_pos_embed_interpolate_from_list, _use_vectorized_pos_embed, fast_pos_embed_interpolate_vectorized，涉及 `Qwen3_VisionMLP, fast_pos_embed_interpolate_from_list, _use_vectorized_pos_embed`。
- 代码 diff 细节:
  - `python/sglang/srt/models/qwen3_vl.py` modified +141/-2 (143 lines); hunks: -94,6 +94,10; -597,6 +601,131 @@ def fast_pos_embed_interpolate_from_list(self, grid_thw):; symbols: Qwen3_VisionMLP, fast_pos_embed_interpolate_from_list, _use_vectorized_pos_embed, fast_pos_embed_interpolate_vectorized
- 关键代码摘录:

```diff
diff -- python/sglang/srt/models/qwen3_vl.py
@@ -94,6 +94,10 @@
+# Below this image count the per-image loop beats the vectorized path (which has a
+# fixed setup cost; measured crossover ~6 on H20); both give the same result.
+_VECTORIZED_VL_POS_EMBED_MIN_IMAGES = 6
@@ -597,6 +601,131 @@ def fast_pos_embed_interpolate_from_list(self, grid_thw):
+    def _use_vectorized_pos_embed(self, num_images: int) -> bool:
+        """Use the vectorized path only past a few images.
```

- 已读文件:
  - runtime: `python/sglang/srt/models/qwen3_vl.py` modified +141/-2
- 验证与风险: diff 自带测试面 `test/registered/models/test_vit_pos_embed_interpolate.py`, `test/registered/unit/multimodal/test_base_processor_image_decode.py`；如果继续改同一模型，优先复跑这些测试并补一个最小 launch/accuracy smoke。

### PR #29261 - [Docs] Fix broken links in cookbook

- 链接: https://github.com/sgl-project/sglang/pull/29261
- 状态/时间: merged / 2026-06-25
- 反查来源: 保留自原 history/skill 显式引用
- 代码 diff 已读范围: GitHub Pull Request files API 返回 3 个文件，+3/-3，可读 patch 27 行；本卡优先审计模型相关文件和高变更量文件。
- 动机: 标题「[Docs] Fix broken links in cookbook」；模型线: Qwen VLM/Omni/ASR；类别: 缺陷修复；主要 diff: `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V4.mdx`, `docs_new/cookbook/autoregressive/GLM/GLM-4.7.mdx`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；技术摘要: 覆盖「[Docs] Fix broken links in cookbook」；主要实现面是 `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V4.mdx`, `docs_new/cookbook/autoregressive/GLM/GLM-4.7.mdx`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`。下方保留文件级证据、代码摘录和验证风险。
- 实现要点: `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V4.mdx` modified +1/-1 (2 lines); hunks: -89,7 +89,7 @@ import { benchmarks } from "/src/snippets/configs/deepseek-ai/...；`docs_new/cookbook/autoregressive/GLM/GLM-4.7.mdx` modified +1/-1 (2 lines); hunks: -127,7 +127,7 @@ Pick a weight format by hardware: **NVFP4** on NVIDIA Blackw...；`docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +1/-1 (2 lines); hunks: -52,7 +52,7 @@ uv pip install 'git+https://github.com/sgl-project/sglang.git#...。
- 代码 diff 细节:
  - `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V4.mdx` modified +1/-1 (2 lines); hunks: -89,7 +89,7 @@ import { benchmarks } from "/src/snippets/configs/deepseek-ai/...
  - `docs_new/cookbook/autoregressive/GLM/GLM-4.7.mdx` modified +1/-1 (2 lines); hunks: -127,7 +127,7 @@ Pick a weight format by hardware: **NVFP4** on NVIDIA Blackw...
  - `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +1/-1 (2 lines); hunks: -52,7 +52,7 @@ uv pip install 'git+https://github.com/sgl-project/sglang.git#...
- 关键代码摘录:

```diff
diff -- docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V4.mdx
@@ -89,7 +89,7 @@ import { benchmarks } from "/src/snippets/configs/deepseek-ai/deepseek-v4-benchm
-  For a runnable end-to-end example, see the [DeepSeek-V4-Flash demo notebook](/demo/deepseek_v4_flash).
+  For a runnable end-to-end example, see the [DeepSeek-V4-Flash demo notebook](https://github.com/sgl-project/sglang/blob/main/docs_new/demo/deepseek_v4_flash.ipynb).
diff -- docs_new/cookbook/autoregressive/GLM/GLM-4.7.mdx
@@ -127,7 +127,7 @@ Pick a weight format by hardware: **NVFP4** on NVIDIA Blackwell (B200, GB200), *
-For general GLM-4.x family launch guidance (AMD ROCm notes and more), see [Launch GLM-4.5 / GLM-4.6 / GLM-4.7 with SGLang](../../../docs/basic_usage/glm45). Per-hardware bench com
+For general GLM-4.x family launch guidance (AMD ROCm notes and more), see [Launch GLM-4.5 / GLM-4.6 / GLM-4.7 with SGLang](/cookbook/autoregressive/GLM/GLM-4.5). Per-hardware benc
diff -- docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx
@@ -52,7 +52,7 @@ uv pip install 'git+https://github.com/sgl-project/sglang.git#subdirectory=pytho
-For the full Docker setup and other installation methods, refer to the [official SGLang installation guide](../../../docs/get-started/installation).
+For the full Docker setup and other installation methods, refer to the [official SGLang installation guide](../../../docs/get-started/install).
```

- 已读文件:
  - docs: `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V4.mdx` modified +1/-1; `docs_new/cookbook/autoregressive/GLM/GLM-4.7.mdx` modified +1/-1; `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx` modified +1/-1
- 验证与风险: 该 PR 主要落在文档/示例 `docs_new/cookbook/autoregressive/DeepSeek/DeepSeek-V4.mdx`, `docs_new/cookbook/autoregressive/GLM/GLM-4.7.mdx`, `docs_new/cookbook/autoregressive/NVIDIA/Nemotron3-Nano-Omni.mdx`；验证重点是文档命令仍能映射到当前 CLI 参数和模型仓库名。

## 补漏结论

- 验收规则: 每个 PR 卡片必须保留反查来源、diff 范围、实现要点、代码摘录、已读文件和验证风险。
- 如果新模型文件落在当前过滤规则之外，先补文件过滤规则，再重新执行本轮 `git log --name-only -- <model-files>` 追溯。
