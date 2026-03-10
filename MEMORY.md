# MEMORY.md

## Submodule Branch Layout
- `dc/vulkan-split-mode-graph` — 6 commits: multi-GPU split mode graph for Vulkan (Phases 1-12)
- `dc/iqk-scalar-fallbacks` — 1 commit: graceful scalar fallbacks + AVX2 compile flags for non-AVX2 x86
- Branch prefix `dc/` follows upstream convention (`ik/`, `fcp/`, `s6/`)
- Commit messages use `vulkan:` or `iqk:` prefix (no phase references)
- Code comments must not reference phase numbers

## All Phases Complete
- Phases 1-10, 12 implemented. Phase 11 skipped (no opportunity with 3 graph splits).
- dmabuf zero-copy (Phase 12) dropped 7B overhead from ~15 ms/tok to ~1 ms/tok
- 13B multi-GPU faster than single-GPU for token generation (doubled memory bandwidth)

## CLAUDE.md Review (2026-03-08)
- Removed 28 "Phase N:" references from code comments across ggml-vulkan.cpp and ggml-vulkan-multigpu.cpp
- Moved AVX2 CMake compile flags from vulkan branch to IQK branch
- dmabuf detection mismatch in print_gpu_info accepted as cosmetic (device init does full probe)

## Hardware
- **Local (retro)**: Xeon X5650, Polaris 12 + lavapipe, no AVX2
- **Remote (target)**: Ryzen 9 3950X, RX 6800 XT + Vega 56/64, AVX2, ssh localhost -p 8022

## Phase 13: FUSED_UP_GATE
- Shader bug found and fixed: gate accumulation loop in mul_mm_fused_up_gate.comp was missing cache_b reload. With WNITER>1 and N<BN, gate pass reused stale zeros from UP pass, producing all-zero output.
- CPU backend ABORTs on FUSED_UP_GATE (no implementation). Tests use decomposed reference: separate mul_mat + fused_mul_unary on CPU, then compare via NMSE.
- K-quant types (Q4_K, Q6_K) have block size 256; test K dimensions must be multiples of block size, not just 32.
- GGML_VK_VISIBLE_DEVICES=0 limits to single GPU (VEGA10) — avoids dual-GPU init overhead in tests.
- 50/50 FUSED_UP_GATE tests pass, 1187/1187 standard backend-ops tests pass on RADV VEGA10.

## Bug Fixes Found During Testing (2026-03-09)
- **Empty-graph fence hang**: `graph_compute` set `compute_pending=true` unconditionally. Test framework sentinel nodes (GGML_OP_NONE) produce graphs with zero GPU submissions. Next `synchronize()` spins forever on unsignaled fence. Fix: guard with `submit_count > 0`.
- **MULTI_ADD descriptor range**: `ggml_vk_op_f32` has an incontiguous-op block that overwrites `x_sz` with `ggml_nbytes(src0)`. For MULTI_ADD's strided view_2d, this gives only the view's logical size, not the full expert data span the shader reads. With `robustBufferAccess`, out-of-range reads silently return 0 — shader appeared to sum only expert 0. Fix: override x_sz *after* the incontiguous block.
- **FUSED_UP_GATE M=1 NMSE instability**: Single-element output near zero produces huge NMSE from tiny absolute errors. Fixed by increasing K from 32 to 64 so the output has more signal.
- Final test counts: 1190 standard + 143 FUSED_UP_GATE + 12 MULTI_ADD all pass on RADV VEGA10.

## Nemotron Architecture Confusion (2026-03-09)
- Target model is **Nemotron-3-Nano-30B-A3B** which uses `nemotron_h_moe` (hybrid Mamba2+Attention+MoE), NOT `LLM_ARCH_DECI`.
- DECI is a pure transformer variant (Nemotron-51B, Ultra-253B). Different architecture entirely.
- `nemotron_h_moe` is not recognized by our ik_llama.cpp fork — needs architecture registration, graph builder, and 5 missing Vulkan ops (SSM_CONV, SSM_SCAN, SWIGLU, ADD_ID, SET_ROWS).
- Upstream llama.cpp (added as `llama.cpp` submodule) has full support including Vulkan shaders for all required ops.
- MUL_MAT_ID (expert matmul) is already in our fork's Vulkan backend.

## Submodule Layout Update
- `ik_llama.cpp` — our fork with multi-GPU split mode
- `llama.cpp` — upstream reference for nemotron_h_moe and other missing architectures

## Vulkan REDUCE Op (2026-03-09)
- REDUCE is a cross-device collective ADD used by split-mode graph (`-sm graph`). CUDA uses P2P `cudaMemcpyPeerAsync`; Vulkan has no P2P.
- Implemented as CPU-mediated host staging: `ggml_vk_buffer_read` from each device → CPU ADD → `ggml_vk_buffer_write` back.
- The scheduler's special REDUCE handling (identity tensor_id_copy, no n_inputs increment) was NOT changed — CUDA depends on it. Instead, REDUCE is handled entirely in the Vulkan backend.
- `ggml_vk_reduce()` is called from `graph_compute` before the dryrun/build loop, since REDUCE splits are always single-node graphs.
- Performance: CPU round-trip is slow for graph-split (193 splits, 6.5 tok/s). Layer-split (default, 3 splits, 18 tok/s) doesn't use REDUCE. Future: dmabuf GPU→GPU + ADD shader.

## Phase 18: dmabuf REDUCE (2026-03-10)
- Replaced CPU-mediated REDUCE with dmabuf GPU-to-GPU copy + ADD shader dispatch on destination device.
- Graph-split prompt eval: 9→47 tok/s (5.3×). Token gen: 6.5→7.8 tok/s (+20%).
- Token gen improvement modest because per-REDUCE data is small (6KB F16) — fence latency dominates, not bandwidth.
- Can't bind dmabuf import buffer directly as storage buffer (only eTransferSrc|eTransferDst). Must copy to temp device-local buffer first.
- Separate descriptor pool (1 set) for REDUCE's ADD dispatch avoids entangling with graph pipeline's descriptor management.

## Build Notes
- Use clang (GCC 15 has -Wtemplate-body errors)
- `-DGGML_IQK_FLASH_ATTENTION=OFF` on non-AVX2 hosts
- Remote: use absolute `-S`/`-B` paths with cmake (SSH starts in /home/llm)
