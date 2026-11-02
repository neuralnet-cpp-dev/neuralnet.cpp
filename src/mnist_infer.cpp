// ── MNIST 手写数字推理程序（引擎化架构） ─────────────────────────────────
//
// 数据流：
//   CSV 行 → Matrix(784, 1) → engine.from_matrix → Tensor[device]
//     → model.forward(Tensor) → Tensor
//     → engine.to_matrix → CPU softmax + top-k 展示
//
// 引擎选择：--gpu 启用 GpuEngine（需要 Vulkan），否则 CpuEngine。
// ─────────────────────────────────────────────────────────────────────────

#include <neuralnet.cpp/nn.hpp>
#include <neuralnet.cpp/model_serialization.hpp>
#include <neuralnet.cpp/domain_mnist.hpp>
#include <neuralnet.cpp/cli/cli_engine_factory.hpp>
#include <neuralnet.cpp/cli/cli_gpu_option.hpp>
#include <neuralnet.cpp/cli/cli_help.hpp>

#include <algorithm>
#include <cstdint>
#include <filesystem>
#include <fstream>
#include <iomanip>
#include <iostream>
#include <memory>
#include <numeric>
#include <string>
#include <utility>
#include <vector>

namespace fs = std::filesystem;

using nn::Scalar;

// ==================== 帮助信息 ====================
void print_usage(const char* prog)
{
    nn::cli::Help help(std::cout, prog, "MNIST 手写数字推理程序");

    help.usage("<image.csv> [选项]", "推理单张图片");
    help.usage("<目录> [选项]", "批量推理目录下所有 CSV");

    help.section("选项");
    help.opt("--model <path>", "模型文件路径 (默认: pretrained/model.bin)");
    help.opt("--topk <n>", "显示前 n 个预测结果 (默认: 3)");
    help.opt("--show-pixels", "显示像素矩阵 (调试用)");
    help.opt("--gpu [索引|名称]",
             "启用 GPU 加速 (需要 Vulkan SDK)\n空格形式只收枚举索引；名称子串用 --gpu=<名称>，如 "
             "--gpu=NVIDIA / --gpu=40HX");
    help.opt("--help, -h", "显示此帮助信息");
}

// ==================== 命令行参数 ====================
struct InferConfig
{
    std::string model_path = "pretrained/model.bin";
    std::string input_path;
    int topk = 3;
    bool show_pixels = false;
    bool gpu_enabled = false;
    std::string gpu_device;      // --gpu 的可选设备选择子（空 = 自动选卡）
};

nn::Result<InferConfig> parse_args(int argc, char* argv[])
{
    InferConfig cfg;
    bool has_input = false;

    for (int i = 1; i < argc; ++i)
    {
        std::string arg = argv[i];
        if (arg == "--help" || arg == "-h")
        {
            print_usage(argv[0]);
            std::exit(0);
        }
        else if (arg == "--model" && i + 1 < argc) { cfg.model_path = argv[++i]; }
        else if (arg == "--topk" && i + 1 < argc)
        {
            auto v = nn::parse_number<int>(argv[++i]);
            NN_TRY_CHECK(v);
            if (*v <= 0) NN_FAIL("--topk 必须为正整数");
            if (*v > static_cast<int>(nn::MNIST_NUM_CLASSES))
                NN_FAIL("--topk 不能超过类别数 " + std::to_string(nn::MNIST_NUM_CLASSES));
            cfg.topk = *v;
        }
        else if (arg == "--show-pixels") { cfg.show_pixels = true; }
        else if (auto dev = nn::cli::parse_gpu_option(argc, argv, i))
        {
            cfg.gpu_enabled = true;
            if (!dev->empty()) cfg.gpu_device = *dev;
        }
        else if (!arg.starts_with("--"))
        {
            cfg.input_path = arg;
            has_input = true;
        }
        else
        {
            NN_FAIL("未知参数: " + arg + "，使用 --help 查看用法");
        }
    }

    if (!has_input) NN_FAIL("请指定图片文件或目录，使用 --help 查看用法");
    return cfg;
}

// ==================== 推理 + 置信度 ====================
struct Prediction
{
    int digit;
    Scalar confidence;
};

