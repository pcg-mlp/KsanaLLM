/* Copyright 2024 Tencent Inc.  All rights reserved.

==============================================================================*/

#include "configure/environment.h"

#include <filesystem>
#include <string>

#include "gflags/gflags.h"
#include "helpers/block_cache_layout_helper.h"
#include "helpers/model_test_helper.h"
#include "test.h"

namespace ksana_llm {

DEFINE_string(config_file_test, "examples/ksana_llm.yaml", "The config file path");

class EnvironmentTest : public ::testing::Test {
 protected:
  static void SetUpTestSuite() { InitLoguru(); }

  void SetUp() override {
    std::filesystem::path current_path = __FILE__;
    std::filesystem::path parent_path = current_path.parent_path();
    FLAGS_config_file_test = parent_path / "../../examples/llama7b/ksana_llm.yaml";
    env_ = std::make_shared<ksana_llm::Environment>();
  }

  std::shared_ptr<ksana_llm::Environment> env_;
};

// 测试配置文件解析
TEST_F(EnvironmentTest, ParseConfig) {
  auto status = env_->ParseConfig(FLAGS_config_file_test);
  EXPECT_TRUE(status.OK()) << status.GetMessage();
}

// 测试获取BatchSchedulerConfig
TEST_F(EnvironmentTest, GetBatchSchedulerConfig) {
  // 先解析配置
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  // 获取配置并验证
  ksana_llm::BatchSchedulerConfig config;
  auto status = env_->GetBatchSchedulerConfig(config);
  EXPECT_TRUE(status.OK());

  // 验证关键配置参数
  EXPECT_GT(config.max_token_len, 0);
  EXPECT_GT(config.max_batch_size, 0);
  EXPECT_GT(config.max_step_token_num, 0);
  EXPECT_GT(config.waiting_timeout_in_ms, 0);
  EXPECT_GT(config.max_waiting_queue_len, 0);
}

// 测试获取CacheManagerConfig
TEST_F(EnvironmentTest, GetCacheManagerConfig) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::CacheManagerConfig config;
  auto status = env_->GetCacheManagerConfig(config);
  EXPECT_TRUE(status.OK());

  EXPECT_GT(config.swap_threadpool_size, 0);
  EXPECT_GE(config.min_flexible_cache_num, 0);
  EXPECT_GT(config.block_token_num, 0);
  EXPECT_GT(config.tensor_para_size, 0);
}

// 测试获取BlockManagerConfig
TEST_F(EnvironmentTest, GetBlockManagerConfig) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());
  ModelConfig model_config;
  env_->GetModelConfig(model_config);
  InitPipelineConfigForTest(env_, model_config);
  auto block_cache_layout = GetTestModelCacheLayout(env_);
  ASSERT_TRUE(env_->InitializeBlockManagerConfig(block_cache_layout).OK());

  ksana_llm::BlockManagerConfig config;
  auto status = env_->GetBlockManagerConfig(config);
  EXPECT_TRUE(status.OK());

  // 验证配置参数
  EXPECT_GT(config.host_allocator_config.block_size, 0);
  EXPECT_GT(config.device_allocator_config.block_size, 0);
  EXPECT_GT(config.host_allocator_config.blocks_num, 0);
  EXPECT_GT(config.device_allocator_config.blocks_num, 0);
  EXPECT_GT(config.reserved_device_memory_ratio, 0);
}

// 测试获取ModelConfig
TEST_F(EnvironmentTest, GetModelConfig) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::ModelConfig config;
  auto status = env_->GetModelConfig(config);
  EXPECT_TRUE(status.OK());

  // 验证模型配置
  EXPECT_FALSE(config.type.empty());
  EXPECT_GT(config.vocab_size, 0);
  EXPECT_GT(config.hidden_units, 0);
  EXPECT_GT(config.num_layer, 0);
  EXPECT_GT(config.head_num, 0);
  EXPECT_GT(config.size_per_head, 0);

  // Test rope scaling factor
  EXPECT_EQ(config.rope_scaling_factor_config.type, "default");
  EXPECT_TRUE(config.rope_scaling_factor_config.mrope_section.empty());

  // 创建一个包含自定义模型配置的临时YAML文件
  auto create_model_config_yaml = [](const std::string& rope_type,
                                     const std::vector<int>& mrope_section) -> std::string {
    std::filesystem::path temp_dir = std::filesystem::temp_directory_path();
    std::string filename = "ksana_model_config_test.yaml";
    std::filesystem::path temp_file_path = temp_dir / filename;

    std::filesystem::path model_dir = temp_dir / "ksana_test_model_dir";
    try {
      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
      std::filesystem::create_directory(model_dir);

      std::ofstream file(temp_file_path);
      if (!file.is_open()) {
        return "";
      }

      // 添加包含模型配置的YAML内容
      file << "setting:\n";
      file << "  global:\n";
      file << "    tensor_para_size: 1\n";
      file << "    pipeline_para_size: 1\n";
      file << "  batch_scheduler:\n";
      file << "    max_waiting_queue_len: 100\n";
      file << "    max_token_len: 4096\n";
      file << "    max_step_tokens: 4096\n";
      file << "    max_batch_size: 32\n";
      file << "  block_manager:\n";
      file << "    block_token_num: 16\n";
      file << "    reserved_device_memory_ratio: 0.01\n";
      file << "model_spec:\n";
      file << "  base_model:\n";
      file << "    model_dir: \"" << model_dir.string() << "\"\n";

      file.close();

      // 创建模型配置文件
      std::ofstream config_json(model_dir / "config.json");
      if (config_json.is_open()) {
        config_json << "{\n";
        config_json << "  \"architectures\": [\"LlamaForCausalLM\"],\n";
        config_json << "  \"model_type\": \"llama\",\n";
        config_json << "  \"torch_dtype\": \"float16\",\n";
        config_json << "  \"vocab_size\": 32000,\n";
        config_json << "  \"hidden_size\": 4096,\n";
        config_json << "  \"intermediate_size\": 11008,\n";
        config_json << "  \"num_attention_heads\": 32,\n";
        config_json << "  \"num_key_value_heads\": 32,\n";
        config_json << "  \"num_hidden_layers\": 32,\n";
        config_json << "  \"max_position_embeddings\": 4096,\n";
        config_json << "  \"bos_token_id\": 1,\n";
        config_json << "  \"eos_token_id\": 2,\n";
        config_json << "  \"pad_token_id\": 0,\n";
        // 自定义rope_scaling
        config_json << "  \"rope_scaling\": {\n";
        config_json << "    \"type\": \"" << rope_type << '"';
        if (!mrope_section.empty()) {
          EXPECT_EQ(mrope_section.size(), 3);
          config_json << ",\n";
          config_json << "    \"mrope_section\": [\n";
          for (int i = 0; i < 3; i++) {
            config_json << "      " << mrope_section[i];
            if (i < 2) {
              config_json << ',';
            }
            config_json << '\n';
          }
          config_json << "    ]\n";
        } else {
          config_json << '\n';
        }
        config_json << "  }\n";
        config_json << "}\n";
        config_json.close();
      }

      return temp_file_path.string();
    } catch (const std::exception& e) {
      return "";
    }
  };

  // Case 1: type = "default", mropse_section != None
  {
    std::string yaml_path = create_model_config_yaml("default", {16, 24, 24});
    ASSERT_FALSE(yaml_path.empty());

    Environment test_env;
    EXPECT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ksana_llm::ModelConfig config;
    EXPECT_TRUE(test_env.GetModelConfig(config).OK());

    EXPECT_EQ(config.rope_scaling_factor_config.type, "mrope");
    EXPECT_EQ(config.rope_scaling_factor_config.mrope_section.size(), 3);

    // 清理临时文件
    try {
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::filesystem::path model_dir = temp_dir / "ksana_test_model_dir";

      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }
      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }
}

