---
slug: ggerganov-llamacpp-v100
name: 'ggerganov/llama.cpp: v1.0.0'
builder: ggerganov
category: ''
summary_zh: ''
inspiration: ''
summary_en: ''
inspiration_en: ''
priority_review: false
project_type: open_source
industries: []
industries_en: []
jobs: []
jobs_en: []
regions: []
regions_en: []
open_source: true
url: https://github.com/ggml-org/llama.cpp/releases/tag/v1.0.0
canonical_url: https://github.com/ggml-org/llama.cpp/releases/tag/v1.0.0
summary: "<img width=\"1600\" height=\"900\" alt=\"llama-cpp-v1\" src=\"https://github.com/user-attachments/assets/ed94ed55-ebe2-4aee-bdfc-81bdaa3a3f59\"\
  \ />\r\n\r\nBlog post: https://huggingface.co/blog/ggml-org/llama-cpp-v1\r\n\r\n## Overview\r\n\r\n\
  llama.cpp v1.0.0 removes the deprecated public API and promotes the NextN/speculative API to `llama.h`,\
  \ adds OCP FP8 KV caches, a host-memory MoE expert cache with a configurable CPU share, and loading\
  \ of external PLE shards. It adds three text architectures (Kimi-K3.1-Pro, Ripple and xing4_0), drama-3\
  \ TTS, and MageVL-Cowork and Kimi-K3.1 vision, hardens `llama-server` (SSRF, CORS, DNS rebinding, MCP\
  \ tool cancellation) and adds a `/v1/audio/speech` endpoint, ships a redesigned web UI with chat groups\
  \ and a markdown editor, and updates `ggml` to v1.0.0.\r\n\r\n### API changes\r\n\r\n- llama.h: remove\
  \ `llama_set_warmup`, 35 deprecated functions, `defrag_thold` and `--defrag-thold` ([#30565](https://github.com/ggml-org/llama.cpp/pull/30565))\r\
  \n- llama.h: promote the NextN API from `llama-ext.h` and rename `llama_set_embd_state_src` to `llama_set_ctx_state_src`\
  \ ([#30565](https://github.com/ggml-org/llama.cpp/pull/30565))\r\n- llama.h: add `moe_cache_size` and\
  \ `moe_cache_cpu_share` to `llama_context_params` ([#30966](https://github.com/ggml-org/llama.cpp/pull/30966))\r\
  \n- mtmd.h: add `MTMD_GEN_AUDIO_TYPE_DRAMA3` and `temp` in `mtmd_helper_gen_audio_inp` ([#31613](https://github.com/ggml-org/llama.cpp/pull/31613),\
  \ [#31655](https://github.com/ggml-org/llama.cpp/pull/31655))\r\n- mtmd-helper.h: add `mtmd_helper_resampler`\
  \ for streaming raw PCM at the model sample rate ([#31964](https://github.com/ggml-org/llama.cpp/pull/31964))\r\
  \n- server: add the OpenAI-compatible `/v1/audio/speech` endpoint and a `temperature` option for `/tts`\
  \ ([#31763](https://github.com/ggml-org/llama.cpp/pull/31763), [#31655](https://github.com/ggml-org/llama.cpp/pull/31655))\r\
  \n\r\n### New models\r\n\r\n- Kimi-K3.1-Pro: K3 with the full-attention MLA layers replaced by DSA ([#31779](https://github.com/ggml-org/llama.cpp/pull/31779))\r\
  \n- Ripple-65B-Preview (`ricursive`): new dense 65B architecture, no new ops ([#31692](https://github.com/ggml-org/llama.cpp/pull/31692))\r\
  \n- xing4_0: mHC, MLA, MoE and MTP ([#31589](https://github.com/ggml-org/llama.cpp/pull/31589))\r\n\
  - drama-3 TTS (fishaudio) ([#31613](https://github.com/ggml-org/llama.cpp/pull/31613))\r\n\r\n### Core\
  \ changes\r\n\r\n- FP8 KV caches (`-ctk/-ctv f8_e4m3`) with optional static per-tensor scales ([#28392](https://github.com/ggml-org/llama.cpp/pull/28392))\r\
  \n- MoE cache: CPU share for misses, LRFU/ClassLRU replacement, no CPU wait on cached experts ([#30966](https://github.com/ggml-org/llama.cpp/pull/30966),\
  \ [#31233](https://github.com/ggml-org/llama.cpp/pull/31233), [#31888](https://github.com/ggml-org/llama.cpp/pull/31888))\r\
  \n- external PLE/engram loading from separate GGUF shards via `--shard`/`--ple` ([#31185](https://github.com/ggml-org/llama.cpp/pull/31185))\r\
  \n- Windows unbuffered model load, mirroring the Linux DirectIO path ([#26014](https://github.com/ggml-org/llama.cpp/pull/26014))\r\
  \n- reuse the backend scheduler and graph results across reserves, and skip unused graph metadata pages\
  \ ([#32009](https://github.com/ggml-org/llama.cpp/pull/32009), [#32089](https://github.com/ggml-org/llama.cpp/pull/32089),\
  \ [#32043](https://github.com/ggml-org/llama.cpp/pull/32043))\r\n- mark every sampling chain as a graph\
  \ output to prevent output aliasing ([#32015](https://github.com/ggml-org/llama.cpp/pull/32015))\r\n\
  - remove the non-fused GDN paths and the ubatch-dependent graph node budget ([#32078](https://github.com/ggml-org/llama.cpp/pull/32078))\r\
  \n- store the MTP conv snapshots of every recurrent model in one `set_rows` ([#31660](https://github.com/ggml-org/llama.cpp/pull/31660))\r\
  \n- per-model `build_rope` with a KV-shifting fix and tests ([#31683](https://github.com/ggml-org/llama.cpp/pull/31683));\
  \ the model is a member of `llm_graph_context` ([#31733](https://github.com/ggml-org/llama.cpp/pull/31733))\r\
  \n- fix on-device state copy sizes for quantized KV caches ([#30541](https://github.com/ggml-org/llama.cpp/pull/30541))\r\
  \n- follow the reference precision of `ggml_prec_set_acc` call sites ([#31851](https://github.com/ggml-org/llama.cpp/pull/31851))\r\
  \n- attach NVFP4 FFN scales in Granite and qwen2 ([#31449](https://github.com/ggml-org/llama.cpp/pull/31449),\
  \ [#31657](https://github.com/ggml-org/llama.cpp/pull/31657)); merge tensors on convert for qwen3.5\
  \ ([#32102](https://github.com/ggml-org/llama.cpp/pull/32102))\r\n- apply the iGPU lazy-mode fallback\
  \ only when mmap is off ([#31957](https://github.com/ggml-org/llama.cpp/pull/31957))\r\n- fit: account\
  \ for skipped NextN layers when setting `n_gpu_layers` ([#31569](https://github.com/ggml-org/llama.cpp/pull/31569))\r\
  \n- jinja: chained comparisons and argument unpacking ([#32072](https://github.com/ggml-org/llama.cpp/pull/32072));\
  \ TTS text normalization via the chat template ([#32053](https://github.com/ggml-org/llama.cpp/pull/32053))\r\
  \n- chat: honor `response_format` in the qwen3-coder/deepseek/ministral3, Muse Spark and gemma4 parsers\
  \ ([#31956](https://github.com/ggml-org/llama.cpp/pull/31956), [#32017](https://github.com/ggml-org/llama.cpp/pull/32017),\
  \ [#31915](https://github.com/ggml-org/llama.cpp/pull/31915))\r\n- json-schema: fix `allOf` of plain\
  \ types ([#31834](https://github.com/ggml-org/llama.cpp/pull/31834)); escape control characters and\
  \ sanitize invalid UTF-8 in tool arguments ([#31937](https://github.com/ggml-org/llama.cpp/pull/31937),\
  \ [#31861](https://github.com/ggml-org/llama.cpp/pull/31861))\r\n\r\n### Multi-modality changes\r\n\r\
  \n- remove `clip.h` and consolidate the model/subcontext infrastructure into `mtmd` ([#31865](https://github.com/ggml-org/llama.cpp/pull/31865))\r\
  \n- share the compute buffer among subcontexts to save memory for vision+audio+gen models ([#31945](https://github.com/ggml-org/llama.cpp/pull/31945))\r\
  \n- compute log-mel in the graph instead of spawning threads per request ([#31808](https://github.com/ggml-org/llama.cpp/pull/31808))\r\
  \n- support Gemma 4 streaming audio input ([#31965](https://github.com/ggml-org/llama.cpp/pull/31965))\r\
  \n- support MageVL-Cowork ([#31819](https://github.com/ggml-org/llama.cpp/pull/31819)) and Kimi-K3.1\
  \ vision ([#31980](https://github.com/ggml-org/llama.cpp/pull/31980))\r\n- require the projector and\
  \ patch embedding tensors and a 2x2 spatial merge at load ([#32129](https://github.com/ggml-org/llama.cpp/pull/32129),\
  \ [#32130](https://github.com/ggml-org/llama.cpp/pull/32130))\r\n- require an F32 position embedding\
  \ for HunyuanVL and read the MiniCPM-V width from ne[1] ([#32131](https://github.com/ggml-org/llama.cpp/pull/32131),\
  \ [#32132](https://github.com/ggml-org/llama.cpp/pull/32132))\r\n\r\n### Server changes\r\n\r\n- security:\
  \ add `--allow-unauthenticated-tools` and `--media-allow-private-urls` opt-ins ([#32113](https://github.com/ggml-org/llama.cpp/pull/32113),\
  \ [#32115](https://github.com/ggml-org/llama.cpp/pull/32115))\r\n- security: fix `--cors-origins`, DNS\
  \ rebinding, CORS proxy SSRF and child instance access ([#32098](https://github.com/ggml-org/llama.cpp/pull/32098),\
  \ [#32115](https://github.com/ggml-org/llama.cpp/pull/32115), [#32120](https://github.com/ggml-org/llama.cpp/pull/32120))\r\
  \n- restrict the `HF_TOKEN` to huggingface.co hosts ([#31730](https://github.com/ggml-org/llama.cpp/pull/31730))\r\
  \n- cancel MCP tool calls on client disconnect or timeout and notify the MCP server ([#32025](https://github.com/ggml-org/llama.cpp/pull/32025))\r\
  \n- keep the server awake while a request uses its state with `--sleep-idle-seconds` ([#32133](https://github.com/ggml-org/llama.cpp/pull/32133))\r\
  \n- use reference-counted context checkpoints instead of deep copies ([#30137](https://github.com/ggml-org/llama.cpp/pull/30137))\r\
  \n- visit parent slots before child slots for shared-prefix requests ([#30779](https://github.com/ggml-org/llama.cpp/pull/30779))\r\
  \n- realtime API: send error events instead of crashing, reject non-object session updates, fix the\
  \ output lang ([#31632](https://github.com/ggml-org/llama.cpp/pull/31632), [#31714](https://github.com/ggml-org/llama.cpp/pull/31714),\
  \ [#31982](https://github.com/ggml-org/llama.cpp/pull/31982))\r\n- accept the top-level `response_format.schema`\
  \ form and convert Responses `text.format` JSON schemas ([#28697](https://github.com/ggml-org/llama.cpp/pull/28697),\
  \ [#26145](https://github.com/ggml-org/llama.cpp/pull/26145))\r\n\r\n### UI changes\r\n\r\n- sidebar:\
  \ fold, preview and rearrange sections ([#31936](https://github.com/ggml-org/llama.cpp/pull/31936))\
  \ and gather chats into named groups ([#32012](https://github.com/ggml-org/llama.cpp/pull/32012))\r\n\
  - move Models, MCP and Settings to a sidebar footer, with full-screen pages on phones ([#32022](https://github.com/ggml-org/llama.cpp/pull/32022))\r\
  \n- mobile: native layout, safe areas and full-screen dialogs ([#31949](https://github.com/ggml-org/llama.cpp/pull/31949))\r\
  \n- open the virtual keyboard in the chat editor on Android ([#32060](https://github.com/ggml-org/llama.cpp/pull/32060))\r\
  \n- chat input: live-preview markdown editor that expands for long messages ([#31955](https://github.com/ggml-org/llama.cpp/pull/31955),\
  \ [#31973](https://github.com/ggml-org/llama.cpp/pull/31973))\r\n- open the actions menu on right-click\
  \ for chats, tabs, messages and models ([#31545](https://github.com/ggml-org/llama.cpp/pull/31545))\r\
  \n- PDF attachments: show text and page thumbnails, stop endless conversion retries ([#31468](https://github.com/ggml-org/llama.cpp/pull/31468))\r\
  \n- Discover: show audio capability from the mmproj ([#31837](https://github.com/ggml-org/llama.cpp/pull/31837))\
  \ and keep downloads during search ([#31467](https://github.com/ggml-org/llama.cpp/pull/31467))\r\n\
  - add a `search_chats` tool ([#32051](https://github.com/ggml-org/llama.cpp/pull/32051)) and move the\
  \ JS sandbox setting out of developer ([#32054](https://github.com/ggml-org/llama.cpp/pull/32054))\r\
  \n- take the logo and favicons from the llama-brand package ([#32039](https://github.com/ggml-org/llama.cpp/pull/32039),\
  \ [#32112](https://github.com/ggml-org/llama.cpp/pull/32112))\r\n- fix a hidden sidebar intercepting\
  \ clicks ([#31712](https://github.com/ggml-org/llama.cpp/pull/31712), [#32035](https://github.com/ggml-org/llama.cpp/pull/32035))\r\
  \n\r\n### ggml changes\r\n\r\n- [v1.0.0](https://github.com/ggml-org/ggml/releases/tag/v1.0.0): ggml\
  \ 1.0.0 prunes the deprecated public API and the legacy `DIAG_MASK` ops, adds configurable YaRN truncation\
  \ and FP8 support, and brings broad performance work across backends: few-row quantized matmuls and\
  \ MoE fusion on CUDA/Metal, a Vulkan prefill FlashAttention path, a device-side MoE scheduler on SYCL,\
  \ decomposed Adreno FlashAttention in OpenCL, new WebGPU kernels, expanded Hexagon op coverage, and\
  \ scheduler improvements that avoid uploading unused inputs.\r\n\r\n## Assets\r\n\r\n**Nightly build:**\
  \ [b12359](https://github.com/ggml-org/llama.cpp/releases/tag/b12359)\r\n\r\n## More info\r\n\r\n- [Releases\
  \ and versioning of `ggml-org` projects](https://github.com/ggml-org/ggml/discussions/1579)\r\n\r\n\
  ## Changelog since [v0.9.0](https://github.com/ggml-org/llama.cpp/releases/tag/v0.9.0)\r\n\r\nb1b770d90\
  \ examples : remove explict version from test-cmake (#32191)\r\n4cda6227a llama.cpp : bump version to\
  \ 1.0.0 (#32190)\r\n685981335 sync : ggml\r\n3bfde28f9 ggml : bump version to 1.0.0 (ggml/1690)\r\n\
  28d37fe2e examples : clean-up old/obsolete stuff (#32184)\r\nbd2767d06 ci: fix HIP quality check by\
  \ ignoring the FP8 vec FA kernel spill (#32183)\r\n82503b42f ci : set windows-cuda ccache size to 1G\
  \ (#32185)\r\n5676dfbe0 chat : accept </ifm|think> as K2 Horizon closer at medium/low effort (#30335)\r\
  \n0a66ac718 server, fix CI: read a small temp file in the read_file tool test [no release] (#32168)\r\
  \n892b40b91 server: allow private media URLs in the vision tests [no ci] (#32167)\r\ne97010147 server:\
  \ skip LAN address tests when the host cannot reach it [no ci] (#32166)\r\n92d6c8a5c fix(hexagon): make\
  \ host build work with clang-cl on Windows ARM64 (#32011)\r\n8ca5a8008 llama : prune (#30565)\r\n29dbbad2b\
  \ ggml : prune (#29801)\r\n2a4daf0e0 hexagon: add Q5_0 and Q5_1 support (#32094)\r\nd8c8cc4d9 server\
  \ : cancel MCP tool calls on client disconnect or timeout (#32025)\r\n3ba1ce0e2 qwen3.5: merge tensors\
  \ on convert also (#32102)\r\n0fb8f1577 Title: CUDA: few-row MMQ for BS 2-24 (#31533)\r\n827466b9e ci\
  \ : build ui on non-slim runner (#32138)\r\n8954f1948 server: fix SSRF for CORS proxy and media URLs\
  \ (#32115)\r\na1a68eb79 server: explicit opt-in tools via non-loopback addr, check cors host port (#32113)\r\
  \ne182fdad4 server: disallow direct access child instance from browser (#32120)\r\n09452cded server:\
  \ keep the server awake while a request uses its state (#32133)\r\ncfb9d4b75 mtmd: require an F32 position\
  \ embedding for HunyuanVL (#32131)\r\n72f4603c7 mtmd: read the MiniCPM-V projection width from ne[1]\
  \ (#32132)\r\n8c388364e mtmd: require the MLP projector and patch embedding tensors (#32129)\r\n08f49598c\
  \ mtmd: require a 2x2 spatial merge for the Qwen-VL projectors (#32130)\r\na8575a3ef ggml : route GATED_DELTA_NET\
  \ to the SpacemiT RVV kernel (#31897)\r\na963f6595 vulkan : Intel FA kernel for prefill. (#29357)\r\n\
  ab4a77b9a ggml-cpu: use the 4x4 simd_gemm tile on ARM NEON (#32128)\r\n0d69255c5 CUDA: Optimize prefil\
  \ via fuse of w_s scale in epilogue MMQ for nvfp4 checkpoints (#26048)\r\n3bce8bd50 ggml-backend : prefetch\
  \ only inputs computed by earlier splits (#32100)\r\n81f21f4b2 ggml : dispatch SpacemiT Q4_1 32x256\
  \ through the HP kernel (#31929)\r\nb19f1d9e6 ui: add search_chats tool (#32051)\r\nd90cfd4a9 ui: install\
  \ llama-brand from a GitHub tarball instead of git (#32112)\r\n60d46a5ab server: when --tools-runtime\
  \ is specified, ignore x-tool-runtime (#32119)\r\n93cf736a8 chat : refactor gemma4 to build loose schema\
  \ rules and clean up (#31915)\r\n4fffab623 llama : avoid touching unused graph metadata pages (#32043)\r\
  \n09338b85e sycl: make oneDNN FA cache thread-safe and memoize runtime failures (#31138)\r\ndcbff2166\
  \ sycl : fix AOT for more than 4GB (#31873)\r\nf3d7725a7 sycl : use cached device-id in set_main_device\
  \ (#32013)\r\n7021f7e09 CUDA: add cuda debug buffer pool (#31919)\r\ne0949d09b opencl: add bin kernel\
  \ `kernel_gemm_noshuffle_q4_0_f32_32b_trans_ila_a7_bin` (#30947)\r\n5d4c8eeb2 CUDA: skip empty MoE tiles\
  \ in MMQ stream-k fixup (#32067)\r\ndd6b945be server: use the moved test model in the router CORS test\
  \ (#32117)\r\ne1f7593c3 opencl: add decomposed FA for Adreno (#32046)\r\n7bcbc04fb ui: move js sandbox\
  \ setting out of \"developer\" (#32054)\r\ndd00306bc docs: update image link in README.md (#32038)\r\
  \n1d8199278 ui: keep downloads in Discover during search and fix their progress with a draft (#31467)\r\
  \nbd717e08f ui: take the logo and favicons from the llama-brand package (#32039)\r\n2cbe0ec42 server:\
  \ fix --cors-origins handling + protect against DNS rebinding (#32098)\r\n664f031f4 ci: move test models\
  \ to ggml-org-dev (#32096)\r\n4180722ee metal : prevent out-of-bounds reads in SOLVE_TRI kernel (#32103)\r\
  \n055c3c26e vulkan: support batched tensor copy API (#31418)\r\n2656b71a1 vendor : update LibreSSL to\
  \ 4.4.1 [no ci] (#32106)\r\ncb44fdb18 llama : reuse graph result instances across scheduler reserves\
  \ (#32089)\r\ncd2db800d jinja : support chained comparisons and argument unpacking (#32072)\r\nf7b886fe6\
  \ chat: allow TTS model to provide custom text normalizer via jinja (#32053)\r\n956591f45 ci : remove\
  \ dead snakes (#32084)\r\nccd360f06 llama : remove non-fused GDN and ubatch-dependent graph nodes (#32078)\r\
  \nb326dd675 devops : add missing MKL runtime DLLs to the Windows SYCL release package (#32005)\r\nb8abe41a5\
  \ vendor: update cpp-httplib to 0.66.0 (#32049)\r\n2e325dcd5 backend : re-instantiate CUDA graphs when\
  \ the cluster dims of a kernel change (#31284)\r\n1648d6411 test-fp8.cpp: use only the public ggml API\
  \ (#32083)\r\n432433637 ROCm/HIP: fixed BLAS workspace instead of rocBLAS allocating one per call (#31838)\r\
  \n71a6a114b quantize: fix imatrix GGUF filepath metadata leak (#32000)\r\n7f24aacde cpu: accumulate\
  \ flash attention V in F32 (#29810)\r\naf6b5243d webgpu: add PAD_REFLECT_1D support (#31877)\r\nd2b3eb9b6\
  \ vulkan: allow dequantized KV optimization with CM2 (#31526)\r\neeb210479 vulkan: allocate the device\
  \ fault vendor binary buffer (#32008)\r\n03d6c824e tests : use only the public ggml API (#32077)\r\n\
  adde94c11 ui: open the virtual keyboard in the chat editor on Android (#32060)\r\n459ab1cdd cuda : use\
  \ MMVF for BF16 matrices of few rows at small batch sizes (#31959)\r\n77e2db8ca cuda : add sm70 FlashAttention\
  \ config case for DKQ=256, DV=256, ncols=64 (#27997)\r\n9d7b2d739 cuda : fattn mma head sizes 40 72\
  \ (#30285)\r\n9e9619d03 CUDA: Add OCP FP8 support (#28413)\r\nf3b407ca1 sycl : fixed sycl CLAMP to actually\
  \ support strided view (#31784)\r\naa75ff323 chat : fix Muse Spark ignoring response_format json_schema\
  \ (#32017)\r\nb5cb8f6f4 ui: keep a hidden sidebar from intercepting clicks again (#32035)\r\n85822a7ab\
  \ ui: update the README banner to the new llama.cpp cover and remove the legacy brand assets (#31789)\r\
  \n2b66bfbf7 ui: show audio in Discover for models whose mmproj has an audio encoder (#31837)\r\n582eab718\
  \ ci : bump ty to 0.0.100 (#32030)\r\n7c2653acc mtmd: fix string format, rename to mtmd_format (#32040)\r\
  \n7592b61d3 ui: move Models, MCP and Settings to a sidebar footer (#32022)\r\ncd4ed902e cuda : remove\
  \ unused ids and type_src0 parameters (#32018)\r\n202c1a229 llama : Add FP8 KV-cache support (#28392)\r\
  \ne24d0b4c3 Merge pull request #32015 from ggml-org/gg/fix-sampling-output-aliasing\r\n3e86ce2c2 llama\
  \ : reuse backend scheduler when sched_params are compatible (#32009)\r\n494d0f47b ggml : add MUL_MAT\
  \ src1 precision tests and gating (#31896)\r\n281e7dad7 ui: gather chats into named groups in the sidebar\
  \ (#32012)\r\n90e3841d9 ui: show settings save button even while focused (#32010)\r\nc75fba30c cuda\
  \ : remove unused quantize_cuda_t typedef (#31884)\r\n40f4f4ac9 graph: mark every sampling chain as\
  \ an output to prevent aliasing\r\n54cde7106 ui: expand the chat form into a large editor for longer\
  \ messages (#31973)\r\n7d6fd845e convert : mark Sarvam byte fallback tokens as BYTE (#32006)\r\n4ed88da2e\
  \ convert : workaround conversion for p-e-w/gpt-oss-20b-heretic-ara-v4 (#31860)\r\nac931b5bc cuda :\
  \ halve VMM pool reservation size and retry on cuMemAddressReserve failure (#30542)\r\n15759e0ca CUDA:\
  \ skip graph compat check when graph is being reused (#32004)\r\na591cbe17 mtmd: share compute buffer\
  \ among subcontext (#31945)\r\n203b5f404 server: fix output lang for realtime api (#31982)\r\n351025ec5\
  \ mtmd: add kimi K3.1 vision (#31980)\r\n0d9eacadf ggml : fix FreeBSD Vulkan build by setting _XOPEN_SOURCE=700\
  \ (#31701)\r\n17701e48d CUDA: move graph and concurrent stream state out of common.cuh (#32001)\r\n\
  ac007054e ui: use a live-preview markdown editor for the chat form input (#31955)\r\n940a30ee3 model\
  \ : stop renaming the recurrent cache tensors in plamo2 (#31984)\r\n45c8ea837 common/json-schema : fix\
  \ allOf with plain types (e.g. integer) generating an empty object grammar (#31834)\r\nc90aa996b common\
  \ : escape control characters in tool argument strings (#31937)\r\na2c942dcf cann: fail early when checking\
  \ if buffer type is supported (#31270)\r\n18c5a95e2 sycl: Add device-side MoE scheduler (#30156)\r\n\
  ae4893a09 vulkan: add tiled-transpose concat shader for Qwen models (#30591)\r\n6122b566b ggml-rpc :\
  \ fail gracefully on unreachable endpoints and failed handshakes (#30415)\r\n3837bf0bc vulkan: Divide\
  \ GROUP_NORM workgroup to 2D to avoid maxComputeWorkGroupCount limit (#31930)\r\nc1a4febe9 vulkan: Fix\
  \ out of bounds reads/writes on MoltenVK (#31890)\r\n78ffbaa18 vulkan: cap scalar flash attention at\
  \ 8 rows for large heads on Qualcomm (#30829)\r\n58e38bdf6 llama : apply the iGPU lazy-mode fallback\
  \ only when mmap is off (#31957)\r\nd5bbcd1f3 ci: update oneAPI 2026.2, oneDNN 2026.1 and Level Zero\
  \ SDK 1.34.0 (#31540)\r\n8766c0273 sycl: un-gate oneDNN fused SDPA for Alchemist at head_dim=64 (#31574)\r\
  \n3b4d6ab3f chat : don't use lazy grammar when response_format is set with tools (#31956)\r\ncf6463ace\
  \ hexagon: fix 64-bit FastRPC handle truncation on close (#30952)\r\n711f9f4c1 server: responses api:\
  \ support conversion of text.format.json_schema to completions (#26145)\r\n26d52b0f9 server : use common_chat_input\
  \ in realtime api (#31978)\r\n08f945ffb server: add oai-compat /v1/audio/speech endpoint (#31763)\r\n\
  20c2e9665 mtmd: support gemma 4 input audio stream (#31965)\r\n3d94ffe45 mtmd: add mtmd_helper_resampler\
  \ (#31964)\r\n0a94a3f28 ui : retry opening the sidebar when a demo imports its traces (#31952)\r\n610f7ab40\
  \ ui: make the app feel native on phones (#31949)\r\n5f490d7bf feat: external PLE file loading (#31185)\r\
  \n9d340ec34 Windows unbuffered model load (#26014)\r\n359dc5858 server : functionality test for new\
  \ spec dec  (#31027)\r\na4d4f2fd4 ggml-zdnn: accept non-zdnn tensors, invalidate compute tensors after\
  \ every op (#31824)\r\n1945793e0 server : fix response_format json_schema when schema is not nested\
  \ in the json_schema wrapper (#28697)\r\n0eebb6edd ggml : implement the backward pass for TRI (#30712)\r\
  \nd628a98f0 tests : keep dummy ffn.act scales away from zero (#31940)\r\na8fad21e9 mtp: read the target\
  \ hidden states from a device buffer (#31927)\r\nb39680c41 ui: fold, preview and rearrange the sidebar's\
  \ sections (#31936)\r\n806b3c2be ggml-backend: don't upload inputs that are not read  (#31419)\r\n0c6dca2fa\
  \ models : Attach Granite NVFP4 weight scales (#31449)\r\nfc0be8618 ci : Run gfx1151 ROCm job on Strix\
  \ Halo Devlab runners (#31567)\r\ne01c9f187 metal : prevent out-of-bounds writes to the Metal FA output\
  \ buffer (#31662)\r\n4b46d9653 metal : make ggml_tri select instead of scaling by the comparison (#30711)\r\
  \nf3178366b opencl : include climits (#31935)\r\n2d99adb10 mtmd: Pocket TTS - add generic support for\
  \ temperature set via API (#31655)\r\ncf92c1323 RPC: Improve loading times (#29413)\r\n9f0d80cf4 ggml\
  \ : support YaRN truncation config on openvino, sycl, vulkan, webgpu, rpc (#30802)\r\na0ad695cb sycl:\
  \ cache device-id (#31126)\r\n6590d25a3 tests: bound the test_rope tolerance by the f32 angle resolution\
  \ (#31874)\r\n53eb66943 opencl: add f32 MUL_MAT_ID (#31783)\r\nd78f4255d ggml-zdnn: fix release binary\
  \ not detecting backend lib (#31905)\r\n7d7f02875 mtmd: refactoring: remove clip.h, consolidate code\
  \ into mtmd (#31865)\r\nb65bf6921 cpu: enable SpacemiT IME2 MXFP4 dense repack (#31776)\r\na3c7cf08f\
  \ llamafile: impl bf16 and q8_0 vxe (#31866)\r\n57d04820d ggml : update CUDA/Metal radix Top-K to make\
  \ tied selections deterministic (#31084)\r\n998200491 ggml-cuda : add d_state=64 fast path to SSM_SCAN\
  \ kernel (#31818)\r\ncf34d3113 moe-cache : ensure CPU part does not wait for the cached experts (#31888)\r\
  \na691b2345 webgpu : add COUNT_EQUAL support (#31578)\r\n2277e7529 ci: move runners to Ubuntu 26.04\
  \ (#31529)\r\n12ab59798 ggml : switch to F32 src1 in the CPU backend (#31854)\r\nd6be06557 llama, mtmd:\
  \ follow the reference precision of ggml_prec_set_acc calls (#31851)\r\na2b301831 speculative : do not\
  \ apply the MoE cache to the draft model (#31497)\r\nc19043f67 opencl: improve q8_0 and MoE small-n\
  \ verification for spec (#31831)\r\n372dc5ca1 common : sanitize invalid UTF-8 in PEG tool call arguments\
  \ (#31861)\r\nf477f795c server : downgrade per-request proxy logs to trace (#31859)\r\n76a67730f hexagon:\
  \ support for automatic loading of libhtp without legacy env vars (#31781)\r\n12e9084dc sycl: exact\
  \ rounding in CPY to Q4_1, Q5_1 and Q8_0 (#31465)\r\n818ac6b07 sycl: refuse device buffers that would\
  \ exceed VRAM (#31285)\r\ne9a2a44fe hexagon: n_hvx and n_threads cleanup (#31857)\r\na2654ec43 mtmd:\
  \ move log-mel computation to cgraph (#31808)\r\n9f0e5098a mtmd: support MageVL-Cowork model (#31819)\r\
  \ne95426f16 llama_moe_cache: run missed experts on CPU, add tuning script (#30966)\r\nf7591a6a0 sycl:\
  \ add f16 support for SWIGLU_OAI (#30857)\r\n80d2c0c2c metal : fix GROUP_NORM for ne03 > 1 and non-contiguous\
  \ inputs (#31852)\r\n095668452 server: visit parent slots before child slots (#30779)\r\ncf659f240 webgpu\
  \ :  Implement group norm kernel (#31490)\r\n193815264 vulkan: Add 'readonly' to decodeBuf declarations.\
  \ (#31833)\r\n5d7d4aec1 CUDA: fix shared memory bank conflicts in the lightning indexer (#31803)\r\n\
  c0ab6e5c0 llama : add missing link to pthread (#31785)\r\n31424b7cf opencl: add arange (#31829)\r\n\
  fd27b2034 meta : raise the compute view limit for buffers with few tensors (#31447)\r\nca89968a2 hexagon:\
  \ fuse post-norm residual add into RMS_NORM_MUL (#31822)\r\nbcb015287 model: add Kimi-K3.1-Pro text\
  \ model (#31779)\r\n669204ee2 hexagon: conv_2d optimizations and support for conv_3d (#31814)\r\n954de248a\
  \ docker: add explicit /usr/local/nvidia search path (#31806)\r\n6c01da627 cli : fix crash on invalid\
  \ UTF-8 in prompt or files (#31563)\r\n8820b088d tests : qualify isnan and signbit with std:: (#31791)\r\
  \n9a1d03c7c tests : override hardware_concurrency in CI (#31797)\r\n18ab62a8e cmake : generate RC file\
  \ directly without win-app.rc.in (#31718)\r\n52c9bad94 opencl:  support repeat for f16, i32, i16, bf16\
  \ (#31782)\r\n5d3ed2ae7 webgpu: add batched tensor API (`get_tensor_n` and `set_tensor_n`) (#31473)\r\
  \n80088fa60 vulkan: detect ReBAR support, avoid BAR allocations if unavailable (#31658)\r\nc4fb57969\
  \ moe-cache : LRFU/MQ-like hybrid cache, ClassLRU (#31233)\r\n3ed7284f2 ci : bump CUDA 13 release builds\
  \ to 13.5 (#31788)\r\nd9cf1870b vendor: update BoringSSL to 0.20261105.0 (#31757)\r\n240d68fcf CUDA:\
  \ fix Maxwell build (#31787)\r\nbbc2e4b65 common : restrict HF token to huggingface.co hosts (#31730)\r\
  \n4b77dee05 opencl: add q6_k multi column tiled GEMV for speculative verification and refactoring (#31758)\r\
  \n67107ac34 hexagon: Implement set_tensor_n and improve repacking/tiling robustness (#31744)\r\ne14a77971\
  \ mtmd: enable cmake unity build (#31760)\r\nd38bea342 tests : drop u8path() (#31755)\r\n186eab1cb ci:\
  \ fix build-cmake-pkg ccache (#31705)\r\n6023692b1 llama: fix kv shifting, add tests, add per-model\
  \ build_rope (#31683)\r\nb1c902f02 llama, mtmd: (chatterbox) add use_classifier_free_guidance as gguf\
  \ metadata (#31698)\r\ne8df20d23 models : recursive fix (#31749)\r\nfecdc81ee model : add Ripple (ricursiveai)\
  \ (#31692)\r\n45b6604b2 model: Add support for the xing4_0  (#31589)\r\ne30ad80fd ui: prevent a hidden\
  \ sidebar from intercepting clicks (#31712)\r\ne0f96a1a1 llama: refactoring: move model to class member\
  \ of llm_graph_context (#31733)\r\n468fde90e server : simplify windows MCP command resolution (#31728)\r\
  \n1416f76aa vendor : update cpp-httplib to 0.65.0 (#31731)\r\n10d4846a5 ggml-cuda: sanitize post-bias\
  \ NaNs in MoE selection (#31005)\r\n61d447234 vulkan: Implement test-fusion interface (#30769)\r\n016c1d914\
  \ CUDA: use highest compiled arch in get_mmvq_mmid_max_batch (#31679)\r\nda3416d80 vulkan: RDNA3/4 Large-Tile\
  \ Split-K Optimization (#30280)\r\ncc78da97c gguf-py : external chat templates have precedence over\
  \ tokenizer_config (#31717)\r\nea40a3a1e metal : fuse DeepSeek-V4/V4.1 and GLM MoE routing (#31615)\r\
  \n15e50990b CUDA/HIP: matrix-core (MFMA) lightning indexer for CDNA2 (gfx90a) (#29050)\r\n69ee2ecc0\
  \ CUDA: linearize MoE data layout for MMQ/MMF (#31047)\r\n2bc46baa9 vulkan: FWHT kernels for block widths\
  \ above 512 (#29772)\r\n3b83d12b0 vulkan : check combined K+V f16 scratch size in FA dequant path (#30487)\r\
  \ne152332a1 llama-server: Use reference-counted checkpoints instead of deep-copies (#30137)\r\n1fa7f1c48\
  \ ggml : support `truncate=false` for YaRN (#30206)\r\n9c9074e14 conversion : resolve quantized_layers\
  \ from source tensor names (#31611)\r\nf7b41cca4 metal : use mul_mm for 32 <= K < 64 (#30982)\r\nc55b09488\
  \ server : reject non-object session updates (#31714)\r\n2c192444c fit : account for skipped NextN layers\
  \ when setting n_gpu_layers (#31569)\r\n553d2c2e7 webgpu : add MEAN support (#31591)\r\n040ce199a graph:\
  \ store the MTP conv snapshots of every recurrent model in one set_rows (#31660)\r\nd4c345d6c ci : remove\
  \ unused model generation (#31412)\r\n2ada83079 common : drop u8path() and use generic_string() (#31681)\r\
  \n5a081c0a7 server : drop u8path() and use generic_string() (#31682)\r\n7e42b95f2 rpc : align code with\
  \ common.cpp (#31684)\r\n3259ab6e5 vulkan: Re-enable large coopmat matmul configuration on AMD proprietary\
  \ driver 26.10.1+ (#31587)\r\na01dff908 tests: fix CI flakes of TOPK_MOE caused by near ties (#31426)\r\
  \n44f91a02b metal: keep fusable node groups inside one command buffer (#31688)\r\n330f0189c qwen2 :\
  \ add nvfp4 scales to build_ffn (#31657)\r\n7d516e25e opencl: enable f32 and q5_k multi column GEMV\
  \ by default for Adreno X2 (#31694)\r\n8bed7cfb9 opencl: support non-contig sigmoid (#31687)\r\n8415bd7bb\
  \ opencl: add DSV4_HC_PRE and DSV4_HC_POST (#31623)\r\n5ce06fc71 Title: CUDA: fuse NVFP4 gate/up matmuls\
  \ and GLU in MMQ (#31296)\r\ne56f006ed llama : fix on-device state copy sizes for quantized KV caches\
  \ (#30541)\r\n3de52ac38 ci: run self hosted cpu jobs on hf or github (#31439)\r\n6f1e65437 server :\
  \ realtime: send an error event instead of crashing on exceptions (#31632)\r\n9e2a04a43 opencl: improve\
  \ decode perf with FA (#31633)\r\nc6a0ff11a ui: open actions on right-click for chats, tabs, messages\
  \ and models (#31545)\r\n5851a8e50 model, mtmd: drama-3 tts support (#31613)\r\nefbf6e80a ui: show text\
  \ and page thumbnails for PDF attachments, stop endless conversion retries (#31468)\r\nb393d73bb webgpu:\
  \ return maxBufferSize from get_max_size and avoid whole-buffer bindings in memset/clear (#31348)\r\n\
  00df7c22d sycl : fix docker issue (#31605)\r\n034e2535a gguf-py : validate every tokenizer merge pair,\
  \ not only the first (#31631)\r\n52e53a76d common : delete common_get_path_from_env() (#31444)"