// 前向：Matrix → engine.from_matrix → model.forward → engine.to_matrix
// 后续 softmax / top-k 在 CPU 上完成（单张图片，开销可忽略）
nn::Result<std::vector<Prediction>> predict_with_confidence(nn::Model& model,
                                                            nn::ComputeEngine& engine,
                                                            const nn::Matrix& img, int topk)
{
    auto x_tensor_r = engine.from_matrix(img);
    NN_TRY_CHECK(x_tensor_r);
    auto logits_tensor_r = model.forward(*x_tensor_r);
    NN_TRY_CHECK(logits_tensor_r);
    auto logits_r = engine.to_matrix(*logits_tensor_r);
    NN_TRY_CHECK(logits_r);
    const auto& logits = *logits_r;

    // Softmax 计算概率
    Scalar max_val = logits.at_unchecked(0, 0);
    for (int c = 1; c < static_cast<int>(nn::MNIST_NUM_CLASSES); ++c)
        max_val = std::max(max_val, logits.at_unchecked(c, 0));

    Scalar sum_exp = 0.0;
    std::vector<Scalar> probs(nn::MNIST_NUM_CLASSES);
    for (std::size_t c = 0; c < nn::MNIST_NUM_CLASSES; ++c)
    {
        probs[c] = std::exp(logits.at_unchecked(c, 0) - max_val);
        sum_exp += probs[c];
    }
    // 防御：logits 全为 -inf 时 sum_exp == 0，回退为均匀分布避免 NaN
    if (!(sum_exp > 0.0) || !std::isfinite(sum_exp))
    {
        for (auto& p : probs)
            p = Scalar{1} / static_cast<Scalar>(nn::MNIST_NUM_CLASSES);
    }
    else
    {
        for (auto& p : probs)
            p /= sum_exp;
    }

    // 按概率排序取 top-k
    std::vector<int> indices(nn::MNIST_NUM_CLASSES);
    std::iota(indices.begin(), indices.end(), 0);
    std::partial_sort(indices.begin(), indices.begin() + topk, indices.end(),
                      [&](int a, int b) { return probs[a] > probs[b]; });

    std::vector<Prediction> results;
    for (int k = 0; k < topk; ++k)
        results.push_back({indices[k], probs[indices[k]]});

    return results;
}

// ==================== 显示像素矩阵 ====================
void show_pixels(const nn::Matrix& img)
{
    for (int r = 0; r < 28; ++r)
    {
        std::cout << "  ";
        for (int c = 0; c < 28; ++c)
        {
            Scalar val = img.at_unchecked(r * 28 + c, 0);
            if (val > 0.5) std::cout << "##";
            else if (val > 0.1) std::cout << "..";
            else std::cout << "  ";
        }
        std::cout << "\n";
    }
}

// ==================== 推理单张图片 ====================
nn::Result<void> infer_single(nn::Model& model, nn::ComputeEngine& engine,
                              const std::string& filepath, const InferConfig& cfg)
{
    std::ifstream file(filepath);
    if (!file) NN_FAIL("无法打开文件: " + filepath);
    std::string line;
    std::getline(file, line);
    auto img_result = nn::load_image_from_csv_line(line);
    NN_TRY_CHECK(img_result);
    auto img = std::move(*img_result);

    if (cfg.show_pixels)
    {
        std::cout << "像素预览:\n";
        show_pixels(img);
        std::cout << "\n";
    }

    auto results = predict_with_confidence(model, engine, img, cfg.topk);
    NN_TRY_CHECK(results);
    std::cout << fs::path(filepath).filename().string() << " -> ";
    for (std::size_t k = 0; k < results->size(); ++k)
    {
        if (k > 0) std::cout << "  ";
        std::cout << (*results)[k].digit << " (" << std::fixed << std::setprecision(1)
                  << (*results)[k].confidence * 100.0 << "%)";
    }
    std::cout << std::endl;
    return {};
}