// 测试获取ProfilerConfig
TEST_F(EnvironmentTest, GetProfilerConfig) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::ProfilerConfig config;
  auto status = env_->GetProfilerConfig(config);
  EXPECT_TRUE(status.OK());
  EXPECT_GT(config.export_interval_millis, 0);
  EXPECT_GT(config.export_timeout_millis, 0);
}

// 测试错误的配置文件路径
TEST_F(EnvironmentTest, ParseConfigError) {
  auto status = env_->ParseConfig("non_exist_config.yaml");
  EXPECT_FALSE(status.OK());
}

// 测试前缀缓存功能状态
TEST_F(EnvironmentTest, PrefixCachingStatus) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::BatchSchedulerConfig config;
  auto status = env_->GetBatchSchedulerConfig(config);
  EXPECT_TRUE(status.OK());
}

// 测试设备兼容性检查
TEST_F(EnvironmentTest, DeviceCompatibilityCheck) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::RuntimeConfig config;
  auto status = env_->GetRuntimeConfig(config);
  EXPECT_TRUE(status.OK());

  // 验证设备相关配置
  EXPECT_GT(config.parallel_basic_config.tensor_parallel_size, 0);
}

// 测试配置参数边界条件
TEST_F(EnvironmentTest, ConfigBoundaryConditions) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::BatchSchedulerConfig batch_config;
  auto status = env_->GetBatchSchedulerConfig(batch_config);
  EXPECT_TRUE(status.OK());

  // 验证参数边界
  EXPECT_GT(batch_config.max_token_len, 0);
  EXPECT_LE(batch_config.max_token_len, 32768);  // 合理的上限

  EXPECT_GT(batch_config.max_batch_size, 0);
  EXPECT_LE(batch_config.max_batch_size, 1024);  // 合理的上限

  EXPECT_GT(batch_config.waiting_timeout_in_ms, 0);
  EXPECT_GT(batch_config.max_waiting_queue_len, 0);
}
// 测试配置项依赖关系
TEST_F(EnvironmentTest, ConfigDependencies) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::ModelConfig model_config;
  auto status = env_->GetModelConfig(model_config);
  EXPECT_TRUE(status.OK());

  // 验证量化配置依赖
  if (model_config.quant_config.method == ksana_llm::QUANT_GPTQ) {
    EXPECT_GT(model_config.quant_config.bits, 0);
    EXPECT_GT(model_config.quant_config.group_size, 0);
  }
}

// 测试配置文件完整性
TEST_F(EnvironmentTest, ConfigFileIntegrity) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  // 验证必需的配置部分
  ksana_llm::BatchSchedulerConfig batch_config;
  EXPECT_TRUE(env_->GetBatchSchedulerConfig(batch_config).OK());

  ksana_llm::BlockManagerConfig block_config;
  EXPECT_TRUE(env_->GetBlockManagerConfig(block_config).OK());

  ksana_llm::ProfilerConfig profiler_config;
  EXPECT_TRUE(env_->GetProfilerConfig(profiler_config).OK());
}

// 测试必需参数验证
TEST_F(EnvironmentTest, RequiredParametersValidation) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::ModelConfig model_config;
  auto status = env_->GetModelConfig(model_config);
  EXPECT_TRUE(status.OK());
  RuntimeConfig runtime_config;
  env_->GetRuntimeConfig(runtime_config);

  // 验证必需的模型参数
  EXPECT_FALSE(model_config.type.empty());
  EXPECT_GT(model_config.vocab_size, 0);
  EXPECT_GT(model_config.hidden_units, 0);
  EXPECT_GT(model_config.num_layer, 0);
  EXPECT_GT(model_config.head_num, 0);
  EXPECT_GT(model_config.size_per_head, 0);
  EXPECT_GT(runtime_config.max_seq_len, 0);
}

// 测试性能相关配置
TEST_F(EnvironmentTest, PerformanceConfig) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  // 验证线程池配置
  ksana_llm::CacheManagerConfig cache_config;
  auto status = env_->GetCacheManagerConfig(cache_config);
  EXPECT_TRUE(status.OK());
  EXPECT_GT(cache_config.swap_threadpool_size, 0);

  // 验证批处理配置
  ksana_llm::BatchSchedulerConfig batch_config;
  status = env_->GetBatchSchedulerConfig(batch_config);
  EXPECT_TRUE(status.OK());
  EXPECT_GT(batch_config.max_batch_size, 0);
  EXPECT_GT(batch_config.max_step_token_num, 0);
}

// 测试内存策略配置
TEST_F(EnvironmentTest, MemoryStrategyConfig) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::BlockManagerConfig block_config;
  auto status = env_->GetBlockManagerConfig(block_config);
  EXPECT_TRUE(status.OK());

  // 验证内存分配策略
  EXPECT_EQ(block_config.host_allocator_config.block_size, 0);
  EXPECT_EQ(block_config.device_allocator_config.block_size, 0);
  EXPECT_EQ(block_config.host_allocator_config.blocks_num, 0);
  EXPECT_EQ(block_config.device_allocator_config.blocks_num, 0);

  // 验证内存比例配置
  EXPECT_GT(block_config.reserved_device_memory_ratio, 0.0f);
  EXPECT_LT(block_config.reserved_device_memory_ratio, 1.0f);
}