first_seen: '2026-11-14T02:27:37Z'
last_seen: '2026-11-14T02:27:37Z'
status: pending_filter
sources:
- github
sightings:
- source: github
  url: https://github.com/ggml-org/llama.cpp/releases/tag/v1.0.0
  seen_at: '2026-11-14T02:27:37Z'
  metrics:
    reactions: 149
  kind: news
---

# ggerganov/llama.cpp: v1.0.0

<img width="1600" height="900" alt="llama-cpp-v1" src="https://github.com/user-attachments/assets/ed94ed55-ebe2-4aee-bdfc-81bdaa3a3f59" />

Blog post: https://huggingface.co/blog/ggml-org/llama-cpp-v1

## Overview

llama.cpp v1.0.0 removes the deprecated public API and promotes the NextN/speculative API to `llama.h`, adds OCP FP8 KV caches, a host-memory MoE expert cache with a configurable CPU share, and loading of external PLE shards. It adds three text architectures (Kimi-K3.1-Pro, Ripple and xing4_0), drama-3 TTS, and MageVL-Cowork and Kimi-K3.1 vision, hardens `llama-server` (SSRF, CORS, DNS rebinding, MCP tool cancellation) and adds a `/v1/audio/speech` endpoint, ships a redesigned web UI with chat groups and a markdown editor, and updates `ggml` to v1.0.0.