// ==================== 主函数 ====================
int main(int argc, char* argv[])
{
    auto cfg_result = parse_args(argc, argv);
    NN_EXIT(cfg_result, 1, "参数错误: ");
    InferConfig cfg = std::move(*cfg_result);

    // ── 从模型文件读取规格（v5/v6/v7 同一 magic，自动按版本分流）──────────
    auto spec_result = nn::peek_any_model_spec(cfg.model_path);
    NN_EXIT(spec_result, 1, "读取模型文件失败: ");
    nn::ModelSpec spec = spec_result.value();
    auto role_r = nn::peek_model_role(cfg.model_path);
    NN_EXIT(role_r, 1, "读取模型文件失败: ");

    // 支持的模型类型：MLP、Transformer（ViT）、CNN
    if (spec.is_mlp()) { std::cout << "从模型文件读取规格: MLP\n"; }
    else if (spec.is_transformer()) { std::cout << "从模型文件读取规格: Transformer (ViT)\n"; }
    else if (spec.is_cnn()) { std::cout << "从模型文件读取规格: CNN (LeNet)\n"; }
    else
    {
        std::cerr << "不支持的模型类型 (type=" << spec.type_name() << ")\n";
        return 1;
    }

    // ── 创建计算引擎 ─────────────────────────────────────────
    // 引擎必须先于 model 构造并晚于 model 析构（model 持有 engine 的非拥有指针）
    nn::cli::EngineConfig eng_cfg;
    eng_cfg.use_gpu = cfg.gpu_enabled;
    eng_cfg.gpu_device = cfg.gpu_device;
    auto engine_res = nn::cli::create_engine(eng_cfg, std::cout);
    NN_EXIT(engine_res, 1, "引擎创建失败: ");
    auto engine = std::move(*engine_res);

    // ── 构建模型（绑定引擎） ─────────────────────────────────
    // 免 latent 构建（2026-11）：role=Model（.nnmodel）→ 三值层按部署形态构建
    // （BitLinear 不分配 f32 latent，权重由载入的打包字 + τ 接管；与 text_infer
    // 同款开关，消除"先建 latent 再被部署条目丢弃"的载入期瞬时峰值）。
    const bool inference_only = (*role_r == nn::ModelRole::Model);
    auto build_result = nn::build_mnist_model_from_spec(*engine, spec, nn::PrecisionProfile{},
                                                       inference_only);
    NN_EXIT(build_result, 1, "构建模型失败: ");
    auto model = std::move(*build_result);

    {
        auto load_result = nn::load_any_model(cfg.model_path, model, nullptr, nullptr);
        NN_EXIT(load_result, 1, "加载模型失败: ");
        std::cout << "模型已加载（角色: " << nn::model_role_name(*role_r)
                  << "）: " << cfg.model_path << "\n"
                  << std::endl;
        // 载入期的解码/中转底材已无活跃引用 → 归还整块空闲池底材
        NN_EXIT(engine->release_idle_pool_blocks(), 1, "显存回收失败: ");
    }

    // 推理模式：BatchNorm 使用保存的 running 统计量（batch 可能为 1，不能算 batch 统计）
    model.set_training(false);

    fs::path input(cfg.input_path);

    if (fs::is_directory(input))
    {
        // 批量推理
        std::vector<fs::path> csv_files;
        for (auto& entry : fs::directory_iterator(input))
        {
            if (entry.path().extension() == ".csv") csv_files.push_back(entry.path());
        }
        std::sort(csv_files.begin(), csv_files.end());

        if (csv_files.empty())
        {
            std::cerr << "目录中没有 CSV 文件: " << cfg.input_path << std::endl;
            return 1;
        }

        std::cout << "找到 " << csv_files.size() << " 个文件\n" << std::endl;

        for (auto& f : csv_files)
        {
            auto result = infer_single(model, *engine, f.string(), cfg);
            if (!result)
            {
                std::cerr << "推理失败: " << f.filename().string() << ": " << result.error().message
                          << '\n';
            }
        }

        std::cout << "\n共推理 " << csv_files.size() << " 张图片" << std::endl;
    }
    else if (fs::is_regular_file(input))
    {
        // 单张推理
        auto result = infer_single(model, *engine, input.string(), cfg);
        NN_EXIT(result, 1, "推理失败: ");
    }
    else
    {
        std::cerr << "输入路径不存在: " << cfg.input_path << std::endl;
        return 1;
    }

    return 0;
}
