#include "gemma_model.h"

#include "../core/ops.h"
#include "../core/checkpoint.h"
#include "../core/memory_manager.h"

#include <algorithm>
#include <cmath>
#include <cctype>
#include <filesystem>
#include <fstream>
#include <iomanip>
#include <iostream>
#include <limits>
#include <regex>
#include <sstream>
#include <stdexcept>
#include <unordered_map>

namespace {

ops::TensorPtr make_base_tensor(const std::vector<int64_t>& shape, bool allocate) {
    if (allocate) {
        return std::make_shared<ops::Tensor>(shape, ops::DType::kFloat32, ops::kCPU);
    }
    // Shape-only placeholder: LoRA injection only needs the logical shape.
    return std::make_shared<ops::Tensor>(
        shape, static_cast<void*>(nullptr), ops::DType::kFloat32, ops::kCPU, true);
}

std::string read_file(const std::string& path) {
    std::ifstream f(path);
    if (!f.is_open()) {
        throw std::runtime_error("Failed to open config file: " + path);
    }
    std::stringstream buffer;
    buffer << f.rdbuf();
    return buffer.str();
}

std::string extract_string(const std::string& content, const std::string& key, const std::string& def = "") {
    std::string pattern_str = "\\\"" + key + R"(\"\s*:\s*\"([^\"]+)\")";
    std::regex pattern(pattern_str);
    std::smatch match;
    if (std::regex_search(content, match, pattern)) {
        return match[1].str();
    }
    return def;
}

int extract_int(const std::string& content, const std::string& key, int def) {
    std::string pattern_str = "\\\"" + key + R"(\"\s*:\s*(-?\d+))";
    std::regex pattern(pattern_str);
    std::smatch match;
    if (std::regex_search(content, match, pattern)) {
        return std::stoi(match[1].str());
    }
    return def;
}

float extract_float(const std::string& content, const std::string& key, float def) {
    std::string pattern_str = "\\\"" + key + R"(\"\s*:\s*(-?\d+(\.\d+)?([eE][-+]?\d+)?))";
    std::regex pattern(pattern_str);
    std::smatch match;
    if (std::regex_search(content, match, pattern)) {
        return std::stof(match[1].str());
    }
    return def;
}

bool extract_bool(const std::string& content, const std::string& key, bool def) {
    std::string pattern_str = "\\\"" + key + R"(\"\s*:\s*(true|false))";
    std::regex pattern(pattern_str, std::regex::icase);
    std::smatch match;
    if (std::regex_search(content, match, pattern)) {
        std::string v = match[1].str();
        for (auto& ch : v) ch = static_cast<char>(std::tolower(ch));
        return v == "true";
    }
    return def;
}

std::vector<std::string> extract_string_array(const std::string& content, const std::string& key) {
    std::string pattern_str = "\\\"" + key + R"(\"\s*:\s*\[([^\]]*)\])";
    std::regex pattern(pattern_str);
    std::smatch match;
    std::vector<std::string> result;
    if (std::regex_search(content, match, pattern)) {
        std::string arr = match[1].str();
        std::regex item_pattern(R"(\"([^\"]+)\")");
        auto it_begin = std::sregex_iterator(arr.begin(), arr.end(), item_pattern);
        auto it_end = std::sregex_iterator();
        for (auto it = it_begin; it != it_end; ++it) {
            result.push_back((*it)[1].str());
        }
    }
    return result;
}

bool mem_debug_enabled() {
    const char* v = std::getenv("OPS_MEM_DEBUG");
    if (!v) return false;
    return std::string(v) == "1";
}

bool rss_stage_enabled() {
    const char* v = std::getenv("OPS_RSS_STAGE");
    if (!v) return false;
    return std::string(v) == "1";
}

std::string shape_to_string(const std::vector<int64_t>& shape) {
    std::ostringstream oss;
    oss << "[";
    for (size_t i = 0; i < shape.size(); ++i) {
        if (i > 0) oss << ",";
        oss << shape[i];
    }
    oss << "]";
    return oss.str();
}

void log_tensor_mem(const std::string& name, const ops::TensorPtr& t) {
    if (!mem_debug_enabled() || !t) return;
    size_t bytes = static_cast<size_t>(t->numel()) * ops::DTypeUtils::size_of(t->dtype());
    double mb = static_cast<double>(bytes) / (1024.0 * 1024.0);
    std::cout << "[MemDbg] " << name << " shape=" << shape_to_string(t->shape())
              << " dtype=" << ops::DTypeUtils::to_string(t->dtype())
              << " bytes=" << bytes << " (" << std::fixed << std::setprecision(2)
              << mb << " MB)" << std::endl;
}

struct StageRssRecorder {
    std::unordered_map<std::string, size_t> max_rss_bytes;

    void record(const std::string& stage) {
        size_t rss = ops::MemoryMonitor::get_system_memory_usage();
        auto it = max_rss_bytes.find(stage);
        if (it == max_rss_bytes.end() || rss > it->second) {
            max_rss_bytes[stage] = rss;
        }
    }

    void print(const std::string& prefix) const {
        if (max_rss_bytes.empty()) return;
        std::vector<std::pair<std::string, size_t>> items;
        items.reserve(max_rss_bytes.size());
        for (const auto& kv : max_rss_bytes) {
            items.push_back(kv);
        }
        std::sort(items.begin(), items.end(),
                  [](const auto& a, const auto& b) { return a.second > b.second; });
        std::cout << "[RSSStage] " << prefix << " peak-by-stage (MB):" << std::endl;
        for (const auto& kv : items) {
            double mb = static_cast<double>(kv.second) / (1024.0 * 1024.0);
            std::cout << "  " << kv.first << " = " << std::fixed << std::setprecision(2) << mb << std::endl;
        }
    }
};

thread_local StageRssRecorder* tls_rss_recorder = nullptr;

void stage_rss(const std::string& stage) {
    if (!rss_stage_enabled() || !tls_rss_recorder) return;
    tls_rss_recorder->record(stage);
}

ops::TensorPtr ensure_fp32(const ops::TensorPtr& t) {
    if (!t) return t;
    if (t->dtype() == ops::kFloat32) return t;
    return ops::cast(t, ops::kFloat32);
}

ops::TensorPtr maybe_fp16(bool enabled, const ops::TensorPtr& t) {
    if (!enabled || !t) return t;
    if (t->dtype() == ops::kFloat16) return t;
    return ops::cast(t, ops::kFloat16);
}

void check_tensor_finite_or_throw(const ops::TensorPtr& tensor,
                                  const std::string& stage) {
    const char* enabled = std::getenv("OPS_GEMMA_FINITE_CHECK");
    if (!enabled || std::string(enabled) != "1") {
        return;
    }
    if (!tensor) {
        throw std::runtime_error("Finite check failed: null tensor at " + stage);
    }
    if (tensor->dtype() != ops::kFloat32 && tensor->dtype() != ops::kFloat16) {
        return;
    }

    auto fp32 = ensure_fp32(tensor);
    const float* data = fp32->data<float>();
    const int64_t n = fp32->numel();
    for (int64_t i = 0; i < n; ++i) {
        const float v = data[i];
        if (!std::isfinite(v)) {
            std::ostringstream oss;
            oss << "[GemmaFiniteCheck] non-finite tensor at " << stage
                << " dtype=" << ops::DTypeUtils::to_string(tensor->dtype())
                << " numel=" << n
                << " bad_index=" << i
                << " value=" << v;
            std::cerr << oss.str() << std::endl;
            throw std::runtime_error(oss.str());
        }
    }
}

}  // namespace