### API changes

- llama.h: remove `llama_set_warmup`, 35 deprecated functions, `defrag_thold` and `--defrag-thold` ([#30565](https://github.com/ggml-org/llama.cpp/pull/30565))
- llama.h: promote the NextN API from `llama-ext.h` and rename `llama_set_embd_state_src` to `llama_set_ctx_state_src` ([#30565](https://github.com/ggml-org/llama.cpp/pull/30565))
- llama.h: add `moe_cache_size` and `moe_cache_cpu_share` to `llama_context_params` ([#30966](https://github.com/ggml-org/llama.cpp/pull/30966))
- mtmd.h: add `MTMD_GEN_AUDIO_TYPE_DRAMA3` and `temp` in `mtmd_helper_gen_audio_inp` ([#31613](https://github.com/ggml-org/llama.cpp/pull/31613), [#31655](https://github.com/ggml-org/llama.cpp/pull/31655))
- mtmd-helper.h: add `mtmd_helper_resampler` for streaming raw PCM at the model sample rate ([#31964](https://github.com/ggml-org/llama.cpp/pull/31964))
- server: add the OpenAI-compatible `/v1/audio/speech` endpoint and a `temperature` option for `/tts` ([#31763](https://github.com/ggml-org/llama.cpp/pull/31763), [#31655](https://github.com/ggml-org/llama.cpp/pull/31655))

### New models

- Kimi-K3.1-Pro: K3 with the full-attention MLA layers replaced by DSA ([#31779](https://github.com/ggml-org/llama.cpp/pull/31779))
- Ripple-65B-Preview (`ricursive`): new dense 65B architecture, no new ops ([#31692](https://github.com/ggml-org/llama.cpp/pull/31692))
- xing4_0: mHC, MLA, MoE and MTP ([#31589](https://github.com/ggml-org/llama.cpp/pull/31589))
- drama-3 TTS (fishaudio) ([#31613](https://github.com/ggml-org/llama.cpp/pull/31613))

### Core changes

- FP8 KV caches (`-ctk/-ctv f8_e4m3`) with optional static per-tensor scales ([#28392](https://github.com/ggml-org/llama.cpp/pull/28392))
- MoE cache: CPU share for misses, LRFU/ClassLRU replacement, no CPU wait on cached experts ([#30966](https://github.com/ggml-org/llama.cpp/pull/30966), [#31233](https://github.com/ggml-org/llama.cpp/pull/31233), [#31888](https://github.com/ggml-org/llama.cpp/pull/31888))
- external PLE/engram loading from separate GGUF shards via `--shard`/`--ple` ([#31185](https://github.com/ggml-org/llama.cpp/pull/31185))
- Windows unbuffered model load, mirroring the Linux DirectIO path ([#26014](https://github.com/ggml-org/llama.cpp/pull/26014))
- reuse the backend scheduler and graph results across reserves, and skip unused graph metadata pages ([#32009](https://github.com/ggml-org/llama.cpp/pull/32009), [#32089](https://github.com/ggml-org/llama.cpp/pull/32089), [#32043](https://github.com/ggml-org/llama.cpp/pull/32043))
- mark every sampling chain as a graph output to prevent output aliasing ([#32015](https://github.com/ggml-org/llama.cpp/pull/32015))
- remove the non-fused GDN paths and the ubatch-dependent graph node budget ([#32078](https://github.com/ggml-org/llama.cpp/pull/32078))
- store the MTP conv snapshots of every recurrent model in one `set_rows` ([#31660](https://github.com/ggml-org/llama.cpp/pull/31660))
- per-model `build_rope` with a KV-shifting fix and tests ([#31683](https://github.com/ggml-org/llama.cpp/pull/31683)); the model is a member of `llm_graph_context` ([#31733](https://github.com/ggml-org/llama.cpp/pull/31733))
- fix on-device state copy sizes for quantized KV caches ([#30541](https://github.com/ggml-org/llama.cpp/pull/30541))
- follow the reference precision of `ggml_prec_set_acc` call sites ([#31851](https://github.com/ggml-org/llama.cpp/pull/31851))
- attach NVFP4 FFN scales in Granite and qwen2 ([#31449](https://github.com/ggml-org/llama.cpp/pull/31449), [#31657](https://github.com/ggml-org/llama.cpp/pull/31657)); merge tensors on convert for qwen3.5 ([#32102](https://github.com/ggml-org/llama.cpp/pull/32102))
- apply the iGPU lazy-mode fallback only when mmap is off ([#31957](https://github.com/ggml-org/llama.cpp/pull/31957))
- fit: account for skipped NextN layers when setting `n_gpu_layers` ([#31569](https://github.com/ggml-org/llama.cpp/pull/31569))
- jinja: chained comparisons and argument unpacking ([#32072](https://github.com/ggml-org/llama.cpp/pull/32072)); TTS text normalization via the chat template ([#32053](https://github.com/ggml-org/llama.cpp/pull/32053))
- chat: honor `response_format` in the qwen3-coder/deepseek/ministral3, Muse Spark and gemma4 parsers ([#31956](https://github.com/ggml-org/llama.cpp/pull/31956), [#32017](https://github.com/ggml-org/llama.cpp/pull/32017), [#31915](https://github.com/ggml-org/llama.cpp/pull/31915))
- json-schema: fix `allOf` of plain types ([#31834](https://github.com/ggml-org/llama.cpp/pull/31834)); escape control characters and sanitize invalid UTF-8 in tool arguments ([#31937](https://github.com/ggml-org/llama.cpp/pull/31937), [#31861](https://github.com/ggml-org/llama.cpp/pull/31861))

### Multi-modality changes

- remove `clip.h` and consolidate the model/subcontext infrastructure into `mtmd` ([#31865](https://github.com/ggml-org/llama.cpp/pull/31865))
- share the compute buffer among subcontexts to save memory for vision+audio+gen models ([#31945](https://github.com/ggml-org/llama.cpp/pull/31945))
- compute log-mel in the graph instead of spawning threads per request ([#31808](https://github.com/ggml-org/llama.cpp/pull/31808))
- support Gemma 4 streaming audio input ([#31965](https://github.com/ggml-org/llama.cpp/pull/31965))
- support MageVL-Cowork ([#31819](https://github.com/ggml-org/llama.cpp/pull/31819)) and Kimi-K3.1 vision ([#31980](https://github.com/ggml-org/llama.cpp/pull/31980))
- require the projector and patch embedding tensors and a 2x2 spatial merge at load ([#32129](https://github.com/ggml-org/llama.cpp/pull/32129), [#32130](https://github.com/ggml-org/llama.cpp/pull/32130))
- require an F32 position embedding for HunyuanVL and read the MiniCPM-V width from ne[1] ([#32131](https://github.com/ggml-org/llama.cpp/pull/32131), [#32132](https://github.com/ggml-org/llama.cpp/pull/32132))

### Server changes

- security: add `--allow-unauthenticated-tools` and `--media-allow-private-urls` opt-ins ([#32113](https://github.com/ggml-org/llama.cpp/pull/32113), [#32115](https://github.com/ggml-org/llama.cpp/pull/32115))
- security: fix `--cors-origins`, DNS rebinding, CORS proxy SSRF and child instance access ([#32098](https://github.com/ggml-org/llama.cpp/pull/32098), [#32115](https://github.com/ggml-org/llama.cpp/pull/32115), [#32120](https://github.com/ggml-org/llama.cpp/pull/32120))
- restrict the `HF_TOKEN` to huggingface.co hosts ([#31730](https://github.com/ggml-org/llama.cpp/pull/31730))
- cancel MCP tool calls on client disconnect or timeout and notify the MCP server ([#32025](https://github.com/ggml-org/llama.cpp/pull/32025))
- keep the server awake while a request uses its state with `--sleep-idle-seconds` ([#32133](https://github.com/ggml-org/llama.cpp/pull/32133))
- use reference-counted context checkpoints instead of deep copies ([#30137](https://github.com/ggml-org/llama.cpp/pull/30137))
- visit parent slots before child slots for shared-prefix requests ([#30779](https://github.com/ggml-org/llama.cpp/pull/30779))
- realtime API: send error events instead of crashing, reject non-object session updates, fix the output lang ([#31632](https://github.com/ggml-org/llama.cpp/pull/31632), [#31714](https://github.com/ggml-org/llama.cpp/pull/31714), [#31982](https://github.com/ggml-org/llama.cpp/pull/31982))
- accept the top-level `response_format.schema` form and convert Responses `text.format` JSON schemas ([#28697](https://github.com/ggml-org/llama.cpp/pull/28697), [#26145](https://github.com/ggml-org/llama.cpp/pull/26145))

### UI changes

- sidebar: fold, preview and rearrange sections ([#31936](https://github.com/ggml-org/llama.cpp/pull/31936)) and gather chats into named groups ([#32012](https://github.com/ggml-org/llama.cpp/pull/32012))
- move Models, MCP and Settings to a sidebar footer, with full-screen pages on phones ([#32022](https://github.com/ggml-org/llama.cpp/pull/32022))
- mobile: native layout, safe areas and full-screen dialogs ([#31949](https://github.com/ggml-org/llama.cpp/pull/31949))
- open the virtual keyboard in the chat editor on Android ([#32060](https://github.com/ggml-org/llama.cpp/pull/32060))
- chat input: live-preview markdown editor that expands for long messages ([#31955](https://github.com/ggml-org/llama.cpp/pull/31955), [#31973](https://github.com/ggml-org/llama.cpp/pull/31973))
- open the actions menu on right-click for chats, tabs, messages and models ([#31545](https://github.com/ggml-org/llama.cpp/pull/31545))
- PDF attachments: show text and page thumbnails, stop endless conversion retries ([#31468](https://github.com/ggml-org/llama.cpp/pull/31468))
- Discover: show audio capability from the mmproj ([#31837](https://github.com/ggml-org/llama.cpp/pull/31837)) and keep downloads during search ([#31467](https://github.com/ggml-org/llama.cpp/pull/31467))
- add a `search_chats` tool ([#32051](https://github.com/ggml-org/llama.cpp/pull/32051)) and move the JS sandbox setting out of developer ([#32054](https://github.com/ggml-org/llama.cpp/pull/32054))
- take the logo and favicons from the llama-brand package ([#32039](https://github.com/ggml-org/llama.cpp/pull/32039), [#32112](https://github.com/ggml-org/llama.cpp/pull/32112))
- fix a hidden sidebar intercepting clicks ([#31712](https://github.com/ggml-org/llama.cpp/pull/31712), [#32035](https://github.com/ggml-org/llama.cpp/pull/32035))

### ggml changes

- [v1.0.0](https://github.com/ggml-org/ggml/releases/tag/v1.0.0): ggml 1.0.0 prunes the deprecated public API and the legacy `DIAG_MASK` ops, adds configurable YaRN truncation and FP8 support, and brings broad performance work across backends: few-row quantized matmuls and MoE fusion on CUDA/Metal, a Vulkan prefill FlashAttention path, a device-side MoE scheduler on SYCL, decomposed Adreno FlashAttention in OpenCL, new WebGPU kernels, expanded Hexagon op coverage, and scheduler improvements that avoid uploading unused inputs.

## Assets

**Nightly build:** [b12359](https://github.com/ggml-org/llama.cpp/releases/tag/b12359)

## More info

- [Releases and versioning of `ggml-org` projects](https://github.com/ggml-org/ggml/discussions/1579)

## Changelog since [v0.9.0](https://github.com/ggml-org/llama.cpp/releases/tag/v0.9.0)

b1b770d90 examples : remove explict version from test-cmake (#32191)
4cda6227a llama.cpp : bump version to 1.0.0 (#32190)
685981335 sync : ggml
3bfde28f9 ggml : bump version to 1.0.0 (ggml/1690)
28d37fe2e examples : clean-up old/obsolete stuff (#32184)
bd2767d06 ci: fix HIP quality check by ignoring the FP8 vec FA kernel spill (#32183)
82503b42f ci : set windows-cuda ccache size to 1G (#32185)
5676dfbe0 chat : accept </ifm|think> as K2 Horizon closer at medium/low effort (#30335)
0a66ac718 server, fix CI: read a small temp file in the read_file tool test [no release] (#32168)
892b40b91 server: allow private media URLs in the vision tests [no ci] (#32167)
e97010147 server: skip LAN address tests when the host cannot reach it [no ci] (#32166)
92d6c8a5c fix(hexagon): make host build work with clang-cl on Windows ARM64 (#32011)
8ca5a8008 llama : prune (#30565)
29dbbad2b ggml : prune (#29801)
2a4daf0e0 hexagon: add Q5_0 and Q5_1 support (#32094)
d8c8cc4d9 server : cancel MCP tool calls on client disconnect or timeout (#32025)
3ba1ce0e2 qwen3.5: merge tensors on convert also (#32102)
0fb8f1577 Title: CUDA: few-row MMQ for BS 2-24 (#31533)
827466b9e ci : build ui on non-slim runner (#32138)
8954f1948 server: fix SSRF for CORS proxy and media URLs (#32115)
a1a68eb79 server: explicit opt-in tools via non-loopback addr, check cors host port (#32113)
e182fdad4 server: disallow direct access child instance from browser (#32120)
09452cded server: keep the server awake while a request uses its state (#32133)
cfb9d4b75 mtmd: require an F32 position embedding for HunyuanVL (#32131)
72f4603c7 mtmd: read the MiniCPM-V projection width from ne[1] (#32132)
8c388364e mtmd: require the MLP projector and patch embedding tensors (#32129)
08f49598c mtmd: require a 2x2 spatial merge for the Qwen-VL projectors (#32130)
a8575a3ef ggml : route GATED_DELTA_NET to the SpacemiT RVV kernel (#31897)
a963f6595 vulkan : Intel FA kernel for prefill. (#29357)
ab4a77b9a ggml-cpu: use the 4x4 simd_gemm tile on ARM NEON (#32128)
0d69255c5 CUDA: Optimize prefil via fuse of w_s scale in epilogue MMQ for nvfp4 checkpoints (#26048)
3bce8bd50 ggml-backend : prefetch only inputs computed by earlier splits (#32100)
81f21f4b2 ggml : dispatch SpacemiT Q4_1 32x256 through the HP kernel (#31929)
b19f1d9e6 ui: add search_chats tool (#32051)
d90cfd4a9 ui: install llama-brand from a GitHub tarball instead of git (#32112)
60d46a5ab server: when --tools-runtime is specified, ignore x-tool-runtime (#32119)
93cf736a8 chat : refactor gemma4 to build loose schema rules and clean up (#31915)
4fffab623 llama : avoid touching unused graph metadata pages (#32043)
09338b85e sycl: make oneDNN FA cache thread-safe and memoize runtime failures (#31138)
dcbff2166 sycl : fix AOT for more than 4GB (#31873)
f3d7725a7 sycl : use cached device-id in set_main_device (#32013)
7021f7e09 CUDA: add cuda debug buffer pool (#31919)
e0949d09b opencl: add bin kernel `kernel_gemm_noshuffle_q4_0_f32_32b_trans_ila_a7_bin` (#30947)
5d4c8eeb2 CUDA: skip empty MoE tiles in MMQ stream-k fixup (#32067)
dd6b945be server: use the moved test model in the router CORS test (#32117)
e1f7593c3 opencl: add decomposed FA for Adreno (#32046)
7bcbc04fb ui: move js sandbox setting out of "developer" (#32054)
dd00306bc docs: update image link in README.md (#32038)
1d8199278 ui: keep downloads in Discover during search and fix their progress with a draft (#31467)
bd717e08f ui: take the logo and favicons from the llama-brand package (#32039)
2cbe0ec42 server: fix --cors-origins handling + protect against DNS rebinding (#32098)
664f031f4 ci: move test models to ggml-org-dev (#32096)
4180722ee metal : prevent out-of-bounds reads in SOLVE_TRI kernel (#32103)
055c3c26e vulkan: support batched tensor copy API (#31418)
2656b71a1 vendor : update LibreSSL to 4.4.1 [no ci] (#32106)
cb44fdb18 llama : reuse graph result instances across scheduler reserves (#32089)
cd2db800d jinja : support chained comparisons and argument unpacking (#32072)
f7b886fe6 chat: allow TTS model to provide custom text normalizer via jinja (#32053)
956591f45 ci : remove dead snakes (#32084)
ccd360f06 llama : remove non-fused GDN and ubatch-dependent graph nodes (#32078)
b326dd675 devops : add missing MKL runtime DLLs to the Windows SYCL release package (#32005)
b8abe41a5 vendor: update cpp-httplib to 0.66.0 (#32049)
2e325dcd5 backend : re-instantiate CUDA graphs when the cluster dims of a kernel change (#31284)
1648d6411 test-fp8.cpp: use only the public ggml API (#32083)
432433637 ROCm/HIP: fixed BLAS workspace instead of rocBLAS allocating one per call (#31838)
71a6a114b quantize: fix imatrix GGUF filepath metadata leak (#32000)
7f24aacde cpu: accumulate flash attention V in F32 (#29810)
af6b5243d webgpu: add PAD_REFLECT_1D support (#31877)
d2b3eb9b6 vulkan: allow dequantized KV optimization with CM2 (#31526)
eeb210479 vulkan: allocate the device fault vendor binary buffer (#32008)
03d6c824e tests : use only the public ggml API (#32077)
adde94c11 ui: open the virtual keyboard in the chat editor on Android (#32060)
459ab1cdd cuda : use MMVF for BF16 matrices of few rows at small batch sizes (#31959)
77e2db8ca cuda : add sm70 FlashAttention config case for DKQ=256, DV=256, ncols=64 (#27997)
9d7b2d739 cuda : fattn mma head sizes 40 72 (#30285)
9e9619d03 CUDA: Add OCP FP8 support (#28413)
f3b407ca1 sycl : fixed sycl CLAMP to actually support strided view (#31784)
aa75ff323 chat : fix Muse Spark ignoring response_format json_schema (#32017)
b5cb8f6f4 ui: keep a hidden sidebar from intercepting clicks again (#32035)
85822a7ab ui: update the README banner to the new llama.cpp cover and remove the legacy brand assets (#31789)
2b66bfbf7 ui: show audio in Discover for models whose mmproj has an audio encoder (#31837)
582eab718 ci : bump ty to 0.0.100 (#32030)
7c2653acc mtmd: fix string format, rename to mtmd_format (#32040)
7592b61d3 ui: move Models, MCP and Settings to a sidebar footer (#32022)
cd4ed902e cuda : remove unused ids and type_src0 parameters (#32018)
202c1a229 llama : Add FP8 KV-cache support (#28392)
e24d0b4c3 Merge pull request #32015 from ggml-org/gg/fix-sampling-output-aliasing
3e86ce2c2 llama : reuse backend scheduler when sched_params are compatible (#32009)
494d0f47b ggml : add MUL_MAT src1 precision tests and gating (#31896)
281e7dad7 ui: gather chats into named groups in the sidebar (#32012)
90e3841d9 ui: show settings save button even while focused (#32010)
c75fba30c cuda : remove unused quantize_cuda_t typedef (#31884)
40f4f4ac9 graph: mark every sampling chain as an output to prevent aliasing
54cde7106 ui: expand the chat form into a large editor for longer messages (#31973)
7d6fd845e convert : mark Sarvam byte fallback tokens as BYTE (#32006)
4ed88da2e convert : workaround conversion for p-e-w/gpt-oss-20b-heretic-ara-v4 (#31860)
ac931b5bc cuda : halve VMM pool reservation size and retry on cuMemAddressReserve failure (#30542)
15759e0ca CUDA: skip graph compat check when graph is being reused (#32004)
a591cbe17 mtmd: share compute buffer among subcontext (#31945)
203b5f404 server: fix output lang for realtime api (#31982)
351025ec5 mtmd: add kimi K3.1 vision (#31980)
0d9eacadf ggml : fix FreeBSD Vulkan build by setting _XOPEN_SOURCE=700 (#31701)
17701e48d CUDA: move graph and concurrent stream state out of common.cuh (#32001)
ac007054e ui: use a live-preview markdown editor for the chat form input (#31955)
940a30ee3 model : stop renaming the recurrent cache tensors in plamo2 (#31984)
45c8ea837 common/json-schema : fix allOf with plain types (e.g. integer) generating an empty object grammar (#31834)
c90aa996b common : escape control characters in tool argument strings (#31937)
a2c942dcf cann: fail early when checking if buffer type is supported (#31270)
18c5a95e2 sycl: Add device-side MoE scheduler (#30156)
ae4893a09 vulkan: add tiled-transpose concat shader for Qwen models (#30591)
6122b566b ggml-rpc : fail gracefully on unreachable endpoints and failed handshakes (#30415)
3837bf0bc vulkan: Divide GROUP_NORM workgroup to 2D to avoid maxComputeWorkGroupCount limit (#31930)
c1a4febe9 vulkan: Fix out of bounds reads/writes on MoltenVK (#31890)
78ffbaa18 vulkan: cap scalar flash attention at 8 rows for large heads on Qualcomm (#30829)
58e38bdf6 llama : apply the iGPU lazy-mode fallback only when mmap is off (#31957)
d5bbcd1f3 ci: update oneAPI 2026.2, oneDNN 2026.1 and Level Zero SDK 1.34.0 (#31540)
8766c0273 sycl: un-gate oneDNN fused SDPA for Alchemist at head_dim=64 (#31574)
3b4d6ab3f chat : don't use lazy grammar when response_format is set with tools (#31956)
cf6463ace hexagon: fix 64-bit FastRPC handle truncation on close (#30952)
711f9f4c1 server: responses api: support conversion of text.format.json_schema to completions (#26145)
26d52b0f9 server : use common_chat_input in realtime api (#31978)
08f945ffb server: add oai-compat /v1/audio/speech endpoint (#31763)
20c2e9665 mtmd: support gemma 4 input audio stream (#31965)
3d94ffe45 mtmd: add mtmd_helper_resampler (#31964)
0a94a3f28 ui : retry opening the sidebar when a demo imports its traces (#31952)
610f7ab40 ui: make the app feel native on phones (#31949)
5f490d7bf feat: external PLE file loading (#31185)
9d340ec34 Windows unbuffered model load (#26014)
359dc5858 server : functionality test for new spec dec  (#31027)
a4d4f2fd4 ggml-zdnn: accept non-zdnn tensors, invalidate compute tensors after every op (#31824)
1945793e0 server : fix response_format json_schema when schema is not nested in the json_schema wrapper (#28697)
0eebb6edd ggml : implement the backward pass for TRI (#30712)
d628a98f0 tests : keep dummy ffn.act scales away from zero (#31940)
a8fad21e9 mtp: read the target hidden states from a device buffer (#31927)
b39680c41 ui: fold, preview and rearrange the sidebar's sections (#31936)
806b3c2be ggml-backend: don't upload inputs that are not read  (#31419)
0c6dca2fa models : Attach Granite NVFP4 weight scales (#31449)
fc0be8618 ci : Run gfx1151 ROCm job on Strix Halo Devlab runners (#31567)
e01c9f187 metal : prevent out-of-bounds writes to the Metal FA output buffer (#31662)
4b46d9653 metal : make ggml_tri select instead of scaling by the comparison (#30711)
f3178366b opencl : include climits (#31935)
2d99adb10 mtmd: Pocket TTS - add generic support for temperature set via API (#31655)
cf92c1323 RPC: Improve loading times (#29413)
9f0d80cf4 ggml : support YaRN truncation config on openvino, sycl, vulkan, webgpu, rpc (#30802)
a0ad695cb sycl: cache device-id (#31126)
6590d25a3 tests: bound the test_rope tolerance by the f32 angle resolution (#31874)
53eb66943 opencl: add f32 MUL_MAT_ID (#31783)
d78f4255d ggml-zdnn: fix release binary not detecting backend lib (#31905)
7d7f02875 mtmd: refactoring: remove clip.h, consolidate code into mtmd (#31865)
b65bf6921 cpu: enable SpacemiT IME2 MXFP4 dense repack (#31776)
a3c7cf08f llamafile: impl bf16 and q8_0 vxe (#31866)
57d04820d ggml : update CUDA/Metal radix Top-K to make tied selections deterministic (#31084)
998200491 ggml-cuda : add d_state=64 fast path to SSM_SCAN kernel (#31818)
cf34d3113 moe-cache : ensure CPU part does not wait for the cached experts (#31888)
a691b2345 webgpu : add COUNT_EQUAL support (#31578)
2277e7529 ci: move runners to Ubuntu 26.04 (#31529)
12ab59798 ggml : switch to F32 src1 in the CPU backend (#31854)
d6be06557 llama, mtmd: follow the reference precision of ggml_prec_set_acc calls (#31851)
a2b301831 speculative : do not apply the MoE cache to the draft model (#31497)
c19043f67 opencl: improve q8_0 and MoE small-n verification for spec (#31831)
372dc5ca1 common : sanitize invalid UTF-8 in PEG tool call arguments (#31861)
f477f795c server : downgrade per-request proxy logs to trace (#31859)
76a67730f hexagon: support for automatic loading of libhtp without legacy env vars (#31781)
12e9084dc sycl: exact rounding in CPY to Q4_1, Q5_1 and Q8_0 (#31465)
818ac6b07 sycl: refuse device buffers that would exceed VRAM (#31285)
e9a2a44fe hexagon: n_hvx and n_threads cleanup (#31857)
a2654ec43 mtmd: move log-mel computation to cgraph (#31808)
9f0e5098a mtmd: support MageVL-Cowork model (#31819)
e95426f16 llama_moe_cache: run missed experts on CPU, add tuning script (#30966)
f7591a6a0 sycl: add f16 support for SWIGLU_OAI (#30857)
80d2c0c2c metal : fix GROUP_NORM for ne03 > 1 and non-contiguous inputs (#31852)
095668452 server: visit parent slots before child slots (#30779)
cf659f240 webgpu :  Implement group norm kernel (#31490)
193815264 vulkan: Add 'readonly' to decodeBuf declarations. (#31833)
5d7d4aec1 CUDA: fix shared memory bank conflicts in the lightning indexer (#31803)
c0ab6e5c0 llama : add missing link to pthread (#31785)
31424b7cf opencl: add arange (#31829)
fd27b2034 meta : raise the compute view limit for buffers with few tensors (#31447)
ca89968a2 hexagon: fuse post-norm residual add into RMS_NORM_MUL (#31822)
bcb015287 model: add Kimi-K3.1-Pro text model (#31779)
669204ee2 hexagon: conv_2d optimizations and support for conv_3d (#31814)
954de248a docker: add explicit /usr/local/nvidia search path (#31806)
6c01da627 cli : fix crash on invalid UTF-8 in prompt or files (#31563)
8820b088d tests : qualify isnan and signbit with std:: (#31791)
9a1d03c7c tests : override hardware_concurrency in CI (#31797)
18ab62a8e cmake : generate RC file directly without win-app.rc.in (#31718)
52c9bad94 opencl:  support repeat for f16, i32, i16, bf16 (#31782)
5d3ed2ae7 webgpu: add batched tensor API (`get_tensor_n` and `set_tensor_n`) (#31473)
80088fa60 vulkan: detect ReBAR support, avoid BAR allocations if unavailable (#31658)
c4fb57969 moe-cache : LRFU/MQ-like hybrid cache, ClassLRU (#31233)
3ed7284f2 ci : bump CUDA 13 release builds to 13.5 (#31788)
d9cf1870b vendor: update BoringSSL to 0.20261105.0 (#31757)
240d68fcf CUDA: fix Maxwell build (#31787)
bbc2e4b65 common : restrict HF token to huggingface.co hosts (#31730)
4b77dee05 opencl: add q6_k multi column tiled GEMV for speculative verification and refactoring (#31758)
67107ac34 hexagon: Implement set_tensor_n and improve repacking/tiling robustness (#31744)
e14a77971 mtmd: enable cmake unity build (#31760)
d38bea342 tests : drop u8path() (#31755)
186eab1cb ci: fix build-cmake-pkg ccache (#31705)
6023692b1 llama: fix kv shifting, add tests, add per-model build_rope (#31683)
b1c902f02 llama, mtmd: (chatterbox) add use_classifier_free_guidance as gguf metadata (#31698)
e8df20d23 models : recursive fix (#31749)
fecdc81ee model : add Ripple (ricursiveai) (#31692)
45b6604b2 model: Add support for the xing4_0  (#31589)
e30ad80fd ui: prevent a hidden sidebar from intercepting clicks (#31712)
e0f96a1a1 llama: refactoring: move model to class member of llm_graph_context (#31733)
468fde90e server : simplify windows MCP command resolution (#31728)
1416f76aa vendor : update cpp-httplib to 0.65.0 (#31731)
10d4846a5 ggml-cuda: sanitize post-bias NaNs in MoE selection (#31005)
61d447234 vulkan: Implement test-fusion interface (#30769)
016c1d914 CUDA: use highest compiled arch in get_mmvq_mmid_max_batch (#31679)
da3416d80 vulkan: RDNA3/4 Large-Tile Split-K Optimization (#30280)
cc78da97c gguf-py : external chat templates have precedence over tokenizer_config (#31717)
ea40a3a1e metal : fuse DeepSeek-V4/V4.1 and GLM MoE routing (#31615)
15e50990b CUDA/HIP: matrix-core (MFMA) lightning indexer for CDNA2 (gfx90a) (#29050)
69ee2ecc0 CUDA: linearize MoE data layout for MMQ/MMF (#31047)
2bc46baa9 vulkan: FWHT kernels for block widths above 512 (#29772)
3b83d12b0 vulkan : check combined K+V f16 scratch size in FA dequant path (#30487)
e152332a1 llama-server: Use reference-counted checkpoints instead of deep-copies (#30137)
1fa7f1c48 ggml : support `truncate=false` for YaRN (#30206)
9c9074e14 conversion : resolve quantized_layers from source tensor names (#31611)
f7b41cca4 metal : use mul_mm for 32 <= K < 64 (#30982)
c55b09488 server : reject non-object session updates (#31714)
2c192444c fit : account for skipped NextN layers when setting n_gpu_layers (#31569)
553d2c2e7 webgpu : add MEAN support (#31591)
040ce199a graph: store the MTP conv snapshots of every recurrent model in one set_rows (#31660)
d4c345d6c ci : remove unused model generation (#31412)
2ada83079 common : drop u8path() and use generic_string() (#31681)
5a081c0a7 server : drop u8path() and use generic_string() (#31682)
7e42b95f2 rpc : align code with common.cpp (#31684)
3259ab6e5 vulkan: Re-enable large coopmat matmul configuration on AMD proprietary driver 26.10.1+ (#31587)
a01dff908 tests: fix CI flakes of TOPK_MOE caused by near ties (#31426)
44f91a02b metal: keep fusable node groups inside one command buffer (#31688)
330f0189c qwen2 : add nvfp4 scales to build_ffn (#31657)
7d516e25e opencl: enable f32 and q5_k multi column GEMV by default for Adreno X2 (#31694)
8bed7cfb9 opencl: support non-contig sigmoid (#31687)
8415bd7bb opencl: add DSV4_HC_PRE and DSV4_HC_POST (#31623)
5ce06fc71 Title: CUDA: fuse NVFP4 gate/up matmuls and GLU in MMQ (#31296)
e56f006ed llama : fix on-device state copy sizes for quantized KV caches (#30541)
3de52ac38 ci: run self hosted cpu jobs on hf or github (#31439)
6f1e65437 server : realtime: send an error event instead of crashing on exceptions (#31632)
9e2a04a43 opencl: improve decode perf with FA (#31633)
c6a0ff11a ui: open actions on right-click for chats, tabs, messages and models (#31545)
5851a8e50 model, mtmd: drama-3 tts support (#31613)
efbf6e80a ui: show text and page thumbnails for PDF attachments, stop endless conversion retries (#31468)
b393d73bb webgpu: return maxBufferSize from get_max_size and avoid whole-buffer bindings in memset/clear (#31348)
00df7c22d sycl : fix docker issue (#31605)
034e2535a gguf-py : validate every tokenizer merge pair, not only the first (#31631)
52e53a76d common : delete common_get_path_from_env() (#31444)

## 笔记


