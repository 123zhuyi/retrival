---
schema_version: okf.v1
kind: operator_optimization
type: optimization_runbook
source_family: runbooks
category: compute-pipeline
dimension: 2.3
title: 'Scheduling Optimization: hardware specific instruction'
description: 'matmul 场景下，Scheduling Optimization: hardware specific instruction，收益 25%'
tags: [多核并行与负载均衡, matrix-operations, matmul]
confidence: verified
status: verified
created_at: 2026-08-21T00:00:00Z
updated_at: 2026-08-21T00:00:00Z
---

## Scheduling Optimization: hardware specific instruction

【优化维度】：多核并行与负载均衡
【泛化层级】：条件性（迁移条件：硬件 910b2, 910b3, 91093, 91095；失效边界：依赖 dl 接口与 grouped_launch_diagonal 辅助函数，运行时缺失则不可用；NUM_HEADS 核内迭代在头数极大时片上压力上升；静态跨步调度要求各块负载大致均匀）

### 原则
- **hardware specific instruction**：Utilizes `dl.compile_hint` with the argument "dot_pad_only_k". This is a critical optimization for Ascend NPUs (910 series), instructing the compiler to pad only the K dimension of the matrix tiles. This minimizes the amount of zero-padding required for the dot product engine, thereby reducing memory traffic and increasing the effective throughput of the Cube unit.
- **batched head iteration**：The kernel iterates over `NUM_HEADS` inside the program body rather than flattening the head dimension into the global grid or launching separate kernels. This reduces kernel launch overhead and allows for efficient handling of the 3D tensor structure (Batch, Heads, Hidden) required by attention mechanisms.
- **static scheduling strategy**：Implements a static work distribution using the loop `for block_idx in range(pid, NUM_BLOCKS, NUM_CORES)`. This pattern statically assigns blocks to processing cores based on the program ID, avoiding the overhead of dynamic scheduling mechanisms and ensuring predictable memory access patterns across the NPU cores.
- **grouped launch diagonal**：Employs a `grouped_launch_diagonal` helper to map block indices to task coordinates. This suggests a diagonal or specific tiling traversal order which can improve cache locality for the matrix operands compared to a standard row-major or column-major traversal.
- **persistent kernel pattern**：Implements a grid-stride loop using `range(pid, NUM_BLOCKS, NUM_CORES)`, allowing a single program instance to process multiple output blocks sequentially. This reduces kernel launch overhead and improves hardware utilization by keeping cores active longer.
- **intra kernel batch iteration**：Manually iterates over the `NUM_HEADS` dimension inside the kernel body (`for head_idx in range(NUM_HEADS)`). This fuses the batch processing logic, avoiding the overhead of launching separate kernels for each attention head.
- **hardware specific padding hint**：Utilizes `dl.compile_hint(..., "dot_pad_only_k")` to provide explicit instructions to the compiler backend regarding padding strategy for the dot product operation. This ensures the data layout aligns with the requirements of the hardware's matrix compute unit (e.g., Cube unit), preventing performance penalties from implicit padding.
- **diagonal block mapping**：Uses `grouped_launch_diagonal` to map block indices to the M and N grid dimensions. This scheduling strategy often improves cache locality or load balancing compared to a simple row-major traversal.

### 代码/骨架出处
- `TritonPath`:
```python
raw_experiences/extracted_kernels/049-matmul_qn_kernel.py
```

**坏实践（反例）**：每个 head 单独 launch 一个 kernel → NUM_HEADS 次 launch 开销，小 head_dim 时调度主导时延 → ✅ 正解即本条：头维核内迭代 + persistent 跨步 + 对角块映射 + `dot_pad_only_k`。

**已知实例**：matmul §raw (`experiences/matmul/exp_matmul_qn_001.yaml`)
- 声称性能收益：25%
- 备注：This kernel is specifically designed for a projection step in attention-like mechanisms on Ascend hardware, leveraging the DeepLink (dl) interface for hardware-specific optimizations.