namespace {

enum class DumpDType { kFloat32, kInt32 };

bool save_npy(const std::string& path,
              const void* data,
              const std::vector<int64_t>& shape,
              DumpDType dtype) {
    std::string descr = (dtype == DumpDType::kFloat32) ? "<f4" : "<i4";
    std::string shape_str = "(";
    for (size_t i = 0; i < shape.size(); ++i) {
        shape_str += std::to_string(shape[i]);
        if (shape.size() == 1) shape_str += ",";
        if (i + 1 < shape.size()) shape_str += ", ";
    }
    shape_str += ")";
    std::string header_dict = "{'descr': '" + descr +
        "', 'fortran_order': False, 'shape': " + shape_str + ", }";

    std::string magic = "\x93NUMPY";
    uint8_t ver_major = 1, ver_minor = 0;
    size_t header_len = header_dict.size() + 1;  // newline
    size_t preamble = magic.size() + 2 + 2;
    size_t padding = 16 - ((preamble + header_len) % 16);
    if (padding == 16) padding = 0;
    header_dict += std::string(padding, ' ');
    header_dict.push_back('\n');
    uint16_t header_size_le = static_cast<uint16_t>(header_dict.size());

    std::filesystem::create_directories(std::filesystem::path(path).parent_path());
    std::ofstream out(path, std::ios::binary);
    if (!out) return false;
    out.write(magic.data(), magic.size());
    out.put(static_cast<char>(ver_major));
    out.put(static_cast<char>(ver_minor));
    out.write(reinterpret_cast<const char*>(&header_size_le), sizeof(header_size_le));
    out.write(header_dict.data(), header_dict.size());

    size_t count = 1;
    for (auto d : shape) count *= static_cast<size_t>(d);
    size_t elem_size = 4;
    out.write(reinterpret_cast<const char*>(data), static_cast<std::streamsize>(count * elem_size));
    return true;
}

}  // namespace

namespace ops {

GemmaTextConfig GemmaTextConfig::from_pretrained(const std::string& model_dir) {
    GemmaTextConfig cfg;
    const std::string path = model_dir + "/config.json";
    const std::string content = read_file(path);

    cfg.vocab_size = extract_int(content, "vocab_size", cfg.vocab_size);
    cfg.hidden_size = extract_int(content, "hidden_size", cfg.hidden_size);
    cfg.intermediate_size = extract_int(content, "intermediate_size", cfg.intermediate_size);
    cfg.num_hidden_layers = extract_int(content, "num_hidden_layers", cfg.num_hidden_layers);
    cfg.num_attention_heads = extract_int(content, "num_attention_heads", cfg.num_attention_heads);
    cfg.num_key_value_heads = extract_int(content, "num_key_value_heads", cfg.num_key_value_heads);
    cfg.head_dim = extract_int(content, "head_dim", cfg.head_dim);
    cfg.max_position_embeddings = extract_int(content, "max_position_embeddings", cfg.max_position_embeddings);
    cfg.sliding_window = extract_int(content, "sliding_window", cfg.sliding_window);
    cfg.attention_bias = extract_bool(content, "attention_bias", cfg.attention_bias);
    cfg.use_bidirectional_attention =
        extract_bool(content, "use_bidirectional_attention", cfg.use_bidirectional_attention);
    cfg.use_cache = extract_bool(content, "use_cache", cfg.use_cache);

    cfg.attention_dropout = extract_float(content, "attention_dropout", cfg.attention_dropout);
    cfg.rms_norm_eps = extract_float(content, "rms_norm_eps", cfg.rms_norm_eps);
    cfg.query_pre_attn_scalar = extract_float(content, "query_pre_attn_scalar", cfg.query_pre_attn_scalar);
    cfg.attn_logit_softcapping = extract_float(content, "attn_logit_softcapping", cfg.attn_logit_softcapping);
    cfg.final_logit_softcapping = extract_float(content, "final_logit_softcapping", cfg.final_logit_softcapping);
    cfg.rope_theta = extract_float(content, "rope_theta", cfg.rope_theta);
    cfg.rope_local_base_freq = extract_float(content, "rope_local_base_freq", cfg.rope_local_base_freq);
    cfg.hidden_activation = extract_string(content, "hidden_activation", cfg.hidden_activation);

    cfg.layer_types = extract_string_array(content, "layer_types");
    if (cfg.layer_types.empty()) {
        cfg.layer_types.assign(cfg.num_hidden_layers, "sliding_attention");
    }
    return cfg;
}

namespace {

constexpr float kMaskValue = -1e10f;

}  // namespace

GemmaModel::GemmaModel(const GemmaTextConfig& config, bool allocate_base_tensors)
    : config_(config) {
    embed_weight_ = make_base_tensor(
        std::vector<int64_t>{config_.vocab_size, config_.hidden_size}, allocate_base_tensors);
    norm_weight_ = make_base_tensor(
        std::vector<int64_t>{config_.hidden_size}, allocate_base_tensors);
    lm_head_weight_ = make_base_tensor(
        std::vector<int64_t>{config_.hidden_size, config_.vocab_size}, allocate_base_tensors);

    blocks_.resize(config_.num_hidden_layers);
    for (auto& block : blocks_) {
        block.input_layernorm_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size}, allocate_base_tensors);
        block.post_attention_layernorm_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size}, allocate_base_tensors);
        block.pre_feedforward_layernorm_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size}, allocate_base_tensors);
        block.post_feedforward_layernorm_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size}, allocate_base_tensors);

        block.q_proj_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size, config_.num_attention_heads * config_.head_dim}, allocate_base_tensors);
        block.k_proj_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size, config_.num_key_value_heads * config_.head_dim}, allocate_base_tensors);
        block.v_proj_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size, config_.num_key_value_heads * config_.head_dim}, allocate_base_tensors);
        block.o_proj_weight = make_base_tensor(
            std::vector<int64_t>{config_.num_attention_heads * config_.head_dim, config_.hidden_size}, allocate_base_tensors);

        block.q_norm_weight = make_base_tensor(
            std::vector<int64_t>{config_.head_dim}, allocate_base_tensors);
        block.k_norm_weight = make_base_tensor(
            std::vector<int64_t>{config_.head_dim}, allocate_base_tensors);

        block.gate_proj_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size, config_.intermediate_size}, allocate_base_tensors);
        block.up_proj_weight = make_base_tensor(
            std::vector<int64_t>{config_.hidden_size, config_.intermediate_size}, allocate_base_tensors);
        block.down_proj_weight = make_base_tensor(
            std::vector<int64_t>{config_.intermediate_size, config_.hidden_size}, allocate_base_tensors);
    }
}

TensorPtr GemmaModel::embedding_lookup(const TensorPtr& indices) const {
    const auto& idx_shape = indices->shape();
    if (idx_shape.size() != 2) {
        throw std::runtime_error("GemmaModel::embedding_lookup expects [batch, seq_len]");
    }
    int64_t batch = idx_shape[0];
    int64_t seq_len = idx_shape[1];
    auto result = zeros({batch, seq_len, config_.hidden_size}, DType::kFloat32, kCPU);

    const float* emb_data = embed_weight_->data<float>();
    float* out_data = result->data<float>();

    float scale = std::sqrt(static_cast<float>(config_.hidden_size));
    auto copy_row = [&](int32_t token_id, float* dst) {
        if (token_id < 0 || token_id >= config_.vocab_size) {
            throw std::runtime_error("Token id out of range in Gemma embedding");
        }
        const float* src = emb_data + token_id * config_.hidden_size;
        for (int64_t i = 0; i < config_.hidden_size; ++i) {
            dst[i] = src[i] * scale;
        }
    };

    if (indices->dtype() == DType::kInt32) {
        const int32_t* ids = indices->data<int32_t>();
        for (int64_t b = 0; b < batch; ++b) {
            for (int64_t s = 0; s < seq_len; ++s) {
                int32_t token = ids[b * seq_len + s];
                float* dst = out_data + (b * seq_len + s) * config_.hidden_size;
                copy_row(token, dst);
            }
        }
    } else {
        throw std::runtime_error("GemmaModel::embedding_lookup expects int32 input_ids");
    }

    return result;
}

