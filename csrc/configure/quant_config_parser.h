/* Copyright 2025 Tencent Inc.  All rights reserved.

==============================================================================*/

#pragma once

#include "configure/model_config_parser.h"
#include "nlohmann/json.hpp"

namespace ksana_llm {

// TODO(jinxcwu) 需要抽象成类

// Parse GPTQ quantization configuration
void ParseGPTQQuantConfig(const nlohmann::json &config_json, bool is_moe, QuantConfig &quant_config);

// Parse AWQ quantization configuration
void ParseAWQQuantConfig(const nlohmann::json &config_json, bool is_moe, QuantConfig &quant_config);

// Parse FP8 quantization configuration
void ParseFP8QuantConfig(const nlohmann::json &config_json, bool is_moe, QuantConfig &quant_config);

// Parse W4A8_AWQ quantization configuration
void ParseModelOptQuantConfig(const nlohmann::json &config_json, bool is_moe, QuantConfig &quant_config);

// Parse W4A8_KLX quantization configuration (Kunlun format)
// Used for Kimi-K2.6-klx-w4a8-gptq style models: INT8 per-channel weights, no activation scales.
void ParseW4A8KlxQuantConfig(QuantConfig &quant_config);

// Parse compressed-tensors quantization configuration
// Extracts GPTQ-equivalent parameters from config_groups and handles MoE ignore list.
// Populates quant_config and sub_quant_configs for MoE INT4 pattern.
void ParseCompressedTensorsQuantConfig(const nlohmann::json &quantization_config, bool is_moe,
                                       QuantConfig &quant_config, std::vector<QuantConfig> &sub_quant_configs);

// Parse and convert mixed precision quantization configuration from hf_quant_config.json
nlohmann::json ParseAndConvertQuantConfig(const nlohmann::json &hf_quant_config);

}  // namespace ksana_llm