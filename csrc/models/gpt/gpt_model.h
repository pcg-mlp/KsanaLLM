/* Copyright 2024 Tencent Inc.  All rights reserved.

==============================================================================*/
#pragma once

#include "configure/environment.h"
#include "models/common/common_model.h"
#include "models/common/common_weight.h"
#include "models/common/model_interface.h"
#include "runtime/forward_request.h"
#include "utils/status.h"
#include "utils/utils.h"

#include "modules/basic/activation.h"
#include "modules/basic/add.h"
#include "modules/basic/layernorm.h"
#include "modules/basic/linear.h"

#include "models/communicator/tp_communicator.h"
#include "modules/attention/multihead_attention.h"
#include "modules/ffn/two_layered_ffn.h"

namespace ksana_llm {

class GPTDecoderLayer {
 public:
  GPTDecoderLayer(int layer_idx, LayerCreationContext& creation_context, ModelCreationConfig& model_creation_config,
                  TensorBuffer* mlp_temp_buffer_);
  ~GPTDecoderLayer() {}
  Status Forward(std::vector<Tensor>& residual_buffer, const bool is_multi_token_forward,
                 ForwardingContext& forwarding_context);

 private:
  Status ForwardMlp(std::vector<Tensor>& mlp_temp_buffer_tensors, std::vector<Tensor>& hidden_buffer_tensors_0,
                    std::vector<Tensor>& reduce_buffer_tensors, const bool is_multi_token_forward,
                    ForwardingContext& forwarding_context);

  Status ForwardMha(std::vector<Tensor>& hidden_buffer_tensors_0, std::vector<Tensor>& reduce_buffer_tensors,
                    const bool is_multi_token_forward, ForwardingContext& forwarding_context);

  Status FlashAttentionForward(std::vector<Tensor>& hidden_buffer_tensors_0,
                               std::vector<Tensor>& hidden_buffer_tensors_1, std::vector<Tensor>& reduce_buffer_tensors,
                               ForwardingContext& forwarding_context);

  Status PagedAttentionForward(std::vector<Tensor>& hidden_buffer_tensors_0,
                               std::vector<Tensor>& hidden_buffer_tensors_1, std::vector<Tensor>& reduce_buffer_tensors,
                               ForwardingContext& forwarding_context);

 private:
  int layer_idx_;
  std::shared_ptr<TpCommunicator> tp_comm_;
  std::shared_ptr<Layernorm> input_layernorms_;
  std::shared_ptr<Layernorm> post_attention_layernorms_;
  std::shared_ptr<Add> adds_;
  std::shared_ptr<Add> attn_proj_bias_add_;
  std::shared_ptr<Add> mlp_gate_bias_add_;
  std::shared_ptr<Add> mlp_down_proj_bias_add_;

  // ffn related
  std::shared_ptr<Linear> mlp_gate_proj_;
  std::shared_ptr<Linear> mlp_down_proj_;
  std::shared_ptr<Activation> activation_layer_;

  // buffer
  TensorBuffer* mlp_temp_buffer_;

  // attention
  std::shared_ptr<CommonAttention> attentions_;
  Tensor qkv_bias_;
  std::shared_ptr<Linear> attn_qkv_projs_;
};

class Gpt : public ModelInterface {
 public:
  Gpt() {}
  ~Gpt() = default;
  Status GetModelRunConfig(ModelRunConfig& model_run_config, const ModelConfig& model_config) override;
  Status CreateLayers(LayerCreationContext& creation_context, ModelCreationConfig& model_creation_config) override;
  Status Forward(std::vector<Tensor>& residual_buffer, ForwardingContext& forwarding_context) override;

 private:
  std::map<int, std::shared_ptr<GPTDecoderLayer>> decoder_layers_;
  std::shared_ptr<Activation> activation_layer_;
  TensorBuffer* mlp_temp_buffer_;
};

class GptModel : public CommonModel {
 public:
  GptModel(const ModelConfig& model_config, const RuntimeConfig& runtime_config, const int rank,
           std::shared_ptr<Context> context, std::shared_ptr<BaseWeight> base_weight);
  ~GptModel() {}

 private:
  Status CreateLayers(LayerCreationContext& creation_context, ModelCreationConfig& model_creation_config) override;

  // Execute the forward of specific layers.
  Status LayerForward(ForwardingContext& forwarding_context, const RunMode run_mode = RunMode::kMain) override;

  void InitRunConfig(const ModelRunConfig& model_run_config, std::shared_ptr<BaseWeight> base_weight);

 protected:
  using CommonModel::GetHiddenUnitBufferTensors;

 private:
  ModelConfig model_config_;

 private:
  Gpt gpt_;
};

}  // namespace ksana_llm