// 测试连接器配置初始化
TEST_F(EnvironmentTest, ConnectorConfigInitialization) {
  // 辅助函数，创建一个带有connector配置和基本模型配置的临时YAML文件
  auto create_temp_yaml = [](const std::string& role, const std::string& comm_type = "") -> std::string {
    // 使用std::filesystem的临时目录路径，而不是硬编码路径
    std::filesystem::path temp_dir = std::filesystem::temp_directory_path();
    std::string filename = "ksana_connector_test_" + role + ".yaml";
    std::filesystem::path temp_file_path = temp_dir / filename;

    // 使用绝对路径创建模型目录
    std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);
    try {
      // 确保模型目录存在
      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
      std::filesystem::create_directory(model_dir);

      std::ofstream file(temp_file_path);
      if (!file.is_open()) {
        std::cerr << "Failed to open file: " << temp_file_path.string() << std::endl;
        return "";
      }

      // 添加基本配置，包括必要的模型规格，这样即使不加载外部模型配置文件也能解析
      file << "setting:\n";
      file << "  connector:\n";
      file << "    group_role: " << role << "\n";
      if (role != "none" && role != "invalid_role") {
        file << "    router_addr: \"localhost:9090\"\n";
        file << "    inference_addr: \"localhost:9091\"\n";
        file << "    cluster_name: \"default_cluster\"\n";
        file << "    heartbeat_interval_ms: 2000\n";
        if (!comm_type.empty()) {
          file << "    communication_type: " << comm_type << "\n";
        }
      }
      file << "  global:\n";
      file << "    tensor_para_size: 1\n";
      file << "    pipeline_para_size: 1\n";

      // 添加模型规格部分，这样即使不加载外部模型配置也能初始化
      file << "  batch_scheduler:\n";
      file << "    max_waiting_queue_len: 100\n";
      file << "    max_token_len: 4096\n";
      file << "    max_step_tokens: 4096\n";
      file << "    max_batch_size: 32\n";
      file << "    enable_auto_prefix_cache: true\n";
      file << "    split_fuse_token_num: 256\n";

      file << "  block_manager:\n";
      file << "    block_token_num: 16\n";
      file << "    reserved_device_memory_ratio: 0.01\n";

      file << "model_spec:\n";
      file << "  base_model:\n";
      file << "    model_dir: \"" << model_dir.string() << "\"\n";

      file.close();

      // 创建模型配置目录和config.json文件
      std::ofstream config_json(model_dir / "config.json");
      if (config_json.is_open()) {
        // 创建一个最小化的配置JSON
        config_json << "{\n";
        config_json << "  \"architectures\": [\"LlamaForCausalLM\"],\n";
        config_json << "  \"model_type\": \"llama\",\n";
        config_json << "  \"torch_dtype\": \"float16\",\n";
        config_json << "  \"vocab_size\": 32000,\n";
        config_json << "  \"hidden_size\": 4096,\n";
        config_json << "  \"intermediate_size\": 11008,\n";
        config_json << "  \"num_attention_heads\": 32,\n";
        config_json << "  \"num_key_value_heads\": 32,\n";
        config_json << "  \"num_hidden_layers\": 32,\n";
        config_json << "  \"max_position_embeddings\": 4096,\n";
        config_json << "  \"bos_token_id\": 1,\n";
        config_json << "  \"eos_token_id\": 2,\n";
        config_json << "  \"pad_token_id\": 0\n";
        config_json << "}\n";
        config_json.close();
      } else {
        std::cerr << "Failed to create config.json in: " << (model_dir / "config.json").string() << std::endl;
      }

      return temp_file_path.string();
    } catch (const std::exception& e) {
      std::cerr << "Exception: " << e.what() << std::endl;
      return "";
    }
  };

  // 测试前准备 - 存储原始配置文件路径，以便测试后恢复
  std::string orig_config_file = FLAGS_config_file_test;

  // 测试1：group_role = "none" 的情况
  {
    std::string yaml_path = create_temp_yaml("none");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    auto parse_status = test_env.ParseConfig(yaml_path);
    if (!parse_status.OK()) {
      std::cerr << "Failed to parse config: " << parse_status.GetMessage() << std::endl;
      ASSERT_TRUE(false);
    }

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_FALSE(status.OK());
    EXPECT_EQ(status.GetCode(), ksana_llm::RET_CONFIG_NOT_FOUND);

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "none";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试2：group_role = "prefill" 的情况
  {
    std::string yaml_path = create_temp_yaml("prefill");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(connector_config.group_role, ksana_llm::GroupRole::PREFILL);
    EXPECT_EQ(connector_config.router_addr, "http://localhost:9090");
    EXPECT_EQ(connector_config.inference_addr, "localhost:9091");
    EXPECT_EQ(connector_config.cluster_name, "default_cluster");
    EXPECT_EQ(connector_config.heartbeat_interval_ms, 2000);
    EXPECT_EQ(connector_config.communication_type, ksana_llm::CommunicationType::TCP);  // 默认值

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "prefill";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试3：group_role = "decode" 的情况
  {
    std::string yaml_path = create_temp_yaml("decode");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(connector_config.group_role, ksana_llm::GroupRole::DECODE);
    EXPECT_EQ(connector_config.communication_type, ksana_llm::CommunicationType::TCP);  // 默认值

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "decode";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试4：group_role = "both" 的情况
  {
    std::string yaml_path = create_temp_yaml("both");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(connector_config.group_role, ksana_llm::GroupRole::BOTH);
    EXPECT_EQ(connector_config.communication_type, ksana_llm::CommunicationType::TCP);  // 默认值

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "both";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试5：无效的 group_role 值
  {
    std::string yaml_path = create_temp_yaml("invalid_role");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_FALSE(status.OK());  // 无效的角色会被设置为NONE，所以获取配置应该失败
    EXPECT_EQ(status.GetCode(), ksana_llm::RET_CONFIG_NOT_FOUND);

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "invalid_role";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试6：communication_type = "nccl" 的情况
  {
    std::string yaml_path = create_temp_yaml("prefill", "nccl");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(connector_config.communication_type, ksana_llm::CommunicationType::NCCL);

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "prefill";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试7：其他 communication_type 值 (应默认为TCP)
  {
    std::string yaml_path = create_temp_yaml("prefill", "other_type");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(connector_config.communication_type, ksana_llm::CommunicationType::TCP);  // 默认为TCP

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "prefill";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试8：测试大小写不敏感
  {
    std::string yaml_path = create_temp_yaml("PREFILL", "NCCL");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(connector_config.group_role, ksana_llm::GroupRole::PREFILL);               // 应能识别大写
    EXPECT_EQ(connector_config.communication_type, ksana_llm::CommunicationType::NCCL);  // 应能识别大写

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "PREFILL";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试9：group_role = "prefill" 但配置了 $DECODE_NODE_BENCHMARK 的情况
  {
    // 设置环境变量
    if (setenv("DECODE_NODE_BENCHMARK", "1", 1) != 0) {
      std::cerr << "Error setting environment variable" << std::endl;
    }

    std::string yaml_path = create_temp_yaml("prefill");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(connector_config.group_role, ksana_llm::GroupRole::DECODE);

    // 取消环境变量
    if (unsetenv("DECODE_NODE_BENCHMARK") != 0) {
      std::cerr << "Error unsetting environment variable" << std::endl;
    }

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "decode";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试10：communication_type = "ZMQ" 的情况
  {
    std::string yaml_path = create_temp_yaml("prefill", "ZMQ");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    auto status = test_env.GetConnectorConfigs(connector_config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(connector_config.communication_type, ksana_llm::CommunicationType::ZMQ);

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "prefill";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试11：自动解决split fuse参数冲突的情况。支持split fuse后移除此单测
  {
    std::string yaml_path = create_temp_yaml("prefill");
    ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

    // 设置测试配置文件路径
    FLAGS_config_file_test = yaml_path;

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    BatchSchedulerConfig batch_scheduluer_config;
    EXPECT_TRUE(test_env.GetBatchSchedulerConfig(batch_scheduluer_config).OK());
    EXPECT_EQ(batch_scheduluer_config.split_fuse_token_num, 0);

    try {
      // 获取YAML文件的基本路径信息
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::string role = "prefill";
      std::filesystem::path model_dir = temp_dir / ("ksana_test_model_dir_" + role);

      // 清理临时文件和目录
      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }

      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }
  // 恢复原始配置文件路径
  FLAGS_config_file_test = orig_config_file;
}

// 测试参数边界条件
TEST_F(EnvironmentTest, ParameterBoundaries) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::ModelConfig model_config;
  auto status = env_->GetModelConfig(model_config);
  EXPECT_TRUE(status.OK());

  // 验证参数范围
  EXPECT_GT(model_config.vocab_size, 0);
  EXPECT_LT(model_config.vocab_size, 1000000);  // 合理的词表大小上限

  EXPECT_GT(model_config.hidden_units, 0);
  EXPECT_LT(model_config.hidden_units, 100000);  // 合理的隐藏层大小上限

  EXPECT_GT(model_config.num_layer, 0);
  EXPECT_LT(model_config.num_layer, 1000);  // 合理的层数上限
}

// 测试无效配置组合
TEST_F(EnvironmentTest, InvalidConfigCombinations) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::ModelConfig model_config;
  auto status = env_->GetModelConfig(model_config);
  EXPECT_TRUE(status.OK());

  // 验证量化配置组合
  if (model_config.quant_config.method == ksana_llm::QUANT_GPTQ) {
    EXPECT_NE(model_config.quant_config.bits, 0);
    EXPECT_NE(model_config.quant_config.group_size, 0);
  }
}

// 测试特殊字符处理
TEST_F(EnvironmentTest, SpecialCharacterHandling) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::ModelConfig model_config;
  auto status = env_->GetModelConfig(model_config);
  EXPECT_TRUE(status.OK());
}

// 测试运行时配置
TEST_F(EnvironmentTest, RuntimeConfig) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::BatchSchedulerConfig batch_config;
  auto status = env_->GetBatchSchedulerConfig(batch_config);
  EXPECT_TRUE(status.OK());

  // 默认YAML的expert_world_size=1, moe_all_to_all_mode=auto → DISABLED
  EXPECT_EQ(env_->schedule_config_parser_.runtime_config_.moe_all_to_all_mode, MoeAllToAllMode::DISABLED);

  // 验证deepep_low_latency_max_tokens的yaml默认值
  EXPECT_EQ(env_->schedule_config_parser_.runtime_config_.deepep_low_latency_max_tokens, 256);
}

// 测试Expert-Parallel配置读取
TEST_F(EnvironmentTest, InitExpertParaConfig) {
  setenv("EXPERT_NODE_RANK", "5", 1);
  setenv("EXPERT_MASTER_HOST", "localhost", 1);
  setenv("EXPERT_MASTER_PORT", "12345", 1);
  ExpertParallelConfig expert_parallel_config;
  env_->GetExpertParallelConfig(expert_parallel_config);
  expert_parallel_config.expert_world_size = 8;
  env_->SetExpertParallelConfig(expert_parallel_config);

  env_->SetTensorParallelSize(12);
  env_->SetExpertParallelSize(6);
  env_->InitializeExpertParallelConfig();
  env_->GetExpertParallelConfig(expert_parallel_config);

  EXPECT_EQ(expert_parallel_config.expert_para_size, 6);
  EXPECT_EQ(expert_parallel_config.expert_tensor_para_size, 2);
  EXPECT_EQ(expert_parallel_config.expert_world_size, 8);
  EXPECT_EQ(expert_parallel_config.expert_node_rank, 5);
  EXPECT_EQ(expert_parallel_config.expert_master_host, "localhost");
  EXPECT_EQ(expert_parallel_config.expert_master_port, 12345);

  // 验证计算的值
  EXPECT_EQ(expert_parallel_config.global_expert_para_size,
            expert_parallel_config.expert_world_size * expert_parallel_config.expert_para_size);

  unsetenv("EXPERT_MASTER_HOST");
  unsetenv("EXPERT_MASTER_PORT");
  unsetenv("EXPERT_WORLD_SIZE");
  unsetenv("EXPERT_NODE_RANK");
}

// 测试Environment的ParseModelQuantConfig方法
TEST_F(EnvironmentTest, ParseModelQuantConfig) {
  // 测试混合量化的配置加载
  {
    nlohmann::json mixed_config = {
        {"quantization_config",
         {{"quant_method", "mixed"},
          {"configs",
           {{"fp8",
             {{"method", "fp8"}, {"activation_scheme", "dynamic"}, {"fmt", "e4m3"}, {"weight_block_size", {128, 128}}}},
            {"gptq",
             {{"method", "gptq"},
              {"bits", 4},
              {"damp_percent", 0.01},
              {"desc_act", false},
              {"group_size", 128},
              {"sym", true}}}}},
          {"layer_mapping",
           {{"gptq",
             {{"default_config", false},
              {"pattern_layers", {".mlp.experts."}},
              {"ignored_layers", nlohmann::json::array()}}},
            {"fp8",
             {{"default_config", true},
              {"pattern_layers", nlohmann::json::array()},
              {"ignored_layers", {"model.layers.61.eh_proj"}}}}}}}}};
    ModelConfig model_config;
    std::string yaml_weight_quant_method = "auto";
    std::string yaml_gptq_backend = "cutlass";
    EnvModelConfigParser model_config_parser("", "");
    model_config_parser.ParseModelQuantConfig(mixed_config, model_config, yaml_weight_quant_method, yaml_gptq_backend);
    EXPECT_TRUE(model_config.is_quant);
    EXPECT_TRUE(model_config.quant_config.is_checkpoint_fp8_serialized);
    EXPECT_TRUE(!model_config.quant_config.is_activation_scheme_static);
    EXPECT_TRUE(model_config.quant_config.is_fp8_blockwise);
    EXPECT_EQ(model_config.quant_config.method, QUANT_BLOCK_FP8_E4M3);
    EXPECT_EQ(model_config.quant_config.weight_block_size.size(), 2);
    EXPECT_EQ(model_config.quant_config.weight_block_size[0], 128);
    EXPECT_EQ(model_config.quant_config.weight_block_size[1], 128);
    EXPECT_EQ(model_config.sub_quant_configs.size(), 1);
    EXPECT_EQ(model_config.sub_quant_configs[0].method, QUANT_GPTQ);
    EXPECT_EQ(model_config.sub_quant_configs[0].bits, 4);
    EXPECT_EQ(model_config.sub_quant_configs[0].group_size, 128);
    EXPECT_EQ(model_config.sub_quant_configs[0].desc_act, false);
  }

  // 测试GPTQ量化的配置加载
  {
    nlohmann::json gptq_config = {{"quantization_config",
                                   {{"quant_method", "gptq"},
                                    {"bits", 4},
                                    {"damp_percent", 0.01},
                                    {"desc_act", false},
                                    {"group_size", 128},
                                    {"sym", true}}}};
    ModelConfig model_config;
    std::string yaml_weight_quant_method = "auto";
    std::string yaml_gptq_backend = "cutlass";
    EnvModelConfigParser model_config_parser("", "");
    model_config_parser.ParseModelQuantConfig(gptq_config, model_config, yaml_weight_quant_method, yaml_gptq_backend);
    EXPECT_TRUE(model_config.is_quant);
    EXPECT_EQ(model_config.quant_config.method, QUANT_GPTQ);
    EXPECT_EQ(model_config.quant_config.bits, 4);
    EXPECT_EQ(model_config.quant_config.group_size, 128);
    EXPECT_EQ(model_config.quant_config.desc_act, false);
  }

  // 测试AWQ量化的配置加载
  {
    nlohmann::json awq_config = {{"quantization_config", {{"quant_method", "awq"}, {"bits", 4}, {"group_size", 128}}}};
    ModelConfig model_config;
    std::string yaml_weight_quant_method = "auto";
    std::string yaml_gptq_backend = "cutlass";
    EnvModelConfigParser model_config_parser("", "");
    model_config_parser.ParseModelQuantConfig(awq_config, model_config, yaml_weight_quant_method, yaml_gptq_backend);
    EXPECT_TRUE(model_config.is_quant);
    EXPECT_EQ(model_config.quant_config.method, QUANT_AWQ);
    EXPECT_EQ(model_config.quant_config.bits, 4);
    EXPECT_EQ(model_config.quant_config.group_size, 128);
  }
}

// 测试GetTransferLayerChunkSize方法
TEST_F(EnvironmentTest, GetTransferLayerChunkSize) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  // 测试默认值
  size_t chunk_size = env_->GetTransferLayerChunkSize();
  EXPECT_GT(chunk_size, 0);  // 应该大于0

  // 默认值应该是1（如果配置文件中没有设置）
  EXPECT_EQ(chunk_size, 1);
}

// 测试BatchSchedulerConfig中的transfer_layer_chunk_size配置
TEST_F(EnvironmentTest, BatchSchedulerConfigTransferLayerChunkSize) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::BatchSchedulerConfig config;
  auto status = env_->GetBatchSchedulerConfig(config);
  EXPECT_TRUE(status.OK());

  // 验证transfer_layer_chunk_size字段存在且有效
  EXPECT_GT(config.transfer_layer_chunk_size, 0);

  // 验证默认值
  EXPECT_EQ(config.transfer_layer_chunk_size, 1);
}

// 测试BatchSchedulerConfig中的max_pretransfer_batch_size配置
TEST_F(EnvironmentTest, BatchSchedulerConfigMaxPretransferBatchSize) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::BatchSchedulerConfig config;
  auto status = env_->GetBatchSchedulerConfig(config);
  EXPECT_TRUE(status.OK());

  // 验证max_pretransfer_batch_size字段存在且有效
  EXPECT_GT(config.max_pretransfer_batch_size, 0);

  // 验证默认值
  EXPECT_EQ(config.max_pretransfer_batch_size, 64);
}

// 测试自定义chunk传输配置
TEST_F(EnvironmentTest, CustomChunkTransferConfig) {
  // 创建一个包含自定义chunk传输配置的临时YAML文件
  auto create_chunk_config_yaml = []() -> std::string {
    std::filesystem::path temp_dir = std::filesystem::temp_directory_path();
    std::string filename = "ksana_chunk_config_test.yaml";
    std::filesystem::path temp_file_path = temp_dir / filename;

    std::filesystem::path model_dir = temp_dir / "ksana_test_chunk_model_dir";
    try {
      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
      std::filesystem::create_directory(model_dir);

      std::ofstream file(temp_file_path);
      if (!file.is_open()) {
        return "";
      }

      // 添加包含chunk传输配置的YAML内容
      file << "setting:\n";
      file << "  global:\n";
      file << "    tensor_para_size: 1\n";
      file << "    pipeline_para_size: 1\n";
      file << "    expert_world_size: 2\n";  // 用于测试MOE all-to-all模式
      file << "    moe_all_to_all_mode: deepep_low_latency\n";
      file << "    enable_full_shared_expert: true\n";
      file << "    deepep_low_latency_max_tokens: 1024\n";
      file << "  batch_scheduler:\n";
      file << "    max_waiting_queue_len: 100\n";
      file << "    max_token_len: 4096\n";
      file << "    max_step_tokens: 4096\n";
      file << "    max_batch_size: 2048\n";
      file << "    max_pretransfer_batch_size: 128\n";  // 自定义值
      file << "    transfer_layer_chunk_size: 4\n";     // 自定义值
      file << "  block_manager:\n";
      file << "    block_token_num: 16\n";
      file << "    reserved_device_memory_ratio: 0.01\n";
      file << "model_spec:\n";
      file << "  base_model:\n";
      file << "    model_dir: \"" << model_dir.string() << "\"\n";

      file.close();

      // 创建模型配置文件
      std::ofstream config_json(model_dir / "config.json");
      if (config_json.is_open()) {
        config_json << "{\n";
        config_json << "  \"architectures\": [\"LlamaForCausalLM\"],\n";
        config_json << "  \"model_type\": \"llama\",\n";
        config_json << "  \"torch_dtype\": \"float16\",\n";
        config_json << "  \"vocab_size\": 32000,\n";
        config_json << "  \"hidden_size\": 4096,\n";
        config_json << "  \"intermediate_size\": 11008,\n";
        config_json << "  \"num_attention_heads\": 32,\n";
        config_json << "  \"num_key_value_heads\": 32,\n";
        config_json << "  \"num_hidden_layers\": 32,\n";
        config_json << "  \"max_position_embeddings\": 4096,\n";
        config_json << "  \"bos_token_id\": 1,\n";
        config_json << "  \"eos_token_id\": 2,\n";
        config_json << "  \"pad_token_id\": 0\n";
        config_json << "}\n";
        config_json.close();
      }

      return temp_file_path.string();
    } catch (const std::exception& e) {
      return "";
    }
  };

  std::string yaml_path = create_chunk_config_yaml();
  ASSERT_FALSE(yaml_path.empty()) << "Failed to create temporary YAML file";

  // 通过yaml配置测试expert_world_size>1时的MOE all-to-all模式
  Environment test_env;
  ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

  // 验证expert_world_size=2时, moe_all_to_all_mode=deepep_low_latency → DEEPEP_LOW_LATENCY
  EXPECT_EQ(test_env.schedule_config_parser_.runtime_config_.moe_all_to_all_mode, MoeAllToAllMode::DEEPEP_LOW_LATENCY);
  EXPECT_EQ(test_env.schedule_config_parser_.runtime_config_.deepep_low_latency_max_tokens, 1024);

  // 测试自定义的chunk大小
  size_t chunk_size = test_env.GetTransferLayerChunkSize();
  EXPECT_EQ(chunk_size, 4);

  // 测试BatchSchedulerConfig中的自定义值
  ksana_llm::BatchSchedulerConfig config;
  auto status = test_env.GetBatchSchedulerConfig(config);
  EXPECT_TRUE(status.OK());
  EXPECT_EQ(config.transfer_layer_chunk_size, 4);
  EXPECT_EQ(config.max_pretransfer_batch_size, 128);

  // 清理临时文件
  try {
    std::filesystem::path yaml_file_path(yaml_path);
    std::filesystem::path temp_dir = yaml_file_path.parent_path();
    std::filesystem::path model_dir = temp_dir / "ksana_test_chunk_model_dir";

    if (std::filesystem::exists(yaml_path)) {
      std::filesystem::remove(yaml_path);
    }
    if (std::filesystem::exists(model_dir)) {
      std::filesystem::remove_all(model_dir);
    }
  } catch (const std::exception& e) {
    std::cerr << "Exception during cleanup: " << e.what() << std::endl;
  }
}

// 测试chunk传输配置的边界值
TEST_F(EnvironmentTest, ChunkTransferConfigBoundaryValues) {
  // 测试chunk_size为1的情况（最小值）
  auto create_boundary_yaml = [](size_t chunk_size, size_t max_pretransfer_batch_size) -> std::string {
    std::filesystem::path temp_dir = std::filesystem::temp_directory_path();
    std::string filename = "ksana_boundary_test_" + std::to_string(chunk_size) + ".yaml";
    std::filesystem::path temp_file_path = temp_dir / filename;

    std::filesystem::path model_dir = temp_dir / ("ksana_test_boundary_model_dir_" + std::to_string(chunk_size));
    try {
      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
      std::filesystem::create_directory(model_dir);

      std::ofstream file(temp_file_path);
      if (!file.is_open()) {
        return "";
      }

      file << "setting:\n";
      file << "  global:\n";
      file << "    tensor_para_size: 1\n";
      file << "    pipeline_para_size: 1\n";
      file << "  batch_scheduler:\n";
      file << "    max_waiting_queue_len: 100\n";
      file << "    max_token_len: 4096\n";
      file << "    max_step_tokens: 4096\n";
      file << "    max_batch_size: 32\n";
      file << "    max_pretransfer_batch_size: " << max_pretransfer_batch_size << "\n";
      file << "    transfer_layer_chunk_size: " << chunk_size << "\n";
      file << "  block_manager:\n";
      file << "    block_token_num: 16\n";
      file << "    reserved_device_memory_ratio: 0.01\n";
      file << "model_spec:\n";
      file << "  base_model:\n";
      file << "    model_dir: \"" << model_dir.string() << "\"\n";

      file.close();

      // 创建模型配置文件
      std::ofstream config_json(model_dir / "config.json");
      if (config_json.is_open()) {
        config_json << "{\n";
        config_json << "  \"architectures\": [\"LlamaForCausalLM\"],\n";
        config_json << "  \"model_type\": \"llama\",\n";
        config_json << "  \"torch_dtype\": \"float16\",\n";
        config_json << "  \"vocab_size\": 32000,\n";
        config_json << "  \"hidden_size\": 4096,\n";
        config_json << "  \"intermediate_size\": 11008,\n";
        config_json << "  \"num_attention_heads\": 32,\n";
        config_json << "  \"num_key_value_heads\": 32,\n";
        config_json << "  \"num_hidden_layers\": 32,\n";
        config_json << "  \"max_position_embeddings\": 4096,\n";
        config_json << "  \"bos_token_id\": 1,\n";
        config_json << "  \"eos_token_id\": 2,\n";
        config_json << "  \"pad_token_id\": 0\n";
        config_json << "}\n";
        config_json.close();
      }

      return temp_file_path.string();
    } catch (const std::exception& e) {
      return "";
    }
  };

  // 测试最小值
  {
    std::string yaml_path = create_boundary_yaml(1, 1);
    ASSERT_FALSE(yaml_path.empty());

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    EXPECT_EQ(test_env.GetTransferLayerChunkSize(), 1);

    ksana_llm::BatchSchedulerConfig config;
    auto status = test_env.GetBatchSchedulerConfig(config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(config.transfer_layer_chunk_size, 1);
    EXPECT_EQ(config.max_pretransfer_batch_size, 1);

    // 清理
    try {
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::filesystem::path model_dir = temp_dir / "ksana_test_boundary_model_dir_1";

      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }
      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }

  // 测试较大值
  {
    std::string yaml_path = create_boundary_yaml(16, 512);
    ASSERT_FALSE(yaml_path.empty());

    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());

    EXPECT_EQ(test_env.GetTransferLayerChunkSize(), 16);

    ksana_llm::BatchSchedulerConfig config;
    auto status = test_env.GetBatchSchedulerConfig(config);
    EXPECT_TRUE(status.OK());
    EXPECT_EQ(config.transfer_layer_chunk_size, 16);
    EXPECT_EQ(config.max_pretransfer_batch_size, 512);

    // 清理
    try {
      std::filesystem::path yaml_file_path(yaml_path);
      std::filesystem::path temp_dir = yaml_file_path.parent_path();
      std::filesystem::path model_dir = temp_dir / "ksana_test_boundary_model_dir_16";

      if (std::filesystem::exists(yaml_path)) {
        std::filesystem::remove(yaml_path);
      }
      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
    } catch (const std::exception& e) {
      std::cerr << "Exception during cleanup: " << e.what() << std::endl;
    }
  }
}

// 测试chunk传输配置的合理性验证
TEST_F(EnvironmentTest, ChunkTransferConfigValidation) {
  ASSERT_TRUE(env_->ParseConfig(FLAGS_config_file_test).OK());

  ksana_llm::BatchSchedulerConfig config;
  auto status = env_->GetBatchSchedulerConfig(config);
  EXPECT_TRUE(status.OK());

  // 验证配置的合理性
  EXPECT_GT(config.transfer_layer_chunk_size, 0);
  EXPECT_LE(config.transfer_layer_chunk_size, 1024);  // 合理的上限

  EXPECT_GT(config.max_pretransfer_batch_size, 0);
  EXPECT_LE(config.max_pretransfer_batch_size, 10240);  // 合理的上限

  // 验证chunk大小不应该超过max_batch_size的某个倍数（合理性检查）
  EXPECT_LE(config.transfer_layer_chunk_size, config.max_batch_size * 10);
}

// 测试 router_addr 各种格式的验证和处理
TEST_F(EnvironmentTest, RouterAddrValidation) {
  auto create_router_addr_yaml = [](const std::string& router_addr) -> std::string {
    std::filesystem::path temp_dir = std::filesystem::temp_directory_path();
    std::string safe_name;
    for (char c : router_addr) {
      safe_name += (std::isalnum(c) || c == '-' || c == '_') ? c : '_';
    }
    std::string filename = "ksana_router_test_" + safe_name + ".yaml";
    std::filesystem::path temp_file_path = temp_dir / filename;
    std::filesystem::path model_dir = temp_dir / ("ksana_test_router_model_" + safe_name);

    try {
      if (std::filesystem::exists(model_dir)) {
        std::filesystem::remove_all(model_dir);
      }
      std::filesystem::create_directory(model_dir);

      std::ofstream file(temp_file_path);
      if (!file.is_open()) return "";

      file << "setting:\n";
      file << "  connector:\n";
      file << "    group_role: prefill\n";
      file << "    router_addr: \"" << router_addr << "\"\n";
      file << "    inference_addr: \"localhost:9091\"\n";
      file << "    cluster_name: \"test_cluster\"\n";
      file << "    heartbeat_interval_ms: 2000\n";
      file << "  global:\n";
      file << "    tensor_para_size: 1\n";
      file << "    pipeline_para_size: 1\n";
      file << "  batch_scheduler:\n";
      file << "    max_waiting_queue_len: 100\n";
      file << "    max_token_len: 4096\n";
      file << "    max_step_tokens: 4096\n";
      file << "    max_batch_size: 32\n";
      file << "  block_manager:\n";
      file << "    block_token_num: 16\n";
      file << "    reserved_device_memory_ratio: 0.01\n";
      file << "model_spec:\n";
      file << "  base_model:\n";
      file << "    model_dir: \"" << model_dir.string() << "\"\n";
      file.close();

      std::ofstream config_json(model_dir / "config.json");
      if (config_json.is_open()) {
        config_json << R"({
  "architectures": ["LlamaForCausalLM"],
  "model_type": "llama",
  "torch_dtype": "float16",
  "vocab_size": 32000,
  "hidden_size": 4096,
  "intermediate_size": 11008,
  "num_attention_heads": 32,
  "num_key_value_heads": 32,
  "num_hidden_layers": 32,
  "max_position_embeddings": 4096,
  "bos_token_id": 1,
  "eos_token_id": 2,
  "pad_token_id": 0
})";
        config_json.close();
      }
      return temp_file_path.string();
    } catch (const std::exception&) {
      return "";
    }
  };

  auto cleanup = [](const std::string& yaml_path, const std::string& safe_name) {
    try {
      std::filesystem::path temp_dir = std::filesystem::path(yaml_path).parent_path();
      std::filesystem::path model_dir = temp_dir / ("ksana_test_router_model_" + safe_name);
      if (std::filesystem::exists(yaml_path)) std::filesystem::remove(yaml_path);
      if (std::filesystem::exists(model_dir)) std::filesystem::remove_all(model_dir);
    } catch (const std::exception&) {
    }
  };

  // Case 1: router_addr 为空 — GetConnectorConfigs 返回错误（connector 未初始化）
  {
    std::string yaml_path = create_router_addr_yaml("");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    // Empty router_addr means connector is not initialized; GetConnectorConfigs returns an error.
    EXPECT_FALSE(test_env.GetConnectorConfigs(connector_config).OK());
    cleanup(yaml_path, "");
  }

  // Case 2: router_addr 已包含协议前缀 "http://" — 保持不变
  {
    std::string yaml_path = create_router_addr_yaml("http://myhost:8080");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://myhost:8080");
    cleanup(yaml_path, "http___myhost_8080");
  }

  // Case 3: router_addr 已包含协议前缀 "https://" — 保持不变
  {
    std::string yaml_path = create_router_addr_yaml("https://myhost:8443");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "https://myhost:8443");
    cleanup(yaml_path, "https___myhost_8443");
  }

  // Case 4: router_addr 无协议且无冒号 — 触发 "not in host:port format" 警告，仍然添加 http://
  {
    std::string yaml_path = create_router_addr_yaml("just-a-hostname");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://just-a-hostname");
    cleanup(yaml_path, "just-a-hostname");
  }

  // Case 5: router_addr 冒号在开头 ":9090" — 触发 "not in host:port format" 警告
  {
    std::string yaml_path = create_router_addr_yaml(":9090");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://:9090");
    cleanup(yaml_path, "_9090");
  }

  // Case 6: router_addr 冒号在末尾 "host:" — 触发 "not in host:port format" 警告
  {
    std::string yaml_path = create_router_addr_yaml("myhost:");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://myhost:");
    cleanup(yaml_path, "myhost_");
  }

  // Case 7: router_addr 端口号超出范围 (port=0) — 触发 "port outside valid range" 警告
  {
    std::string yaml_path = create_router_addr_yaml("myhost:0");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://myhost:0");
    cleanup(yaml_path, "myhost_0");
  }

  // Case 8: router_addr 端口号超出范围 (port=70000) — 触发 "port outside valid range" 警告
  {
    std::string yaml_path = create_router_addr_yaml("myhost:70000");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://myhost:70000");
    cleanup(yaml_path, "myhost_70000");
  }

  // Case 9: router_addr 端口号为非数字 — 触发 "non-numeric port" 警告
  {
    std::string yaml_path = create_router_addr_yaml("myhost:abc");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://myhost:abc");
    cleanup(yaml_path, "myhost_abc");
  }

  // Case 10: router_addr 端口号为负数 — 触发 "port outside valid range" 警告
  {
    std::string yaml_path = create_router_addr_yaml("myhost:-1");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://myhost:-1");
    cleanup(yaml_path, "myhost_-1");
  }

  // Case 11: router_addr 正常的 host:port — 添加 http:// 前缀，无警告
  {
    std::string yaml_path = create_router_addr_yaml("10.0.0.1:8080");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://10.0.0.1:8080");
    cleanup(yaml_path, "10_0_0_1_8080");
  }

  // Case 12: router_addr 端口号为边界值 1 — 有效端口，添加 http://
  {
    std::string yaml_path = create_router_addr_yaml("myhost:1");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://myhost:1");
    cleanup(yaml_path, "myhost_1");
  }

  // Case 13: router_addr 端口号为边界值 65535 — 有效端口，添加 http://
  {
    std::string yaml_path = create_router_addr_yaml("myhost:65535");
    ASSERT_FALSE(yaml_path.empty());
    Environment test_env;
    ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());
    ConnectorConfig connector_config;
    EXPECT_TRUE(test_env.GetConnectorConfigs(connector_config).OK());
    EXPECT_EQ(connector_config.router_addr, "http://myhost:65535");
    cleanup(yaml_path, "myhost_65535");
  }
}