TensorPtr GemmaModel::lookup_token_embeddings(const TensorPtr& token_ids,
                                              bool scale_like_input) const {
    const auto& shape = token_ids->shape();
    if (shape.empty() || shape.size() > 2) {
        throw std::runtime_error("GemmaModel::lookup_token_embeddings expects [batch] or [batch, 1]");
    }

    int64_t batch = shape[0];
    int64_t cols = (shape.size() == 1) ? 1 : shape[1];
    if (cols != 1) {
        throw std::runtime_error("GemmaModel::lookup_token_embeddings expects [batch] or [batch, 1]");
    }

    auto result = zeros({batch, config_.hidden_size}, DType::kFloat32, kCPU);
    const float* emb_data = embed_weight_->data<float>();
    float* out_data = result->data<float>();
    const float scale = scale_like_input ? std::sqrt(static_cast<float>(config_.hidden_size)) : 1.0f;

    auto copy_row = [&](int32_t token_id, float* dst) {
        if (token_id < 0 || token_id >= config_.vocab_size) {
            throw std::runtime_error("Token id out of range in Gemma embedding");
        }
        const float* src = emb_data + token_id * config_.hidden_size;
        for (int64_t i = 0; i < config_.hidden_size; ++i) {
            dst[i] = src[i] * scale;
        }
    };

    if (token_ids->dtype() != DType::kInt32) {
        throw std::runtime_error("GemmaModel::lookup_token_embeddings expects int32 token ids");
    }

    const int32_t* ids = token_ids->data<int32_t>();
    for (int64_t b = 0; b < batch; ++b) {
        const int64_t idx = (shape.size() == 1) ? b : (b * cols);
        copy_row(ids[idx], out_data + b * config_.hidden_size);
    }
    return result;
}

TensorPtr GemmaModel::forward_prefix(const TensorPtr& input_ids,
                                     int split_layer,
                                     const TensorPtr& attention_mask) const {
    (void)attention_mask;
    if (split_layer != 0) {
        throw std::runtime_error("GemmaModel::forward_prefix currently supports split_layer=0 only");
    }
    return embedding_lookup(input_ids);
}

TensorPtr GemmaModel::build_causal_mask(int seq_len) const {
    auto mask = full({seq_len, seq_len}, 0.0f, DType::kFloat32, kCPU);
    float* data = mask->data<float>();
    for (int64_t i = 0; i < seq_len; ++i) {
        for (int64_t j = i + 1; j < seq_len; ++j) {
            data[i * seq_len + j] = kMaskValue;
        }
    }
    return mask;
}

TensorPtr GemmaModel::build_sliding_mask(int seq_len) const {
    auto mask = full({seq_len, seq_len}, 0.0f, DType::kFloat32, kCPU);
    float* data = mask->data<float>();
    int window = config_.sliding_window;
    for (int64_t i = 0; i < seq_len; ++i) {
        for (int64_t j = 0; j < seq_len; ++j) {
            bool allow = (j <= i) && (i - j < window);
            if (!allow) {
                data[i * seq_len + j] = kMaskValue;
            }
        }
    }
    return mask;
}

TensorPtr GemmaModel::build_padding_mask(const TensorPtr& attention_mask) const {
    if (!attention_mask) return nullptr;
    const auto& shape = attention_mask->shape();
    if (shape.size() != 2) {
        throw std::runtime_error("Gemma attention_mask must be [batch, seq_len]");
    }
    int64_t batch = shape[0];
    int64_t seq_len = shape[1];
    auto mask = zeros({batch, 1, 1, seq_len}, DType::kFloat32, kCPU);
    float* mask_data = mask->data<float>();

    if (attention_mask->dtype() == DType::kFloat32) {
        const float* src = attention_mask->data<float>();
        for (int64_t b = 0; b < batch; ++b) {
            for (int64_t s = 0; s < seq_len; ++s) {
                if (src[b * seq_len + s] <= 0.5f) {
                    mask_data[b * seq_len + s] = kMaskValue;
                }
            }
        }
    } else if (attention_mask->dtype() == DType::kInt32) {
        const int32_t* src = attention_mask->data<int32_t>();
        for (int64_t b = 0; b < batch; ++b) {
            for (int64_t s = 0; s < seq_len; ++s) {
                if (src[b * seq_len + s] == 0) {
                    mask_data[b * seq_len + s] = kMaskValue;
                }
            }
        }
    } else {
        throw std::runtime_error("Gemma attention_mask must be int32 or float32");
    }

    return mask;
}

GemmaModel::RotaryCache GemmaModel::build_rotary_embeddings(int batch,
                                                            int seq_len,
                                                            float theta) const {
    auto cos = zeros({batch, seq_len, config_.head_dim}, DType::kFloat32, kCPU);
    auto sin = zeros({batch, seq_len, config_.head_dim}, DType::kFloat32, kCPU);
    float* cos_data = cos->data<float>();
    float* sin_data = sin->data<float>();

    int64_t half = config_.head_dim / 2;
    std::vector<float> inv_freq(half);
    for (int64_t i = 0; i < half; ++i) {
        float exponent = static_cast<float>(2 * i) / static_cast<float>(config_.head_dim);
        inv_freq[i] = std::pow(theta, -exponent);
    }

    for (int64_t b = 0; b < batch; ++b) {
        for (int64_t s = 0; s < seq_len; ++s) {
            float pos = static_cast<float>(s);
            float* cos_row = cos_data + (b * seq_len + s) * config_.head_dim;
            float* sin_row = sin_data + (b * seq_len + s) * config_.head_dim;
            for (int64_t i = 0; i < half; ++i) {
                float angle = pos * inv_freq[i];
                float c = std::cos(angle);
                float sn = std::sin(angle);
                cos_row[i] = c;
                cos_row[i + half] = c;
                sin_row[i] = sn;
                sin_row[i + half] = sn;
            }
        }
    }

    return {cos, sin};
}

