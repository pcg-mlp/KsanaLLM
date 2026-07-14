/* Copyright 2024 Tencent Inc.  All rights reserved.

==============================================================================*/

#include <Python.h>
#include <stdlib.h>
#include <filesystem>

#include "models/quant/quant_weight.h"
#include "test.h"
#include "utils/singleton.h"

using namespace ksana_llm;

#ifdef ENABLE_CUDA
class QuantWeightTest : public testing::Test {
 protected:
  void SetUp() override {
    context_ = std::make_shared<Context>();
    // 解析 config.json,初始化 ModelConfig 以及 BlockManager
    std::filesystem::path current_path = __FILE__;
    std::filesystem::path parent_path = current_path.parent_path();
    std::filesystem::path config_path_relate = parent_path / "../../../../examples/llama7b/ksana_llm.yaml";
    std::string config_path = std::filesystem::absolute(config_path_relate).string();

    const auto& env = Singleton<Environment>::GetInstance();
    env->ParseConfig(config_path, "/model/hunyuan_large");
    env->GetModelConfig(model_config);

    BlockManagerConfig block_manager_config;
    env->InitializeBlockManagerConfig();
    env->GetBlockManagerConfig(block_manager_config);
    KLLM_LOG_DEBUG << fmt::format("block_size {}", block_manager_config.device_allocator_config.block_size);

    env->GetRuntimeConfig(runtime_config);

    CUDA_CHECK(cudaGetDevice(&device_rank));
    tensor_manager = std::make_shared<TensorManager>(device_rank, weights_map);
  }

#  ifdef ENABLE_FP8
  void AddFp8WeightTensor(std::string tensor_name, std::vector<size_t>& shape, float value) {
    tensor_manager->AddWeightTensor(tensor_name, shape, TYPE_FP8_E4M3);
    Tensor& tensor = weights_map[tensor_name];
    __nv_fp8_e4m3 fp8_value = __nv_fp8_e4m3(value);
    std::vector<__nv_fp8_e4m3> fp8_data(tensor.GetElementNumber(), fp8_value);
    MemcpyAsync(tensor.GetPtr<void>(), fp8_data.data(), tensor.GetTotalBytes(), MEMCPY_HOST_TO_DEVICE,
                context_->device->GetMemoryManageStream());
  }

  void AddFp8ScaleTensor(std::string tensor_name, float value) {
    std::vector<size_t> scale_shape = {1};
    tensor_manager->AddWeightTensor(tensor_name, scale_shape, TYPE_FP32);
    MemcpyAsync(weights_map[tensor_name].GetPtr<void>(), &value, sizeof(float), MEMCPY_HOST_TO_DEVICE,
                context_->device->GetMemoryManageStream());
  }
  // Passing different values into the tensor.
  void AddFp8BlockWiseWeightTensor(std::string tensor_name, std::vector<size_t>& shape, float value1, float value2) {
    tensor_manager->AddWeightTensor(tensor_name, shape, TYPE_FP8_E4M3);
    Tensor& tensor = weights_map[tensor_name];
    __nv_fp8_e4m3 fp8_value1 = __nv_fp8_e4m3(value1);
    std::vector<__nv_fp8_e4m3> fp8_data1((tensor.GetElementNumber() / 4 * 3), fp8_value1);
    MemcpyAsync(tensor.GetPtr<void>(), fp8_data1.data(), (tensor.GetTotalBytes() / 4 * 3), MEMCPY_HOST_TO_DEVICE,
                context_->device->GetMemoryManageStream());
    __nv_fp8_e4m3 fp8_value2 = __nv_fp8_e4m3(value2);
    std::vector<__nv_fp8_e4m3> fp8_data2((tensor.GetElementNumber() / 4), fp8_value2);
    MemcpyAsync(tensor.GetPtr<void>() + (tensor.GetTotalBytes() / 4 * 3), fp8_data2.data(), tensor.GetTotalBytes() / 4,
                MEMCPY_HOST_TO_DEVICE, context_->device->GetMemoryManageStream());
  }