// ---------------------------------------------------------------------------
// Tests for --json_model_override_args integration
// ---------------------------------------------------------------------------

// Helper: write a minimal YAML + config.json pair under a unique temp dir and
// return the YAML path.  The config.json contains a standard LLaMA-like model
// with known field values so tests can assert overrides precisely.
static std::string CreateJsonOverrideTestYaml(const std::string& unique_suffix) {
  std::filesystem::path temp_dir = std::filesystem::temp_directory_path();
  std::filesystem::path model_dir = temp_dir / ("ksana_json_override_" + unique_suffix);
  std::filesystem::path yaml_path = temp_dir / ("ksana_json_override_" + unique_suffix + ".yaml");

  try {
    if (std::filesystem::exists(model_dir)) {
      std::filesystem::remove_all(model_dir);
    }
    std::filesystem::create_directory(model_dir);

    // Write YAML
    {
      std::ofstream f(yaml_path);
      f << "setting:\n"
        << "  global:\n"
        << "    tensor_para_size: 1\n"
        << "    pipeline_para_size: 1\n"
        << "  batch_scheduler:\n"
        << "    max_waiting_queue_len: 100\n"
        << "    max_token_len: 4096\n"
        << "    max_step_tokens: 4096\n"
        << "    max_batch_size: 32\n"
        << "  block_manager:\n"
        << "    block_token_num: 16\n"
        << "    reserved_device_memory_ratio: 0.01\n"
        << "model_spec:\n"
        << "  base_model:\n"
        << "    model_dir: \"" << model_dir.string() << "\"\n";
    }

    // Write config.json with known baseline values
    {
      std::ofstream f(model_dir / "config.json");
      f << "{\n"
        << "  \"architectures\": [\"LlamaForCausalLM\"],\n"
        << "  \"model_type\": \"llama\",\n"
        << "  \"torch_dtype\": \"float16\",\n"
        << "  \"vocab_size\": 32000,\n"
        << "  \"hidden_size\": 4096,\n"
        << "  \"intermediate_size\": 11008,\n"
        << "  \"num_attention_heads\": 32,\n"
        << "  \"num_key_value_heads\": 32,\n"
        << "  \"num_hidden_layers\": 32,\n"
        << "  \"max_position_embeddings\": 4096,\n"
        << "  \"rope_theta\": 10000.0,\n"
        << "  \"bos_token_id\": 1,\n"
        << "  \"eos_token_id\": 2,\n"
        << "  \"pad_token_id\": 0\n"
        << "}\n";
    }

    return yaml_path.string();
  } catch (const std::exception&) {
    return "";
  }
}

