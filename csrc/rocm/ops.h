#pragma once

#include <torch/all.h>

torch::Tensor LLMM1(at::Tensor& in_a, at::Tensor& in_b,
                    const int64_t rows_per_block);

torch::Tensor wvSplitK(const at::Tensor& in_a, const at::Tensor& in_b,
                       const std::optional<at::Tensor>& in_bias,
                       const int64_t CuCount);

torch::Tensor wvSplitK_int8(const at::Tensor& in_a, const at::Tensor& in_b,
                            const at::Tensor& in_scale,
                            const std::optional<at::Tensor>& in_bias,
                            const int64_t CuCount);

torch::Tensor wvSplitK_int4_g(const at::Tensor& in_a, const at::Tensor& in_b,
                              const at::Tensor& in_scale,
                              const std::optional<at::Tensor>& in_zero_points,
                              const std::optional<at::Tensor>& in_bias,
                              const int64_t CuCount, const int64_t group_size);

void fused_moe_wvSplitK_int4_gemm(torch::Tensor a, torch::Tensor w,
                                  torch::Tensor scales, torch::Tensor c,
                                  torch::Tensor expert_ids,
                                  int64_t block_size_m, int64_t CuCount,
                                  int64_t group_size, torch::Tensor zero_points,
                                  torch::Tensor sorted_token_ids,
                                  int64_t top_k);

// Fused GEMM1 + silu_and_mul + GEMM2 mega-kernel for the W4A16 MoE
// decode path on gfx1151.  Called when VLLM_MOE_HYBRID_W4A16_FUSED=1
// and the decode-shape preconditions hold (M=1, top_k>=1, GS=128,
// fp16, all groups share src_row).  Mutates `gemm2_out` in place and
// returns the same tensor so PyTorch's alias analysis tracks the
// output through torch.compile / FakeTensorMode.  See
// csrc/rocm/skinny_gemms_int4_fused.cu for invariants.
torch::Tensor fused_moe_wvSplitK_int4_megakernel(
    torch::Tensor a, torch::Tensor w1, torch::Tensor s1,
    torch::Tensor w2, torch::Tensor s2, torch::Tensor gemm2_out,
    torch::Tensor expert_ids, torch::Tensor sorted_token_ids,
    int64_t top_k, int64_t group_size, int64_t cu_count);

#ifdef VLLM_SKINNY_GEMM_SWEEP
torch::Tensor wvSplitK_sweep(const at::Tensor& in_a, const at::Tensor& in_b,
                             const std::optional<at::Tensor>& in_bias,
                             const int64_t CuCount, const int64_t ytile,
                             const int64_t unrl);

torch::Tensor wvSplitK_int8_sweep(const at::Tensor& in_a,
                                  const at::Tensor& in_b,
                                  const at::Tensor& in_scale,
                                  const std::optional<at::Tensor>& in_bias,
                                  const int64_t CuCount, const int64_t ytile,
                                  const int64_t unrl, const int64_t achunk,
                                  const int64_t wvprgrp);

torch::Tensor wvSplitK_int4g_sweep(
    const at::Tensor& in_a, const at::Tensor& in_b, const at::Tensor& in_scale,
    const int64_t CuCount, const int64_t group_size, const int64_t ytile,
    const int64_t unrl, const int64_t achunk, const int64_t wvprgrp);

torch::Tensor wvSplitK_int4g_hf_sweep(
    const at::Tensor& in_a, const at::Tensor& in_b, const at::Tensor& in_scale,
    const int64_t CuCount, const int64_t group_size, const int64_t ytile,
    const int64_t unrl, const int64_t achunk, const int64_t wvprgrp);
#endif

torch::Tensor wvSplitKrc(const at::Tensor& in_a, const at::Tensor& in_b,
                         const std::optional<at::Tensor>& in_bias,
                         const int64_t CuCount);

void wvSplitKQ(const at::Tensor& in_a, const at::Tensor& in_b,
               const std::optional<at::Tensor>& in_bias, at::Tensor& out_c,
               const at::Tensor& scale_a, const at::Tensor& scale_b,
               const int64_t CuCount);

void paged_attention(
    torch::Tensor& out, torch::Tensor& exp_sums, torch::Tensor& max_logits,
    torch::Tensor& tmp_out, torch::Tensor& query, torch::Tensor& key_cache,
    torch::Tensor& value_cache, int64_t num_kv_heads, double scale,
    torch::Tensor& block_tables, torch::Tensor& seq_lens,
    const std::optional<torch::Tensor>& query_start_loc, int64_t block_size,
    int64_t max_seq_len, const std::optional<torch::Tensor>& alibi_slopes,
    const std::string& kv_cache_dtype, torch::Tensor& k_scale,
    torch::Tensor& v_scale, const std::optional<torch::Tensor>& fp8_out_scale,
    const std::string& mfma_type);