  void AddFp8BlockWiseScaleTensor(std::string tensor_name, std::vector<size_t>& scale_shape, float value) {
    tensor_manager->AddWeightTensor(tensor_name, scale_shape, TYPE_FP32);
    Tensor& tensor = weights_map[tensor_name];
    std::vector<float> fp32_data(tensor.GetElementNumber(), value);
    MemcpyAsync(weights_map[tensor_name].GetPtr<void>(), fp32_data.data(), tensor.GetTotalBytes(),
                MEMCPY_HOST_TO_DEVICE, context_->device->GetMemoryManageStream());
  }

  std::vector<float> CopyFp8InputScales(std::string tensor_name) {
    Tensor& tensor = weights_map[tensor_name];
    size_t n = tensor.input_scales->shape[0];
    std::vector<float> input_scales(n);
    MemcpyAsync(input_scales.data(), tensor.input_scales->GetPtr<void>(), n * sizeof(float), MEMCPY_DEVICE_TO_HOST,
                context_->device->GetMemoryManageStream());
    StreamSynchronize(context_->device->GetMemoryManageStream());
    return input_scales;
  }

  std::vector<float> CopyFp8WeightScales(std::string tensor_name) {
    Tensor& tensor = weights_map[tensor_name];
    size_t n = tensor.weight_scales->shape[0];
    std::vector<float> weight_scales(n);
    MemcpyAsync(weight_scales.data(), tensor.weight_scales->GetPtr<void>(), n * sizeof(float), MEMCPY_DEVICE_TO_HOST,
                context_->device->GetMemoryManageStream());
    StreamSynchronize(context_->device->GetMemoryManageStream());
    return weight_scales;
  }

#  endif
  std::vector<half> CopyFp16Weight(std::string tensor_name) {
    Tensor& tensor = weights_map[tensor_name];
    std::vector<half> fp16_weight(tensor.GetElementNumber());
    MemcpyAsync(fp16_weight.data(), tensor.GetPtr<void>(), tensor.GetTotalBytes(), MEMCPY_DEVICE_TO_HOST,
                context_->device->GetMemoryManageStream());
    StreamSynchronize(context_->device->GetMemoryManageStream());
    return fp16_weight;
  }

  void TearDown() override {}

 protected:
  ModelConfig model_config;
  RuntimeConfig runtime_config;
  std::shared_ptr<Context> context_{nullptr};
  int32_t device_rank = 0;
  std::unordered_map<std::string, Tensor> weights_map;
  std::unordered_map<std::string, DataType> weights_data_type_map;
  std::shared_ptr<TensorManager> tensor_manager;
};

