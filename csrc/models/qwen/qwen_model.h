/* Copyright 2024 Tencent Inc.  All rights reserved.

==============================================================================*/
#pragma once

#include <unordered_map>

#include "models/common/model_interface.h"
#include "models/common/simple_decoder_layer.h"
#include "modules/basic/add.h"

namespace ksana_llm {

class Qwen : public ModelInterface {
 public:
  Qwen() {}
  ~Qwen() = default;

  Status GetModelRunConfig(ModelRunConfig& model_run_config, const ModelConfig& model_config) override;
  Status CreateLayers(LayerCreationContext& creation_context, ModelCreationConfig& model_creation_config) override;
  Status Forward(std::vector<Tensor>& residual_buffer, ForwardingContext& forwarding_context) override;
  Status InjectDeepstack(std::vector<Tensor>& residual_buffer, const ModelInput::DeepstackData& deepstack,
                         int layer_idx);

  // Add module for DeepStack injection (Qwen3-VL).
  std::shared_ptr<Add> deepstack_add_;

 private:
  std::unordered_map<int, std::shared_ptr<SimpleDecoderLayer>> decoder_layers_;
};

class QwenModel : public CommonModel {
 public:
  QwenModel(const ModelConfig& model_config, const RuntimeConfig& runtime_config, const int rank,
            std::shared_ptr<Context> context, std::shared_ptr<BaseWeight> base_weight);
  ~QwenModel() = default;

 private:
  Status CreateLayers(LayerCreationContext& creation_context, ModelCreationConfig& model_creation_config) override;
  Status LayerForward(ForwardingContext& forwarding_context, const RunMode run_mode = RunMode::kMain) override;

 protected:
  using CommonModel::GetHiddenUnitBufferTensors;

 private:
  Qwen qwen_;
};

}  // namespace ksana_llm
