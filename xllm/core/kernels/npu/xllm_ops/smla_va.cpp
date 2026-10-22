/* Copyright 2026 The xLLM Authors.

Licensed under the Apache License, Version 2.0 (the "License");
you may not use this file except in compliance with the License.
You may obtain a copy of the License at

    https://github.com/xLLM-AI/xllm/blob/main/LICENSE

Unless required by applicable law or agreed to in writing, software
distributed under the License is distributed on an "AS IS" BASIS,
WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
See the License for the specific language governing permissions and
limitations under the License.
==============================================================================*/

/*!
 * \file smla_va.cpp
 * \brief
 */

#include <glog/logging.h>
#include <torch/library.h>
#include <torch/torch.h>

#include <array>

#include "core/kernels/npu/aclnn/pytorch_npu_helper.hpp"
#include "core/kernels/npu/xllm_ops/xllm_ops_api.h"

namespace xllm::kernel::npu {
namespace {
constexpr int64_t kDim0 = 0;
constexpr int64_t kDim1 = 1;
constexpr int64_t kDim2 = 2;

// Metadata factories accept integer lengths/indices only. An absent input is
// represented by an empty int32 tensor on the metadata output device.
torch::Tensor get_valid_smla_tensor(const std::optional<torch::Tensor>& tensor,
                                    const torch::Device& device) {
  return tensor.has_value()
             ? tensor.value()
             : torch::empty(
                   {0},
                   torch::TensorOptions().dtype(torch::kInt32).device(device));
}

void check_query_shape(const torch::Tensor& q, const std::string& layout) {
  CHECK(layout == "TND" || layout == "BSND");
  CHECK_GT(q.numel(), 0);
  CHECK_EQ(q.dim(), layout == "TND" ? 3 : 4);
  for (const int64_t size : q.sizes()) {
    CHECK_GT(size, 0);
  }
}

int64_t get_kv_head_num(const std::optional<torch::Tensor>& ori_kv,
                        const std::optional<torch::Tensor>& cmp_kv,
                        const std::string& layout_kv_str) {
  CHECK(ori_kv.has_value() || cmp_kv.has_value());
  const torch::Tensor& kv =
      ori_kv.has_value() ? ori_kv.value() : cmp_kv.value();
  if (layout_kv_str == "TND") {
    return kv.size(kDim1);
  }
  return kv.size(kDim2);
}

std::tuple<torch::Tensor, torch::Tensor> make_smla_outputs(
    const torch::Tensor& q,
    const std::optional<torch::Tensor>& ori_kv,
    const std::optional<torch::Tensor>& cmp_kv,
    const std::string& layout_q_str,
    const std::string& layout_kv_str,
    bool return_softmax_lse) {
  check_query_shape(q, layout_q_str);
  torch::Tensor atten_out = torch::empty_like(q);
  torch::Tensor softmax_lse;
  if (!return_softmax_lse) {
    softmax_lse = torch::empty({0}, q.options().dtype(torch::kFloat32));
    return {atten_out, softmax_lse};
  }

  int64_t kv_head_num = get_kv_head_num(ori_kv, cmp_kv, layout_kv_str);
  CHECK_GT(kv_head_num, 0);
  const int64_t query_head_num = q.size(layout_q_str == "TND" ? kDim1 : kDim2);
  CHECK_EQ(query_head_num % kv_head_num, 0)
      << "SMLA query heads must be divisible by KV heads";
  if (layout_q_str == "BSND") {
    softmax_lse = torch::empty({q.size(kDim0),
                                kv_head_num,
                                q.size(kDim1),
                                q.size(kDim2) / kv_head_num},
                               q.options().dtype(torch::kFloat32));
  } else {
    softmax_lse =
        torch::empty({kv_head_num, q.size(kDim0), q.size(kDim1) / kv_head_num},
                     q.options().dtype(torch::kFloat32));
  }
  return {atten_out, softmax_lse};
}

}  // namespace

torch::Tensor smla_va_metadata(
    int64_t num_heads_q,
    int64_t num_heads_kv,
    int64_t head_dim,
    const std::optional<torch::Tensor>& cu_seqlens_q,
    const std::optional<torch::Tensor>& cu_seqlens_ori_kv,
    const std::optional<torch::Tensor>& cu_seqlens_cmp_kv,
    const std::optional<torch::Tensor>& seqused_q,
    const std::optional<torch::Tensor>& seqused_ori_kv,
    const std::optional<torch::Tensor>& seqused_cmp_kv,
    const std::optional<torch::Tensor>& cmp_residual_kv,
    const std::optional<torch::Tensor>& ori_topk_length,
    const std::optional<torch::Tensor>& cmp_topk_length,
    int64_t batch_size,
    int64_t max_seqlen_q,
    int64_t max_seqlen_ori_kv,
    int64_t max_seqlen_cmp_kv,
    int64_t ori_topk,
    int64_t cmp_topk,
    int64_t cmp_ratio,
    int64_t ori_mask_mode,
    int64_t cmp_mask_mode,
    int64_t ori_win_left,
    int64_t ori_win_right,
    c10::string_view layout_q,
    c10::string_view layout_kv,
    bool has_ori_kv,
    bool has_cmp_kv) {
  // With scalar-only metadata, allocate on the current NPU just as the
  // execution API does; CPU metadata is not a valid fallback for this op.
  torch::Device output_device(torch::kPrivateUse1);
  const std::array<const std::optional<torch::Tensor>*, 9> tensor_args = {
      &cu_seqlens_q,
      &cu_seqlens_ori_kv,
      &cu_seqlens_cmp_kv,
      &seqused_q,
      &seqused_ori_kv,
      &seqused_cmp_kv,
      &cmp_residual_kv,
      &ori_topk_length,
      &cmp_topk_length};
  for (const auto* arg : tensor_args) {
    if (arg->has_value()) {
      output_device = arg->value().device();
      break;
    }
  }

  torch::Tensor output =
      torch::zeros({kDsaMetadataBufferElements},
                   torch::dtype(torch::kInt32).device(output_device));
  auto cu_seqlens_q_val = get_valid_smla_tensor(cu_seqlens_q, output_device);
  auto cu_seqlens_ori_kv_val =
      get_valid_smla_tensor(cu_seqlens_ori_kv, output_device);
  auto cu_seqlens_cmp_kv_val =
      get_valid_smla_tensor(cu_seqlens_cmp_kv, output_device);
  auto seqused_q_val = get_valid_smla_tensor(seqused_q, output_device);
  auto seqused_ori_kv_val =
      get_valid_smla_tensor(seqused_ori_kv, output_device);
  auto seqused_cmp_kv_val =
      get_valid_smla_tensor(seqused_cmp_kv, output_device);
  auto cmp_residual_kv_val =
      get_valid_smla_tensor(cmp_residual_kv, output_device);
  auto ori_topk_length_val =
      get_valid_smla_tensor(ori_topk_length, output_device);
  auto cmp_topk_length_val =
      get_valid_smla_tensor(cmp_topk_length, output_device);

  // GetWorkspaceSize consumes layout attributes synchronously. The queued
  // execution receives only the resulting executor, not these host strings.
  const std::string layout_q_str(layout_q);
  const std::string layout_kv_str(layout_kv);
  const char* layout_q_ptr = layout_q_str.c_str();
  const char* layout_kv_ptr = layout_kv_str.c_str();

  EXEC_NPU_CMD(aclnnSmlaVaMetadata,
               cu_seqlens_q_val,
               cu_seqlens_ori_kv_val,
               cu_seqlens_cmp_kv_val,
               seqused_q_val,
               seqused_ori_kv_val,
               seqused_cmp_kv_val,
               cmp_residual_kv_val,
               ori_topk_length_val,
               cmp_topk_length_val,
               num_heads_q,
               num_heads_kv,
               head_dim,
               batch_size,
               max_seqlen_q,
               max_seqlen_ori_kv,
               max_seqlen_cmp_kv,
               ori_topk,
               cmp_topk,
               cmp_ratio,
               ori_mask_mode,
               cmp_mask_mode,
               ori_win_left,
               ori_win_right,
               layout_q_ptr,
               layout_kv_ptr,
               has_ori_kv,
               has_cmp_kv,
               output);
  return output;
}

std::tuple<torch::Tensor, torch::Tensor> smla_va(
    const torch::Tensor& q,
    const std::optional<torch::Tensor>& ori_kv,
    const std::optional<torch::Tensor>& cmp_kv,
    const std::optional<torch::Tensor>& ori_sparse_indices,
    const std::optional<torch::Tensor>& cmp_sparse_indices,
    const std::optional<torch::Tensor>& ori_block_table,
    const std::optional<torch::Tensor>& cmp_block_table,
    const std::optional<torch::Tensor>& cu_seqlens_q,
    const std::optional<torch::Tensor>& cu_seqlens_ori_kv,
    const std::optional<torch::Tensor>& cu_seqlens_cmp_kv,
    const std::optional<torch::Tensor>& seqused_q,
    const std::optional<torch::Tensor>& seqused_ori_kv,
    const std::optional<torch::Tensor>& seqused_cmp_kv,
    const std::optional<torch::Tensor>& cmp_residual_kv,
    const std::optional<torch::Tensor>& ori_topk_length,
    const std::optional<torch::Tensor>& cmp_topk_length,
    const std::optional<torch::Tensor>& sinks,
    const std::optional<torch::Tensor>& metadata,
    double softmax_scale,
    int64_t cmp_ratio,
    int64_t ori_mask_mode,
    int64_t cmp_mask_mode,
    int64_t ori_win_left,
    int64_t ori_win_right,
    c10::string_view layout_q,
    c10::string_view layout_kv,
    int64_t topk_value_mode,
    bool return_softmax_lse) {
  std::string layout_q_str = std::string(layout_q);
  std::string layout_kv_str = std::string(layout_kv);
  // The generated SMLA API takes char*, unlike the metadata API. Its layout
  // attributes are consumed by the synchronous GetWorkspaceSize call.
  char* layout_q_ptr = layout_q_str.data();
  char* layout_kv_ptr = layout_kv_str.data();

  auto [atten_out, softmax_lse] = make_smla_outputs(
      q, ori_kv, cmp_kv, layout_q_str, layout_kv_str, return_softmax_lse);

  EXEC_NPU_CMD(aclnnSmlaVa,
               q,
               ori_kv,
               cmp_kv,
               ori_sparse_indices,
               cmp_sparse_indices,
               ori_block_table,
               cmp_block_table,
               cu_seqlens_q,
               cu_seqlens_ori_kv,
               cu_seqlens_cmp_kv,
               seqused_q,
               seqused_ori_kv,
               seqused_cmp_kv,
               cmp_residual_kv,
               ori_topk_length,
               cmp_topk_length,
               sinks,
               metadata,
               softmax_scale,
               cmp_ratio,
               ori_mask_mode,
               cmp_mask_mode,
               ori_win_left,
               ori_win_right,
               layout_q_ptr,
               layout_kv_ptr,
               topk_value_mode,
               return_softmax_lse,
               atten_out,
               softmax_lse);
  return std::tuple<torch::Tensor, torch::Tensor>(atten_out, softmax_lse);
}

}  // namespace xllm::kernel::npu
