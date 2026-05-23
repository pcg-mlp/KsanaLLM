/* Copyright 2024 Tencent Inc.  All rights reserved.

==============================================================================*/
#pragma once
#include "models/common/common_model.h"
#include "models/common/model_interface.h"

#include "cache_manager/cache_layout/base_cache_layout.h"
#include "models/communicator/tp_communicator.h"
#include "modules/attention/cross_layer_attention.h"
#include "modules/ffn/two_layered_ffn.h"

#include "modules/basic/moe.h"

namespace ksana_llm {

class HunyuanDecoderLayer {
 public:
  HunyuanDecoderLayer(int layer_idx, TensorBuffer* moe_buffer, int cla_share_factor, ClaBuffers& cla_buffers,
                      LayerCreationContext& creation_context, ModelCreationConfig& model_creation_config);
  ~HunyuanDecoderLayer() = default;

  Status Forward(std::vector<Tensor>& residual_buffer, const bool is_multi_token_forward,
                 ForwardingContext& forwarding_context);

 private:
  Status ForwardMlp(std::vector<Tensor>& hidden_buffer_tensors_0, std::vector<Tensor>& reduce_buffer_tensors,
                    const bool is_multi_token_forward, ForwardingContext& forwarding_context);

 private:
  int layer_idx_;
  std::shared_ptr<Add> adds_;
  std::shared_ptr<Layernorm> input_layernorms_;
  std::shared_ptr<Layernorm> post_attention_layernorms_;

  std::shared_ptr<CrossLayerAttention> cla_;

  std::shared_ptr<TwoLayeredFFN> shared_mlps_;
  std::shared_ptr<MoE> moes_;
  std::shared_ptr<Linear> expert_gates_;
  std::shared_ptr<TpCommunicator> tp_comm_;

  TensorBuffer* moe_buffer_;
};

class HunyuanLarge : public ModelInterface {
 public:
  HunyuanLarge() {}
  ~HunyuanLarge() = default;

  Status GetModelRunConfig(ModelRunConfig& model_run_config, const ModelConfig& model_config) override;
  Status CreateLayers(LayerCreationContext& creation_context, ModelCreationConfig& model_creation_config) override;
  Status Forward(std::vector<Tensor>& residual_buffer, ForwardingContext& forwarding_context) override;

 private:
  // for cla (if the model not use cross of attention, default nullptr)
  int cla_share_factor_;
  ClaBuffers cla_buffers_;
  TensorBuffer* moe_buffer_;

  std::map<int, std::shared_ptr<HunyuanDecoderLayer>> decoder_layers_;
};

class HunyuanLargeModel : public CommonModel {
 public:
  HunyuanLargeModel(const ModelConfig& model_config, const RuntimeConfig& runtime_config, const int rank,
                    std::shared_ptr<Context> context, std::shared_ptr<BaseWeight> base_weight,
                    std::shared_ptr<BaseModelCacheLayout> block_cache_layout);

 private:
  Status CreateLayers(LayerCreationContext& creation_context, ModelCreationConfig& model_creation_config) override;

  // Execute the forward of specific layers.
  Status LayerForward(ForwardingContext& forwarding_context, const RunMode run_mode = RunMode::kMain) override;

 protected:
  using CommonModel::GetHiddenUnitBufferTensors;

 private:
  HunyuanLarge hunyuan_large_;
};

}  // namespace ksana_llm