// Helper: remove the temp YAML and its associated model_dir.
static void CleanupJsonOverrideTestYaml(const std::string& yaml_path, const std::string& unique_suffix) {
  try {
    std::filesystem::path temp_dir = std::filesystem::temp_directory_path();
    std::filesystem::path model_dir = temp_dir / ("ksana_json_override_" + unique_suffix);
    if (std::filesystem::exists(yaml_path)) {
      std::filesystem::remove(yaml_path);
    }
    if (std::filesystem::exists(model_dir)) {
      std::filesystem::remove_all(model_dir);
    }
  } catch (...) {
  }
}

// Case 1: valid JSON with a single integer field override (num_layer).
TEST_F(EnvironmentTest, JsonModelOverrideArgsSingleField) {
  const std::string suffix = "single";
  std::string yaml_path = CreateJsonOverrideTestYaml(suffix);
  ASSERT_FALSE(yaml_path.empty());

  Environment test_env;
  ASSERT_TRUE(test_env.ParseConfig(yaml_path, "", "config.json", R"({"num_layer":16})").OK());

  ModelConfig cfg;
  ASSERT_TRUE(test_env.GetModelConfig(cfg).OK());
  EXPECT_EQ(cfg.num_layer, 16u);

  CleanupJsonOverrideTestYaml(yaml_path, suffix);
}