TensorPtr GemmaModel::apply_attention(const TensorPtr& x,
                                      GemmaBlockWeights& block,
                                      const TensorPtr& position_cos,
                                      const TensorPtr& position_sin,
                                      const TensorPtr& pad_mask,
                                      const TensorPtr& base_mask,
                                      float rope_theta,
                                      int dbg_layer) const {
    (void)position_cos;
    (void)position_sin;
    const std::string stage_prefix = (dbg_layer >= 0) ? ("block" + std::to_string(dbg_layer) + "/") : std::string();
    int64_t B = x->shape()[0];
    int64_t S = x->shape()[1];
    int64_t n_head = config_.num_attention_heads;
    int64_t kv_heads = config_.num_key_value_heads;
    int64_t Hd = config_.head_dim;

    auto x_fp32 = ensure_fp32(x);
    check_tensor_finite_or_throw(x_fp32, stage_prefix + "attn_input");
    check_tensor_finite_or_throw(block.q_proj_weight, stage_prefix + "attn_q_weight");
    check_tensor_finite_or_throw(block.k_proj_weight, stage_prefix + "attn_k_weight");
    check_tensor_finite_or_throw(block.v_proj_weight, stage_prefix + "attn_v_weight");
    auto linear_forward = [&](const TensorPtr& input,
                              const std::unique_ptr<LoRALinear>& linear,
                              const TensorPtr& weight) -> TensorPtr {
        if (linear) {
            return linear->forward(input);
        }
        return matmul(input, weight);
    };

    auto q = linear_forward(x_fp32, block.q_proj_lora, block.q_proj_weight);
    auto k = linear_forward(x_fp32, block.k_proj_lora, block.k_proj_weight);
    auto v = linear_forward(x_fp32, block.v_proj_lora, block.v_proj_weight);
    check_tensor_finite_or_throw(q, stage_prefix + "attn_q_proj");
    check_tensor_finite_or_throw(k, stage_prefix + "attn_k_proj");
    check_tensor_finite_or_throw(v, stage_prefix + "attn_v_proj");
    if (!stage_prefix.empty()) stage_rss(stage_prefix + "attn_qkv");
    if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
        dump_tensor(q, "q_proj_out_l" + std::to_string(dbg_layer));
        dump_tensor(k, "k_proj_out_l" + std::to_string(dbg_layer));
        dump_tensor(v, "v_proj_out_l" + std::to_string(dbg_layer));
    }
    // Allow numeric perturbation exactly at pre-norm projection outputs
    auto perturb_if_match = [&](const std::string& name, const TensorPtr& t) {
        if (debug_.numeric_enabled && debug_.numeric_name == name &&
            debug_.numeric_index >= 0 && debug_.numeric_index < t->numel()) {
            float* data = t->data<float>();
            data[debug_.numeric_index] += debug_.numeric_eps;
        }
    };
    perturb_if_match("q_proj_out_l" + std::to_string(dbg_layer), q);
    perturb_if_match("k_proj_out_l" + std::to_string(dbg_layer), k);
    perturb_if_match("v_proj_out_l" + std::to_string(dbg_layer), v);

    q = reshape(q, {B, S, n_head, Hd});
    k = reshape(k, {B, S, kv_heads, Hd});
    v = reshape(v, {B, S, kv_heads, Hd});

    q = permute(q, {0, 2, 1, 3});  // [B,n_head,S,Hd]
    k = permute(k, {0, 2, 1, 3});
    v = permute(v, {0, 2, 1, 3});
    if (!stage_prefix.empty()) stage_rss(stage_prefix + "attn_qkv_perm");

    // Optional: allow disabling q/k RMSNorm via env for isolation tests
    const char* disable_qk_norm = std::getenv("DISABLE_QK_NORM");
      if (!(disable_qk_norm && std::string(disable_qk_norm) == "1")) {
          // Debug: dump inv_rms before applying RMSNorm to locate reduce/broadcast differences
          if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
              // Manually calculate inv_rms to avoid dimension path interference from generic reduce
              // q,k: [B,H,S,Hd] -> inv_rms: [B,H,S,1]
              {
                  auto inv = zeros({B, n_head, S, 1}, DType::kFloat32, kCPU);
                  const float* q_data = q->data<float>();
                  float* inv_data = inv->data<float>();
                  for (int64_t b = 0; b < B; ++b) {
                      for (int64_t h = 0; h < n_head; ++h) {
                          for (int64_t s = 0; s < S; ++s) {
                              int64_t base = (((b * n_head) + h) * S + s) * Hd;
                              double sqsum = 0.0;
                              for (int64_t d = 0; d < Hd; ++d) {
                                  float v = q_data[base + d];
                                  sqsum += static_cast<double>(v) * static_cast<double>(v);
                              }
                              float inv_rms = static_cast<float>(1.0 / std::sqrt(sqsum / static_cast<double>(Hd) + static_cast<double>(config_.rms_norm_eps)));
                              inv_data[((b * n_head) + h) * S + s] = inv_rms;
                          }
                      }
                  }
                  dump_tensor(inv, "q_inv_rms_l" + std::to_string(dbg_layer));
              }
              {
                  auto inv = zeros({B, kv_heads, S, 1}, DType::kFloat32, kCPU);
                  const float* k_data = k->data<float>();
                  float* inv_data = inv->data<float>();
                  for (int64_t b = 0; b < B; ++b) {
                      for (int64_t h = 0; h < kv_heads; ++h) {
                          for (int64_t s = 0; s < S; ++s) {
                              int64_t base = (((b * kv_heads) + h) * S + s) * Hd;
                              double sqsum = 0.0;
                              for (int64_t d = 0; d < Hd; ++d) {
                                  float v = k_data[base + d];
                                  sqsum += static_cast<double>(v) * static_cast<double>(v);
                              }
                              float inv_rms = static_cast<float>(1.0 / std::sqrt(sqsum / static_cast<double>(Hd) + static_cast<double>(config_.rms_norm_eps)));
                              inv_data[((b * kv_heads) + h) * S + s] = inv_rms;
                          }
                      }
                  }
                  dump_tensor(inv, "k_inv_rms_l" + std::to_string(dbg_layer));
              }
          }
          q = rms_norm(q, block.q_norm_weight, config_.rms_norm_eps);
          k = rms_norm(k, block.k_norm_weight, config_.rms_norm_eps);
      }
    check_tensor_finite_or_throw(q, stage_prefix + "attn_q_norm");
    check_tensor_finite_or_throw(k, stage_prefix + "attn_k_norm");
    if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
        dump_tensor(q, "q_norm_out_l" + std::to_string(dbg_layer));
        dump_tensor(k, "k_norm_out_l" + std::to_string(dbg_layer));
        dump_tensor(q, "q_norm_out_l" + std::to_string(dbg_layer) + "_pre_rope");
        dump_tensor(k, "k_norm_out_l" + std::to_string(dbg_layer) + "_pre_rope");
    }

    // apply rotary embeddings with tracked autograd
    q = apply_rope_contiguous(q, S, Hd, rope_theta);
    k = apply_rope_contiguous(k, S, Hd, rope_theta);
    check_tensor_finite_or_throw(q, stage_prefix + "attn_q_rope");
    check_tensor_finite_or_throw(k, stage_prefix + "attn_k_rope");
    if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
        dump_tensor(q, "q_rotary_out_l" + std::to_string(dbg_layer));
        dump_tensor(k, "k_rotary_out_l" + std::to_string(dbg_layer));
    }

    // Numerical gradient perturbation: can also target normalized q/k before entering scores
    perturb_if_match("q_norm_out_l" + std::to_string(dbg_layer), q);
    perturb_if_match("k_norm_out_l" + std::to_string(dbg_layer), k);

    auto k_full = repeat_kv_heads(k, n_head / kv_heads);
    auto v_full = repeat_kv_heads(v, n_head / kv_heads);
    check_tensor_finite_or_throw(k_full, stage_prefix + "attn_k_repeat");
    check_tensor_finite_or_throw(v_full, stage_prefix + "attn_v_repeat");
    if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
        dump_tensor(v_full, "v_full_l" + std::to_string(dbg_layer));
    }

    float scaling = std::pow(config_.query_pre_attn_scalar, -0.5f);
    TensorPtr context;
    auto scores = matmul_transB(q, k_full);        // [B,n_head,S,S]
    check_tensor_finite_or_throw(scores, stage_prefix + "attn_scores_raw");
    log_tensor_mem("attn_scores", scores);
    if (!stage_prefix.empty()) stage_rss(stage_prefix + "attn_scores");

    scores = mul(scores, scaling);
    check_tensor_finite_or_throw(scores, stage_prefix + "attn_scores_scaled");

    if (base_mask) {
        scores = add(scores, base_mask);
        check_tensor_finite_or_throw(scores, stage_prefix + "attn_scores_base_mask");
    }
    if (pad_mask) {
        scores = add(scores, pad_mask);
        check_tensor_finite_or_throw(scores, stage_prefix + "attn_scores_pad_mask");
    }

    auto probs = softmax(scores, -1);
    check_tensor_finite_or_throw(probs, stage_prefix + "attn_probs");
    log_tensor_mem("attn_probs", probs);
    if (!stage_prefix.empty()) stage_rss(stage_prefix + "attn_probs");
    if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
        dump_tensor(scores, "attn_scores_l" + std::to_string(dbg_layer));
        dump_tensor(probs, "attn_probs_l" + std::to_string(dbg_layer));
    }
    context = matmul(probs, v_full);  // [B,n_head,S,Hd]
    check_tensor_finite_or_throw(context, stage_prefix + "attn_context_raw");
    log_tensor_mem("attn_context", context);
    if (!stage_prefix.empty()) stage_rss(stage_prefix + "attn_context");
    context = permute(context, {0, 2, 1, 3});
    int64_t attn_dim = block.q_proj_weight->shape()[1];
    context = reshape(context, {B, S, attn_dim});
    check_tensor_finite_or_throw(context, stage_prefix + "attn_context");
    if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
        dump_tensor(context, "attn_context_l" + std::to_string(dbg_layer));
    }
    perturb_if_match("attn_context_l" + std::to_string(dbg_layer), context);

    auto attn_out = linear_forward(context, block.o_proj_lora, block.o_proj_weight);
    check_tensor_finite_or_throw(attn_out, stage_prefix + "attn_o_proj");
    if (!stage_prefix.empty()) stage_rss(stage_prefix + "attn_out");
    perturb_if_match("attn_out_raw_l" + std::to_string(dbg_layer), attn_out);
    if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
        dump_tensor(attn_out, "attn_out_raw_l" + std::to_string(dbg_layer));
    }
    return attn_out;
}