<!-- okf:related:start -->

# 相关

- 开发指南: [Ascend 910B2/910B3 Hardware Reference](../../reference/ascend-910b.md) — 同属优化知识，主题相关
- 开发指南: [Ascend NPU 特有语法与模式](../../reference/ascend-patterns.md) — 同属优化知识，主题相关
- 相关主题: [Memory Access Optimization: make block ptr hardware acceleration](../memory-sram/exp_causal_conv1d_update_003.md) — 同属优化知识，主题相关
- 相关主题: [MatMul 调度：对角遍历 grouped_launch + dot_pad_only_k hint + 寄存器原位累加](../portability/exp_matmul_ascend_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Scheduling Optimization: dynamic autotuning](exp_addmm_ascend_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Compute Optimization: block ptr utilization](exp_block_matmul_inv_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Scheduling Optimization: grouped scheduling](exp_bmm_grouped_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Compute Optimization: tiling strategy](exp_cube1_qk_gemm_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Scheduling Optimization: kernel fusion and recomputation](exp_entropy_backward_001.md) — 主题相关：共享 matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: persistent kernel grid stride](exp_entropy_backward_d_weight_001.md) — 主题相关：共享 matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: grid stride scheduling](exp_entropy_backward_fused_001.md) — 主题相关：共享 matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: grid stride loop](exp_flash_attn_gridstride_001.md) — 主题相关：共享 matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: operator fusion](exp_fused_attn_preprocess_001.md) — 主题相关：共享 matrix-operations, 多核并行与负载均衡
- 相关主题: [Compute Optimization: operator fusion](exp_fused_gemm_scale_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Scheduling Optimization: async pipeline scheduling](exp_fused_matmul_norm_sigmoid_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: operator fusion](exp_fused_matmul_rms_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: operator fusion](exp_fused_matmul_rmsnorm_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: operator fusion](exp_fused_matmul_rope_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: hardware unit isolation](exp_fused_norm_rope_matmul_001.md) — 主题相关：共享 matmul, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: dynamic work stealing](exp_grouped_gemm_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: dynamic load balancing](exp_grouped_gemm_bkmajor_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: dynamic load balancing](exp_grouped_gemm_bnmajor_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: dynamic load balancing](exp_grouped_matmul_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: dynamic load balancing](exp_grouped_matmul_bkmajor_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: activation recomputation](exp_hstu_attn_bwd_001.md) — 主题相关：共享 matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: static task scheduling](exp_hstu_attn_sched_001.md) — 主题相关：共享 matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: diagonal partitioning](exp_matmul_ascend_diag_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Compute Optimization: block tiling strategy](exp_matmul_bias_fused_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Scheduling Optimization: diagonal tiling strategy](exp_matmul_diag_tiling_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: micro tiling strategy](exp_matmul_small_tile_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Scheduling Optimization: block swizzling](exp_matmul_swizzle_hardware_hint_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Compute Optimization: small tile strategy](exp_matmul_triton_base_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Compute Optimization: vector parallelism strategy](exp_matmul_vec_parallel_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Compute Optimization: kernel fusion](exp_mhc_fused_gemm_sqrsum_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Scheduling Optimization: pid grouping strategy](exp_mm_grouped_reorder_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Compute Optimization: grid stride scheduling](exp_partial_matmul_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Scheduling Optimization: dynamic persistent scheduling](exp_partial_matmul_dynamic_001.md) — 主题相关：共享 matmul, matrix-operations, 多核并行与负载均衡
- 相关主题: [Compute Optimization: fused rope computation](exp_rope_matmul_fused_001.md) — 主题相关：共享 matmul, matrix-operations
- 相关主题: [Scheduling Optimization: block tiling strategy](exp_sdpa_bwd_kv_001.md) — 主题相关：共享 matrix-operations, 多核并行与负载均衡

<!-- okf:related:end -->