// Case 2: valid JSON with multiple fields overridden simultaneously.
TEST_F(EnvironmentTest, JsonModelOverrideArgsMultipleFields) {
  const std::string suffix = "multi";
  std::string yaml_path = CreateJsonOverrideTestYaml(suffix);
  ASSERT_FALSE(yaml_path.empty());

  Environment test_env;
  ASSERT_TRUE(
      test_env.ParseConfig(yaml_path, "", "config.json", R"({"num_layer":8,"hidden_units":2048,"rope_theta":500000.0})")
          .OK());

  ModelConfig cfg;
  ASSERT_TRUE(test_env.GetModelConfig(cfg).OK());
  EXPECT_EQ(cfg.num_layer, 8u);
  EXPECT_EQ(cfg.hidden_units, 2048u);
  EXPECT_FLOAT_EQ(cfg.rope_theta, 500000.0f);

  CleanupJsonOverrideTestYaml(yaml_path, suffix);
}

// Case 3: invalid JSON string — ParseConfig must not crash and the original
// parsed values must be preserved (num_layer stays 32 from config.json).
TEST_F(EnvironmentTest, JsonModelOverrideArgsInvalidJsonNocrash) {
  const std::string suffix = "invalid";
  std::string yaml_path = CreateJsonOverrideTestYaml(suffix);
  ASSERT_FALSE(yaml_path.empty());

  Environment test_env;
  // ParseConfig should still succeed — the bad JSON is skipped with a warning
  ASSERT_TRUE(test_env.ParseConfig(yaml_path, "", "config.json", "this is not valid json {{{").OK());

  ModelConfig cfg;
  ASSERT_TRUE(test_env.GetModelConfig(cfg).OK());
  // Original value from config.json must be intact
  EXPECT_EQ(cfg.num_layer, 32u);

  CleanupJsonOverrideTestYaml(yaml_path, suffix);
}