#  ifdef ENABLE_FP8
TEST_F(QuantWeightTest, BindFp8E4m3ScaleOfMoeWeight) {
  int num_layers = model_config.num_layer;
  // model_config.moe_config.num_experts;
  size_t num_experts = 4;
  // model_config.hidden_units;
  size_t hidden_units = 8;
  // model_config.moe_config.moe_inter_size;
  size_t inter_size = 8;

  // create weights
  std::vector<size_t> q_shape = {hidden_units, hidden_units};
  std::vector<size_t> shared_gate_shape = {inter_size, hidden_units};
  std::vector<size_t> shared_down_shape = {hidden_units, inter_size};
  std::vector<size_t> down_shape = {num_experts, hidden_units, inter_size};
  std::vector<size_t> up_gate_shape = {num_experts, 2 * inter_size, hidden_units};
  for (int layer_idx = 0; layer_idx < num_layers; ++layer_idx) {
    std::string prefix = "model.layers." + std::to_string(layer_idx);
    if (layer_idx % model_config.cla_share_factor == 0) {
      AddFp8WeightTensor(prefix + ".self_attn.q_proj.weight", q_shape, 1.0f);
    }
    AddFp8WeightTensor(prefix + ".mlp.shared_expert.gate_proj.weight", shared_gate_shape, 1.0f);
    AddFp8WeightTensor(prefix + ".mlp.shared_expert.up_proj.weight", shared_gate_shape, 1.0f);
    AddFp8WeightTensor(prefix + ".mlp.shared_expert.down_proj.weight", shared_down_shape, 1.0f);
    AddFp8WeightTensor(prefix + ".mlp.experts.down_proj.weight", down_shape, 1.0f);
    AddFp8WeightTensor(prefix + ".mlp.experts.up_gate_proj.weight", up_gate_shape, 1.0f);
  }

  // create scales
  std::vector<std::string> scale_names = {"input_scale", "weight_scale"};
  for (int layer_idx = 0; layer_idx < num_layers; ++layer_idx) {
    std::string prefix = "model.layers." + std::to_string(layer_idx);
    for (std::string scale_name : scale_names) {
      if (layer_idx % model_config.cla_share_factor == 0) {
        AddFp8ScaleTensor(prefix + ".self_attn.q_proj." + scale_name, 1.0f);
      }
      AddFp8ScaleTensor(prefix + ".mlp.shared_expert.gate_proj." + scale_name, 1.0f);
      AddFp8ScaleTensor(prefix + ".mlp.shared_expert.up_proj." + scale_name, 1.0f);
      AddFp8ScaleTensor(prefix + ".mlp.shared_expert.down_proj." + scale_name, 1.0f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.0.down_proj." + scale_name, 0.5f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.1.down_proj." + scale_name, 0.5f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.2.down_proj." + scale_name, 0.5f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.3.down_proj." + scale_name, 1.0f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.0.gate_proj." + scale_name, 0.25f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.1.gate_proj." + scale_name, 0.25f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.2.gate_proj." + scale_name, 0.25f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.3.gate_proj." + scale_name, 0.5f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.0.up_proj." + scale_name, 0.5f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.1.up_proj." + scale_name, 0.5f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.2.up_proj." + scale_name, 0.5f);
      AddFp8ScaleTensor(prefix + ".mlp.experts.3.up_proj." + scale_name, 1.0f);
    }
  }

  StreamSynchronize(context_->device->GetMemoryManageStream());

  QuantWeight<half> quant_weight =
      QuantWeight<half>(model_config, runtime_config, device_rank, context_, weights_map, weights_data_type_map);
  EXPECT_TRUE(quant_weight.BindFp8E4m3ScaleOfMoeWeight().OK());

  // check scales
  for (int layer_idx = 0; layer_idx < num_layers; ++layer_idx) {
    std::string prefix = "model.layers." + std::to_string(layer_idx);

    if (layer_idx % model_config.cla_share_factor == 0) {
      EXPECT_EQ(CopyFp8InputScales(prefix + ".self_attn.q_proj.weight")[0], 1.0f);
      EXPECT_EQ(CopyFp8WeightScales(prefix + ".self_attn.q_proj.weight")[0], 1.0f);
    }

    EXPECT_EQ(CopyFp8InputScales(prefix + ".mlp.shared_expert.gate_proj.weight")[0], 1.0f);
    EXPECT_EQ(CopyFp8WeightScales(prefix + ".mlp.shared_expert.gate_proj.weight")[0], 1.0f);

    EXPECT_EQ(CopyFp8InputScales(prefix + ".mlp.shared_expert.up_proj.weight")[0], 1.0f);
    EXPECT_EQ(CopyFp8WeightScales(prefix + ".mlp.shared_expert.up_proj.weight")[0], 1.0f);

    EXPECT_EQ(CopyFp8InputScales(prefix + ".mlp.shared_expert.down_proj.weight")[0], 1.0f);
    EXPECT_EQ(CopyFp8WeightScales(prefix + ".mlp.shared_expert.down_proj.weight")[0], 1.0f);

    std::vector<float> scales;
    EXPECT_EQ(CopyFp8InputScales(prefix + ".mlp.experts.down_proj.weight")[0], 1.0f);
    scales = CopyFp8WeightScales(prefix + ".mlp.experts.down_proj.weight");
    EXPECT_EQ(scales[0], 0.5f);
    EXPECT_EQ(scales[1], 0.5f);
    EXPECT_EQ(scales[2], 0.5f);
    EXPECT_EQ(scales[3], 1.0f);

    EXPECT_EQ(CopyFp8InputScales(prefix + ".mlp.experts.up_gate_proj.weight")[0], 1.0f);
    scales = CopyFp8WeightScales(prefix + ".mlp.experts.up_gate_proj.weight");
    EXPECT_EQ(scales[0], 0.5f);
    EXPECT_EQ(scales[1], 0.5f);
    EXPECT_EQ(scales[2], 0.5f);
    EXPECT_EQ(scales[3], 1.0f);
  }
}
#  endif
#endif