TensorPtr GemmaModel::apply_mlp(const TensorPtr& x,
                                GemmaBlockWeights& block,
                                int dbg_layer) const {
    const std::string stage_prefix = (dbg_layer >= 0) ? ("block" + std::to_string(dbg_layer) + "/") : std::string();
    auto linear_forward = [&](const TensorPtr& input,
                              const std::unique_ptr<LoRALinear>& linear,
                              const TensorPtr& weight) -> TensorPtr {
        if (linear) {
            return linear->forward(input);
        }
        return matmul(input, weight);
    };

    const int64_t seq_len = x->shape()[1];
    const int64_t chunk = static_cast<int64_t>(config_.mlp_chunk_size);
    if (chunk <= 0 || chunk >= seq_len) {
        auto gate = linear_forward(x, block.gate_proj_lora, block.gate_proj_weight);
        if (!stage_prefix.empty()) stage_rss(stage_prefix + "mlp_gate");
        if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
            dump_tensor(gate, "gate_proj_out_l" + std::to_string(dbg_layer));
        }
        auto gate_act = gelu(gate);
        if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
            dump_tensor(gate_act, "gate_act_l" + std::to_string(dbg_layer));
        }
        auto up = linear_forward(x, block.up_proj_lora, block.up_proj_weight);
        if (!stage_prefix.empty()) stage_rss(stage_prefix + "mlp_up");
        if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
            dump_tensor(up, "up_proj_out_l" + std::to_string(dbg_layer));
        }
        auto prod = mul(gate_act, up);
        if (!stage_prefix.empty()) stage_rss(stage_prefix + "mlp_prod");
        if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
            dump_tensor(prod, "mlp_prod_l" + std::to_string(dbg_layer));
        }
        auto down = linear_forward(prod, block.down_proj_lora, block.down_proj_weight);
        if (!stage_prefix.empty()) stage_rss(stage_prefix + "mlp_down");
        if (dbg_layer >= 0 && need_dump_layer(dbg_layer)) {
            dump_tensor(down, "down_proj_out_l" + std::to_string(dbg_layer));
        }
        return down;
    }

    std::vector<TensorPtr> out_chunks;
    out_chunks.reserve(static_cast<size_t>((seq_len + chunk - 1) / chunk));
    for (int64_t s0 = 0; s0 < seq_len; s0 += chunk) {
        int64_t s1 = std::min(s0 + chunk, seq_len);
        auto x_chunk = x->slice(1, s0, s1);

        auto gate = linear_forward(x_chunk, block.gate_proj_lora, block.gate_proj_weight);
        if (!stage_prefix.empty()) stage_rss(stage_prefix + "mlp_gate");
        auto gate_act = gelu(gate);
        auto up = linear_forward(x_chunk, block.up_proj_lora, block.up_proj_weight);
        if (!stage_prefix.empty()) stage_rss(stage_prefix + "mlp_up");
        auto prod = mul(gate_act, up);
        if (!stage_prefix.empty()) stage_rss(stage_prefix + "mlp_prod");
        auto down = linear_forward(prod, block.down_proj_lora, block.down_proj_weight);
        if (!stage_prefix.empty()) stage_rss(stage_prefix + "mlp_down");
        out_chunks.push_back(down);
    }
    return cat(out_chunks, 1);
}

TensorPtr GemmaModel::forward_block(const TensorPtr& input,
                                    GemmaBlockWeights& block,
                                    const TensorPtr& position_cos,
                                    const TensorPtr& position_sin,
                                    const TensorPtr& pad_mask,
                                    const TensorPtr& base_mask,
                                    float rope_theta,
                                    int block_idx) const {
    // Important for activation checkpoint + sharding:
    // During backward recomputation, this function may be invoked after prior blocks were evicted.
    // Ensure current block parameters are resident before any compute.
    if (sharder_) {
        const std::string prefix = "layers." + std::to_string(block_idx) + ".";
        sharder_->require(prefix + "input_layernorm.weight");
        sharder_->require(prefix + "post_attention_layernorm.weight");
        sharder_->require(prefix + "pre_feedforward_layernorm.weight");
        sharder_->require(prefix + "post_feedforward_layernorm.weight");
        sharder_->require(prefix + "self_attn.q_proj.weight");
        sharder_->require(prefix + "self_attn.k_proj.weight");
        sharder_->require(prefix + "self_attn.v_proj.weight");
        sharder_->require(prefix + "self_attn.o_proj.weight");
        sharder_->require(prefix + "self_attn.q_norm.weight");
        sharder_->require(prefix + "self_attn.k_norm.weight");
        sharder_->require(prefix + "mlp.gate_proj.weight");
        sharder_->require(prefix + "mlp.up_proj.weight");
        sharder_->require(prefix + "mlp.down_proj.weight");
        if (!block.input_layernorm_weight || !block.post_attention_layernorm_weight ||
            !block.pre_feedforward_layernorm_weight || !block.post_feedforward_layernorm_weight ||
            !block.q_proj_weight || !block.k_proj_weight || !block.v_proj_weight || !block.o_proj_weight ||
            !block.q_norm_weight || !block.k_norm_weight ||
            !block.gate_proj_weight || !block.up_proj_weight || !block.down_proj_weight) {
            throw std::runtime_error("Sharder failed to load block params at layer " + std::to_string(block_idx));
        }
    }

    const std::string stage_prefix = "block" + std::to_string(block_idx) + "/";
    auto input_fp32 = ensure_fp32(input);
    auto hidden_states = rms_norm(input_fp32, block.input_layernorm_weight, config_.rms_norm_eps);
    check_tensor_finite_or_throw(hidden_states, stage_prefix + "attn_ln");
    stage_rss(stage_prefix + "attn_ln");
    auto attn_out = apply_attention(hidden_states, block, position_cos, position_sin, pad_mask, base_mask, rope_theta, block_idx);
    check_tensor_finite_or_throw(attn_out, stage_prefix + "attn_out");
    // HF semantics: Gemma3RMSNorm uses (1 + weight) scaling
    attn_out = rms_norm(attn_out, block.post_attention_layernorm_weight, config_.rms_norm_eps);
    check_tensor_finite_or_throw(attn_out, stage_prefix + "attn_post_norm");
    hidden_states = add(input_fp32, attn_out);
    check_tensor_finite_or_throw(hidden_states, stage_prefix + "attn_residual");
    stage_rss(stage_prefix + "attn_residual");

    auto residual = hidden_states;
    hidden_states = rms_norm(hidden_states, block.pre_feedforward_layernorm_weight, config_.rms_norm_eps);
    check_tensor_finite_or_throw(hidden_states, stage_prefix + "mlp_ln");
    stage_rss(stage_prefix + "mlp_ln");
    TensorPtr mlp_out;
    if (config_.checkpoint_mlp) {
        auto* block_ptr = &block;
        mlp_out = checkpoint([this, block_ptr, block_idx](const TensorPtr& inp) {
            return apply_mlp(inp, *block_ptr, block_idx);
        }, hidden_states);
    } else {
        mlp_out = apply_mlp(hidden_states, block, block_idx);
    }
    check_tensor_finite_or_throw(mlp_out, stage_prefix + "mlp_out");
    // HF semantics: Gemma3RMSNorm uses (1 + weight) scaling
    mlp_out = rms_norm(mlp_out, block.post_feedforward_layernorm_weight, config_.rms_norm_eps);
    check_tensor_finite_or_throw(mlp_out, stage_prefix + "mlp_post_norm");
    hidden_states = add(residual, mlp_out);
    check_tensor_finite_or_throw(hidden_states, stage_prefix + "mlp_residual");
    stage_rss(stage_prefix + "mlp_residual");
    hidden_states = maybe_fp16(config_.use_bf16_activations, hidden_states);
    return hidden_states;
}