// Case 4: JSON with unknown / unrecognised field names — must be silently
// ignored and ParseConfig must succeed.
TEST_F(EnvironmentTest, JsonModelOverrideArgsUnknownFieldsIgnored) {
  const std::string suffix = "unknown";
  std::string yaml_path = CreateJsonOverrideTestYaml(suffix);
  ASSERT_FALSE(yaml_path.empty());

  Environment test_env;
  ASSERT_TRUE(
      test_env.ParseConfig(yaml_path, "", "config.json", R"({"totally_unknown_field":42,"another_unknown":"hello"})")
          .OK());

  ModelConfig cfg;
  ASSERT_TRUE(test_env.GetModelConfig(cfg).OK());
  // Known fields must remain at their parsed values
  EXPECT_EQ(cfg.num_layer, 32u);
  EXPECT_EQ(cfg.hidden_units, 4096u);

  CleanupJsonOverrideTestYaml(yaml_path, suffix);
}

// Case 5: empty json_model_override_args (default) — no override applied,
// all values come from config.json as usual.
TEST_F(EnvironmentTest, JsonModelOverrideArgsEmptyFlagNoEffect) {
  const std::string suffix = "empty";
  std::string yaml_path = CreateJsonOverrideTestYaml(suffix);
  ASSERT_FALSE(yaml_path.empty());

  Environment test_env;
  ASSERT_TRUE(test_env.ParseConfig(yaml_path).OK());  // default — no override

  ModelConfig cfg;
  ASSERT_TRUE(test_env.GetModelConfig(cfg).OK());
  EXPECT_EQ(cfg.num_layer, 32u);
  EXPECT_EQ(cfg.hidden_units, 4096u);
  EXPECT_EQ(cfg.vocab_size, 32000u);

  CleanupJsonOverrideTestYaml(yaml_path, suffix);
}

// Case 6: type-mismatch in JSON value (string where int expected) — the
// offending field is skipped with a warning; other fields and ParseConfig
// overall must still succeed.
TEST_F(EnvironmentTest, JsonModelOverrideArgsTypeMismatchSkipped) {
  const std::string suffix = "typemismatch";
  std::string yaml_path = CreateJsonOverrideTestYaml(suffix);
  ASSERT_FALSE(yaml_path.empty());

  // "num_layer" expects uint32_t but receives a string — should be skipped
  Environment test_env;
  ASSERT_TRUE(
      test_env.ParseConfig(yaml_path, "", "config.json", R"({"num_layer":"not_a_number","hidden_units":1024})").OK());

  ModelConfig cfg;
  ASSERT_TRUE(test_env.GetModelConfig(cfg).OK());
  // num_layer skipped due to type mismatch → stays at parsed value (32)
  EXPECT_EQ(cfg.num_layer, 32u);
  // hidden_units override succeeds
  EXPECT_EQ(cfg.hidden_units, 1024u);

  CleanupJsonOverrideTestYaml(yaml_path, suffix);
}

}  // namespace ksana_llm
