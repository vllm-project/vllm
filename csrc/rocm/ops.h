#pragma once

#include <torch/all.h>

torch::Tensor LLMM1(at::Tensor& in_a, at::Tensor& in_b,
                    const int64_t rows_per_block);

torch::Tensor wvSplitK(const at::Tensor& in_a, const at::Tensor& in_b,
                       const std::optional<at::Tensor>& in_bias,
                       const int64_t CuCount);

torch::Tensor wvSplitKrc(const at::Tensor& in_a, const at::Tensor& in_b,
                         const std::optional<at::Tensor>& in_bias,
                         const int64_t CuCount);

void wvSplitKQ(const at::Tensor& in_a, const at::Tensor& in_b,
               const std::optional<at::Tensor>& in_bias, at::Tensor& out_c,
               const at::Tensor& scale_a, const at::Tensor& scale_b,
               const int64_t CuCount);

torch::Tensor gptq_gemm_rdna3(torch::Tensor a, torch::Tensor b_q_weight,
                              torch::Tensor b_qzeros, torch::Tensor b_scales,
                              torch::Tensor b_g_idx, bool use_v2_format);

torch::Tensor gptq_gemm_rdna3_wmma(torch::Tensor a, torch::Tensor b_q_weight,
                                   torch::Tensor b_qzeros,
                                   torch::Tensor b_scales,
                                   torch::Tensor b_g_idx, bool use_v2_format);

void moe_gptq_gemm_rdna3(torch::Tensor a, torch::Tensor c,
                         torch::Tensor b_q_weight, torch::Tensor b_scales,
                         torch::Tensor b_qzeros, torch::Tensor topk_weights,
                         torch::Tensor sorted_token_ids,
                         torch::Tensor expert_ids,
                         torch::Tensor num_tokens_post_padded, int64_t top_k,
                         int64_t block_size_m, bool mul_topk_weight,
                         int64_t output_topk);

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

void sparse_mla_decode_single(
    torch::Tensor q, torch::Tensor main_cache, torch::Tensor main_indices,
    torch::Tensor main_indptr, torch::Tensor extra_cache,
    torch::Tensor extra_indices, torch::Tensor extra_indptr,
    const std::optional<torch::Tensor>& attn_sink, torch::Tensor output,
    int64_t main_block_size, int64_t extra_block_size, int64_t main_num_rows,
    int64_t extra_num_rows, double scale, bool has_extra);

void sparse_mla_decode_split(
    torch::Tensor q, torch::Tensor main_cache, torch::Tensor main_indices,
    torch::Tensor main_indptr, torch::Tensor extra_cache,
    torch::Tensor extra_indices, torch::Tensor extra_indptr,
    const std::optional<torch::Tensor>& attn_sink, torch::Tensor output,
    torch::Tensor scratch_m, torch::Tensor scratch_l, torch::Tensor scratch_acc,
    int64_t main_block_size, int64_t extra_block_size, int64_t main_num_rows,
    int64_t extra_num_rows, double scale, bool has_extra, int64_t split_k);