TensorPtr GemmaModel::forward(const TensorPtr& input_ids,
                              const TensorPtr& attention_mask) {
    StageRssRecorder rss_recorder;
    StageRssRecorder* prev_recorder = tls_rss_recorder;
    if (rss_stage_enabled()) {
        tls_rss_recorder = &rss_recorder;
        stage_rss("forward/begin");
    }
    if (sharder_) {
        embed_weight_ = sharder_->require("embed_tokens.weight");
        if (!embed_weight_) {
            std::cerr << sharder_->debug_string();
            throw std::runtime_error("Sharder failed to load embed weight");
        }
    }

    auto hidden_states = embedding_lookup(input_ids);
    check_tensor_finite_or_throw(hidden_states, "forward/embeddings");
    if (debug_.enabled) {
        dump_tensor(hidden_states, "hidden_states_emb");
    }
    stage_rss("forward/embeddings");
    hidden_states = maybe_fp16(config_.use_bf16_activations, hidden_states);

    int64_t batch = hidden_states->shape()[0];
    int64_t seq_len = hidden_states->shape()[1];
    int64_t hidden_dim = hidden_states->shape()[2];
    maybe_dump_embedding(hidden_states, batch, seq_len, hidden_dim);

    auto causal_mask = build_causal_mask(seq_len);
    auto sliding_mask = build_sliding_mask(seq_len);
    auto pad_mask = build_padding_mask(attention_mask);
    stage_rss("forward/mask");

    auto rotary_global = build_rotary_embeddings(batch, seq_len, config_.rope_theta);
    auto rotary_local = build_rotary_embeddings(batch, seq_len, config_.rope_local_base_freq);

    for (int i = 0; i < config_.num_hidden_layers; ++i) {
        // Non-debug path loads per-block parameters inside forward_block().
        // Keep eager require here only for debug path where block compute is inlined below.
        if (sharder_ && debug_.enabled) {
            const std::string prefix = "layers." + std::to_string(i) + ".";
            sharder_->require(prefix + "input_layernorm.weight");
            sharder_->require(prefix + "post_attention_layernorm.weight");
            sharder_->require(prefix + "pre_feedforward_layernorm.weight");
            sharder_->require(prefix + "post_feedforward_layernorm.weight");
            sharder_->require(prefix + "self_attn.q_proj.weight");
            sharder_->require(prefix + "self_attn.k_proj.weight");
            sharder_->require(prefix + "self_attn.v_proj.weight");
            sharder_->require(prefix + "self_attn.o_proj.weight");
            sharder_->require(prefix + "self_attn.q_norm.weight");
            sharder_->require(prefix + "self_attn.k_norm.weight");
            sharder_->require(prefix + "mlp.gate_proj.weight");
            sharder_->require(prefix + "mlp.up_proj.weight");
            sharder_->require(prefix + "mlp.down_proj.weight");
        }

        bool is_sliding = i < static_cast<int>(config_.layer_types.size()) &&
                          config_.layer_types[i] == "sliding_attention";
        const auto& pos = is_sliding ? rotary_local : rotary_global;
        float rope_theta = is_sliding ? config_.rope_local_base_freq : config_.rope_theta;
        const auto& mask = is_sliding ? sliding_mask : causal_mask;
        if (!debug_.enabled) {
            if (config_.checkpoint_every > 0 && (i % config_.checkpoint_every) == 0) {
                int block_idx = i;
                auto pos_cos = pos.cos;
                auto pos_sin = pos.sin;
                auto ckpt_pad = pad_mask;
                auto base_mask = mask;
                float rope = rope_theta;
                hidden_states = checkpoint([this, block_idx, pos_cos, pos_sin, ckpt_pad, base_mask, rope](const TensorPtr& inp) {
                    return forward_block(inp, blocks_[block_idx], pos_cos, pos_sin, ckpt_pad, base_mask, rope, block_idx);
                }, hidden_states);
            } else {
                hidden_states = forward_block(hidden_states, blocks_[i], pos.cos, pos.sin, pad_mask, mask, rope_theta, i);
            }
            continue;
        }

        auto normed = rms_norm(hidden_states, blocks_[i].input_layernorm_weight, config_.rms_norm_eps);

        if (need_dump_layer(i)) {
            // Dump the exact tensor fed into attention (input_layernorm output)
            dump_tensor(normed, "hidden_before_attn_l" + std::to_string(i));
            // Also dump selected layer weights for cross-check (MLP weights)
            dump_tensor(blocks_[i].gate_proj_weight, "weights/gate_proj_weight_l" + std::to_string(i));
            dump_tensor(blocks_[i].up_proj_weight, "weights/up_proj_weight_l" + std::to_string(i));
            dump_tensor(blocks_[i].down_proj_weight, "weights/down_proj_weight_l" + std::to_string(i));
        }

        auto attn_out = apply_attention(normed, blocks_[i], pos.cos, pos.sin, pad_mask, mask, rope_theta, i);
        if (need_dump_layer(i)) dump_tensor(attn_out, "hidden_after_attn_l" + std::to_string(i));

        // HF semantics: Gemma3RMSNorm multiplies by (1 + weight)
        attn_out = rms_norm(attn_out, blocks_[i].post_attention_layernorm_weight, config_.rms_norm_eps);
        if (need_dump_layer(i)) dump_tensor(attn_out, "hidden_after_attn_norm_l" + std::to_string(i));
        hidden_states = add(hidden_states, attn_out);
        if (need_dump_layer(i)) dump_tensor(hidden_states, "hidden_after_attn_add_l" + std::to_string(i));

        auto residual = hidden_states;
        auto mlp_in = rms_norm(hidden_states, blocks_[i].pre_feedforward_layernorm_weight, config_.rms_norm_eps);
        if (need_dump_layer(i)) dump_tensor(mlp_in, "hidden_before_mlp_norm_l" + std::to_string(i));
        auto mlp_out = apply_mlp(mlp_in, blocks_[i], i);
        if (need_dump_layer(i)) dump_tensor(mlp_out, "hidden_after_mlp_l" + std::to_string(i));
        // HF semantics: Gemma3RMSNorm multiplies by (1 + weight)
        mlp_out = rms_norm(mlp_out, blocks_[i].post_feedforward_layernorm_weight, config_.rms_norm_eps);
        if (need_dump_layer(i)) dump_tensor(mlp_out, "hidden_after_mlp_norm_l" + std::to_string(i));
        hidden_states = add(residual, mlp_out);
    }

    if (sharder_) {
        norm_weight_ = sharder_->require("norm.weight");
        if (!norm_weight_) {
            std::cerr << sharder_->debug_string();
            throw std::runtime_error("Sharder failed to load norm.weight");
        }
    }
    hidden_states = ensure_fp32(hidden_states);
    hidden_states = rms_norm(hidden_states, norm_weight_, config_.rms_norm_eps);
    check_tensor_finite_or_throw(hidden_states, "forward/final_norm");
    stage_rss("forward/norm");
    if (sharder_) {
        lm_head_weight_ = sharder_->require("lm_head.weight");
        if (!lm_head_weight_) {
            std::cerr << sharder_->debug_string();
            throw std::runtime_error("Sharder failed to load lm_head.weight");
        }
    }
    auto logits = matmul(hidden_states, lm_head_weight_);
    check_tensor_finite_or_throw(logits, "forward/logits");
    stage_rss("forward/end");
    if (debug_.enabled) {
        dump_tensor(logits, "logits");
    }
    if (rss_stage_enabled()) {
        rss_recorder.print("gemma_forward");
    }
    tls_rss_recorder = prev_recorder;
    return logits;
}

