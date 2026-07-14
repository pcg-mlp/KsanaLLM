/* Copyright 2024 Tencent Inc.  All rights reserved.

==============================================================================*/
#pragma once

#include <memory>
#include <vector>
#ifdef ENABLE_CUDA
#  include "layers/custom_all_reduce_sum_layer.h"
#  include "layers/nccl_all_gather_layer.h"
#  include "layers/nccl_all_reduce_sum_layer.h"
#  include "layers/trt_all_reduce_sum_layer.h"
#elif defined(ENABLE_ACL)
#  include "layers/hccl_all_gather_layer.h"
#  include "layers/hccl_all_reduce_sum_layer.h"
#elif defined(ENABLE_TOPS)
#  include "layers/eccl_all_gather_layer.h"
#  include "layers/eccl_all_reduce_sum_layer.h"
#endif

namespace ksana_llm {

// The collective communicator library.
class ModelCommunicator {
 public:
  ModelCommunicator(Tensor* input, int rank, const RuntimeConfig& runtime_config, std::shared_ptr<Context> context);
  ~ModelCommunicator();

  // The all-gather reduce.
  Status AllGather(const std::vector<Tensor>& input_tensors, std::vector<Tensor>& output_tensors);

  // The reduce-sum reduce.
  Status ReduceSum(const std::vector<Tensor>& input_tensors, std::vector<Tensor>& output_tensors,
                   bool is_multi_token_forward, bool use_custom);

 private:
#ifdef ENABLE_CUDA
  // The default all reduce layer.
  std::shared_ptr<NcclAllReduceSumLayer> nccl_all_reduce_sum_layer_;

  // The all gather layer
  std::shared_ptr<NcclAllGatherLayer> nccl_all_gather_layer_;

  // The custom all reduce layer.
  std::shared_ptr<CustomAllReduceSumLayer> tp_custom_all_reduce_sum_layer_;

  // The trt all reduce layer.
  std::shared_ptr<TrtAllReduceSumLayer> tp_trt_all_reduce_sum_layer_;

  // This value is determined by the performance testing of
  // `3rdparty/LLM_kernels/csrc/kernels/nvidia/others/tensorrt-llm/main/communication_kernels/trtllm_all_reduce.h`
  size_t kTrtReduceThreshold = 256 * 7168 * 2;
#elif defined(ENABLE_ACL)
  // The default all reduce layer.
  std::shared_ptr<HcclAllReduceSumLayer> hccl_all_reduce_sum_layer_;

  // The all gather layer
  std::shared_ptr<HcclAllGatherLayer> hccl_all_gather_layer_;
#endif

 private:
  int rank_;
  std::shared_ptr<Context> context_;

  // For custom all reduce layer.
  Tensor tp_signal_tensor_;
  Tensor tp_custom_all_reduce_rank_tensor_;

  // Use for custom all reduce layer.
  Tensor* input_;

  // Whether the communication is finished.
  Event comm_finish_event_;

  uint32_t tp_size_ = 1;

  bool is_full_nvlink_ = false;

  bool select_all_reduce_by_size_ = false;

  static constexpr size_t kAllReduceThreshold = 8 * 1024 * 1024;  // 8MB

 private:
#ifdef ENABLE_CUDA
  void InitTensorParaCustomAllReduceSumLayer(Tensor* input, const RuntimeConfig& runtime_config);
#endif
};

}  // namespace ksana_llm