void GemmaModel::assign_weight(const std::string& key, const TensorPtr& tensor) {
    if (key == "embed_tokens.weight") {
        embed_weight_ = tensor;
        if (auto_lm_head_tying_ && !lm_head_initialized_) {
            lm_head_weight_ = transpose(tensor, 0, 1);
            lm_head_initialized_ = true;
        }
        return;
    }
    if (key == "norm.weight") {
        norm_weight_ = tensor;
        return;
    }
    if (key == "lm_head.weight") {
        lm_head_weight_ = tensor;
        lm_head_initialized_ = true;
        return;
    }

    std::regex block_pattern(R"(layers\.(\d+)\.(.+))");
    std::smatch match;
    if (!std::regex_match(key, match, block_pattern)) {
        throw std::runtime_error("Unknown Gemma weight key: " + key);
    }

    int layer = std::stoi(match[1].str());
    if (layer < 0 || layer >= config_.num_hidden_layers) {
        throw std::runtime_error("Invalid Gemma layer index: " + std::to_string(layer));
    }
    std::string name = match[2].str();
    auto& block = blocks_[layer];

    if (name == "input_layernorm.weight") block.input_layernorm_weight = tensor;
    else if (name == "post_attention_layernorm.weight") block.post_attention_layernorm_weight = tensor;
    else if (name == "pre_feedforward_layernorm.weight") block.pre_feedforward_layernorm_weight = tensor;
    else if (name == "post_feedforward_layernorm.weight") block.post_feedforward_layernorm_weight = tensor;
    else if (name == "self_attn.q_proj.weight") block.q_proj_weight = tensor;
    else if (name == "self_attn.k_proj.weight") block.k_proj_weight = tensor;
    else if (name == "self_attn.v_proj.weight") block.v_proj_weight = tensor;
    else if (name == "self_attn.o_proj.weight") block.o_proj_weight = tensor;
    else if (name == "self_attn.q_norm.weight") block.q_norm_weight = tensor;
    else if (name == "self_attn.k_norm.weight") block.k_norm_weight = tensor;
    else if (name == "mlp.gate_proj.weight") block.gate_proj_weight = tensor;
    else if (name == "mlp.up_proj.weight") block.up_proj_weight = tensor;
    else if (name == "mlp.down_proj.weight") block.down_proj_weight = tensor;
    else
        throw std::runtime_error("Unknown Gemma block weight: " + name);
}

TensorPtr* GemmaModel::weight_ref(const std::string& key) {
    if (key == "embed_tokens.weight") return &embed_weight_;
    if (key == "norm.weight") return &norm_weight_;
    if (key == "lm_head.weight") return &lm_head_weight_;

    std::regex block_pattern(R"(layers\.(\d+)\.(.+))");
    std::smatch match;
    if (!std::regex_match(key, match, block_pattern)) {
        throw std::runtime_error("Unknown Gemma weight key: " + key);
    }

    const int layer = std::stoi(match[1].str());
    if (layer < 0 || layer >= config_.num_hidden_layers) {
        throw std::runtime_error("Invalid Gemma layer index: " + std::to_string(layer));
    }
    auto& block = blocks_[layer];
    const std::string name = match[2].str();

    if (name == "input_layernorm.weight") return &block.input_layernorm_weight;
    if (name == "post_attention_layernorm.weight") return &block.post_attention_layernorm_weight;
    if (name == "pre_feedforward_layernorm.weight") return &block.pre_feedforward_layernorm_weight;
    if (name == "post_feedforward_layernorm.weight") return &block.post_feedforward_layernorm_weight;
    if (name == "self_attn.q_proj.weight") return &block.q_proj_weight;
    if (name == "self_attn.k_proj.weight") return &block.k_proj_weight;
    if (name == "self_attn.v_proj.weight") return &block.v_proj_weight;
    if (name == "self_attn.o_proj.weight") return &block.o_proj_weight;
    if (name == "self_attn.q_norm.weight") return &block.q_norm_weight;
    if (name == "self_attn.k_norm.weight") return &block.k_norm_weight;
    if (name == "mlp.gate_proj.weight") return &block.gate_proj_weight;
    if (name == "mlp.up_proj.weight") return &block.up_proj_weight;
    if (name == "mlp.down_proj.weight") return &block.down_proj_weight;

    throw std::runtime_error("Unknown Gemma block weight: " + name);
}

GemmaBlockWeights& GemmaModel::get_block(int i) {
    if (i < 0 || i >= static_cast<int>(blocks_.size())) {
        throw std::out_of_range("Gemma block index");
    }
    return blocks_[i];
}

const GemmaBlockWeights& GemmaModel::get_block(int i) const {
    if (i < 0 || i >= static_cast<int>(blocks_.size())) {
        throw std::out_of_range("Gemma block index");
    }
    return blocks_[i];
}

void GemmaModel::enable_debug_dump(const std::string& dir, const std::vector<int>& layers) {
    debug_.enabled = true;
    debug_.dir = dir;
    debug_.layers.clear();
    debug_.tensors.clear();
    for (int l : layers) debug_.layers.insert(l);
}

void GemmaModel::disable_debug_dump() {
    debug_ = DebugConfig{};
}

void GemmaModel::dump_layer_norm_weights(int layer, const std::string& dir) const {
    if (layer < 0 || layer >= static_cast<int>(blocks_.size())) return;
    const auto& block = blocks_[layer];
    auto dump_vec = [&](const TensorPtr& w, const std::string& name) {
        if (!w) return;
        if (w->dtype() == DType::kFloat32) {
            save_npy(dir + "/" + name + ".npy", w->data<float>(), w->shape(), DumpDType::kFloat32);
        }
    };
    dump_vec(block.input_layernorm_weight, "weights/input_layernorm_l" + std::to_string(layer));
    dump_vec(block.post_attention_layernorm_weight, "weights/post_attention_layernorm_l" + std::to_string(layer));
    dump_vec(block.pre_feedforward_layernorm_weight, "weights/pre_feedforward_layernorm_l" + std::to_string(layer));
    dump_vec(block.post_feedforward_layernorm_weight, "weights/post_feedforward_layernorm_l" + std::to_string(layer));
    // Additional export: q_norm/k_norm weights for PT comparison
    dump_vec(block.q_norm_weight, "weights/q_norm_l" + std::to_string(layer));
    dump_vec(block.k_norm_weight, "weights/k_norm_l" + std::to_string(layer));
}
void GemmaModel::set_numeric_perturb(bool enable, const std::string& name, int64_t index, float eps) {
    debug_.numeric_enabled = enable;
    debug_.numeric_name = name;
    debug_.numeric_index = index;
    debug_.numeric_eps = eps;
}

bool GemmaModel::need_dump_layer(int idx) const {
    return debug_.layers.empty() || debug_.layers.count(idx) > 0;
}

void GemmaModel::dump_tensor(const TensorPtr& t, const std::string& name) const {
    if (!t || !debug_.enabled) return;
    if (t->requires_grad() && debug_.retain_grads) {
        t->retain_grad();  // Retain non-leaf gradients
    }
    // Cache tensor to read gradients after backward
    debug_.tensors[name] = t;
    std::vector<int64_t> shape = t->shape();
    std::string path = debug_.dir + "/" + name + ".npy";
    if (t->dtype() == DType::kFloat32) {
        save_npy(path, t->data<float>(), shape, DumpDType::kFloat32);
    } else if (t->dtype() == DType::kInt32) {
        save_npy(path, t->data<int32_t>(), shape, DumpDType::kInt32);
    }
}

void GemmaModel::init_lora_modules() {
    for (auto& block : blocks_) {
        if (block.lora_initialized) continue;

        block.q_proj_lora = std::make_unique<LoRALinear>(&block.q_proj_weight, nullptr);
        block.k_proj_lora = std::make_unique<LoRALinear>(&block.k_proj_weight, nullptr);
        block.v_proj_lora = std::make_unique<LoRALinear>(&block.v_proj_weight, nullptr);
        block.o_proj_lora = std::make_unique<LoRALinear>(&block.o_proj_weight, nullptr);

        block.gate_proj_lora = std::make_unique<LoRALinear>(&block.gate_proj_weight, nullptr);
        block.up_proj_lora = std::make_unique<LoRALinear>(&block.up_proj_weight, nullptr);
        block.down_proj_lora = std::make_unique<LoRALinear>(&block.down_proj_weight, nullptr);

        block.lora_initialized = true;
    }
}

std::vector<TensorPtr> GemmaModel::get_lora_parameters() const {
    std::vector<TensorPtr> params;
    for (const auto& block : blocks_) {
        auto collect = [&](const std::unique_ptr<LoRALinear>& linear) {
            if (!linear) return;
            auto slices = linear->trainable_parameters();
            params.insert(params.end(), slices.begin(), slices.end());
        };
        collect(block.q_proj_lora);
        collect(block.k_proj_lora);
        collect(block.v_proj_lora);
        collect(block.o_proj_lora);
        collect(block.gate_proj_lora);
        collect(block.up_proj_lora);
        collect(block.down_proj_lora);
    }
    return params;
}

void GemmaModel::merge_lora() {
    for (auto& block : blocks_) {
        if (!block.lora_initialized) continue;
        if (block.q_proj_lora) block.q_proj_lora->merge_to_base();
        if (block.k_proj_lora) block.k_proj_lora->merge_to_base();
        if (block.v_proj_lora) block.v_proj_lora->merge_to_base();
        if (block.o_proj_lora) block.o_proj_lora->merge_to_base();
        if (block.gate_proj_lora) block.gate_proj_lora->merge_to_base();
        if (block.up_proj_lora) block.up_proj_lora->merge_to_base();
        if (block.down_proj_lora) block.down_proj_lora->merge_to_base();
    }
}

void GemmaModel::unmerge_lora() {
    for (auto& block : blocks_) {
        if (!block.lora_initialized) continue;
        if (block.q_proj_lora) block.q_proj_lora->unmerge_from_base();
        if (block.k_proj_lora) block.k_proj_lora->unmerge_from_base();
        if (block.v_proj_lora) block.v_proj_lora->unmerge_from_base();
        if (block.o_proj_lora) block.o_proj_lora->unmerge_from_base();
        if (block.gate_proj_lora) block.gate_proj_lora->unmerge_from_base();
        if (block.up_proj_lora) block.up_proj_lora->unmerge_from_base();
        if (block.down_proj_lora) block.down_proj_lora->unmerge_from_base();
    }
}

void GemmaModel::request_embedding_dump(int step, const std::string& output_dir) {
    dump_request_.active = true;
    dump_request_.target_step = step;
    dump_request_.output_dir = output_dir;
    dump_request_.fulfilled = false;
}

void GemmaModel::maybe_dump_embedding(const TensorPtr& hidden_states,
                                      int batch,
                                      int seq_len,
                                      int hidden_dim) {
    if (!dump_request_.active || dump_request_.fulfilled) {
        return;
    }

    const float* data = hidden_states->data<float>();
    int64_t total = static_cast<int64_t>(batch) * seq_len * hidden_dim;
    if (total == 0) {
        dump_request_.fulfilled = true;
        dump_request_.active = false;
        return;
    }

    double sum = 0.0;
    double sumsq = 0.0;
    float min_val = std::numeric_limits<float>::max();
    float max_val = std::numeric_limits<float>::lowest();
    for (int64_t i = 0; i < total; ++i) {
        float v = data[i];
        sum += v;
        sumsq += static_cast<double>(v) * v;
        min_val = std::min(min_val, v);
        max_val = std::max(max_val, v);
    }
    double mean = sum / static_cast<double>(total);
    double var = sumsq / static_cast<double>(total) - mean * mean;
    if (var < 0.0) var = 0.0;
    double stddev = std::sqrt(var);

    std::cout << "[EmbeddingDump] step " << dump_request_.target_step
              << " shape=[" << batch << "," << seq_len << "," << hidden_dim << "] "
              << std::fixed << std::setprecision(6)
              << "mean=" << mean << " std=" << stddev
              << " min=" << min_val << " max=" << max_val << std::endl;

    int tokens_to_show = std::min<int>(seq_len, 4);
    int dims_to_show = std::min<int>(hidden_dim, 8);
    for (int t = 0; t < tokens_to_show; ++t) {
        std::cout << "  hidden[0," << t << ",0:" << dims_to_show << "] = [";
        for (int d = 0; d < dims_to_show; ++d) {
            int64_t idx = ((0 * seq_len) + t) * hidden_dim + d;
            std::cout << std::setprecision(4) << data[idx];
            if (d + 1 < dims_to_show) std::cout << ", ";
        }
        std::cout << "]" << std::endl;
    }

    try {
        std::filesystem::create_directories(dump_request_.output_dir);
        std::string filename = dump_request_.output_dir + "/embedding_step" +
                               std::to_string(dump_request_.target_step) + ".bin";
        std::ofstream out(filename, std::ios::binary);
        if (out) {
            out.write(reinterpret_cast<const char*>(data), total * sizeof(float));
            std::cout << "  [EmbeddingDump] wrote raw tensor to " << filename << std::endl;
        } else {
            std::cerr << "  [EmbeddingDump] failed to write " << filename << std::endl;
        }
    } catch (const std::exception& e) {
        std::cerr << "  [EmbeddingDump] filesystem error: " << e.what() << std::endl;
    }

    dump_request_.fulfilled = true;
    dump_request_.active = false;
}

}  // namespace ops
