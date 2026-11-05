// ── MNIST 手写数字训练程序（引擎化架构，支持 MLP 与 Transformer） ────────
//
// 数据流：
//   CSV → Matrix(feat_dim, N) + Matrix(10, N)
//   每 batch：Matrix → engine.from_matrix → Tensor[device]
//     → model.forward(Tensor) → Tensor
//     → ce_loss.forward(engine, out, target) → Scalar
//     → ce_loss.backward() → Tensor
//     → model.backward(Tensor) → (丢弃)
//     → optimizer.step() / model.zero_grad()
//   evaluate：forward → engine.to_matrix → CPU argmax
//
// 引擎选择：--gpu 启用 GpuEngine（需要 Vulkan），否则 CpuEngine。
// 架构选择：--arch mlp|transformer（默认 mlp，从已保存模型 resume 时自动识别）
// ─────────────────────────────────────────────────────────────────────────

#include <nn_error_macros.hpp>
#include <neuralnet.cpp/nn.hpp>
#include <neuralnet.cpp/model_serialization.hpp>
#include <neuralnet.cpp/domain_mnist.hpp>
#include <neuralnet.cpp/precision.hpp>
#include <neuralnet.cpp/cli/cli_engine_factory.hpp>
#include <neuralnet.cpp/cli/cli_help.hpp>
#include <neuralnet.cpp/cli/cli_lr_scheduler.hpp>
#include <neuralnet.cpp/cli/cli_mnist_io.hpp>
#include <neuralnet.cpp/cli/cli_train_common.hpp>
#include <neuralnet.cpp/cli/cli_precision_warning.hpp>

#include <algorithm>
#include <chrono>
#include <cstdint>
#include <cstring>
#include <iomanip>
#include <iostream>
#include <memory>
#include <optional>
#include <random>
#include <sstream>
#include <string>
#include <utility>
#include <vector>

using nn::Scalar;

// ── 精度解析辅助 ─────────────────────────────────────────────────────────
// allow_t1_58：三值（T1_58）**只适用于 param 槽**（"该层权重是三值"），
// compute/stable/optimizer 出现它一律在参数解析处拒绝，而不是拖到 init 期才报
// 能力校验错误（docs/internal/21-quantized-weights.md §4.1）。
nn::Precision parse_precision(const std::string& name, const char* flag, bool allow_t1_58 = false)
{
    if (name == "f16" || name == "half") return nn::Precision::F16;
    if (name == "f32" || name == "float") return nn::Precision::F32;
    if (name == "t1_58")
    {
        if (allow_t1_58) return nn::Precision::T1_58;
        std::cerr << "无效 --" << flag << ": t1_58（三值权重只适用于 --precision-param）"
                  << "，可选: f16, f32\n";
        std::exit(1);
    }
    std::cerr << "无效 --" << flag << ": " << name
              << "，可选: " << (allow_t1_58 ? "f16, f32, t1_58" : "f16, f32") << "\n";
    std::exit(1);
}

enum class ArchType
{
    MLP,
    Transformer,
    CNN
};

// ==================== 帮助信息 ====================
void print_usage(const char* prog)
{
    nn::cli::Help help(std::cout, prog, "MNIST 手写数字训练程序 (MLP / Transformer / CNN)");

    help.usage("[选项]");

    help.section("选项");
    help.opt("--arch <name>", "模型架构: mlp/transformer/cnn (默认: mlp)");
    help.opt("--resume <path>", "从已有模型恢复训练 (自动读取模型规格与架构；\n推理模型 .nnmodel "
                                "没有训练参数，会被明确拒绝)");
    help.opt("--save <path>",
             "推理模型保存路径 (默认: "
             "mnist_model.nnmodel；\n只含推理所需参数——三值层写打包形态，不含训练参数)");
    help.opt("--dataset <path>", "数据集目录 (默认: datasets/mnist_data)");
    help.opt("--epochs <n>", "训练轮数 (默认: 10)");
    help.opt("--lr <lr>", "学习率 (默认: 0.001)");
    help.opt("--batch-size <n>", "批大小 (默认: 64)");
    // RV-04：名单文本由 nn::optimizer_table()（唯一真源）生成，不再手抄
    help.opt("--optimizer <name>", "优化器: " + nn::optimizer_names("/") +
                                       " (默认: adam)\nadamwquant: 量化状态的 AdamW（状态 4 B/权重 "
                                       "vs 8 B；见 docs/internal/21 §4.13）");
    help.opt("--weight-decay <w>", "AdamW 权重衰减系数 (默认: 0.01)");
    help.opt("--max-samples <n>", "限制训练样本数 (默认: 全部，用于快速测试)");
    help.opt("--shuffle-steps <true|false>", "每 epoch 打乱 batch 顺序 (默认: true)");
    help.opt("--gpu [索引|名称]",
             "启用 GPU 加速 (需要 Vulkan SDK)\n空格形式只收枚举索引；名称子串用 --gpu=<名称>，如 "
             "--gpu=NVIDIA / --gpu=40HX");
    help.opt("--help, -h", "显示此帮助信息");

    help.section("MLP 专用");
    help.opt("--layer-dims <d1,d2,...>", "各层维度，逗号分隔 (默认: 784,512,256,128,64,10)");

    help.section("归一化");
    help.opt("--norm <type>",
             "归一化层: auto/layernorm/rmsnorm/batchnorm (默认: auto)\nauto = 按架构取最合适: "
             "MLP/ViT = layernorm, CNN = batchnorm\nlayernorm: 按特征维归一化\nrmsnorm: "
             "无均值、更轻量\nbatchnorm: 沿 batch 维归一化");
    help.opt("--norm-place <where>",
             "归一化挂载位置: auto/none/conv/head/both/final (默认: auto)\nauto = 按架构: CNN = "
             "conv, ViT = final, MLP = 结构内置(不额外加)\nconv: CNN 每个卷积(+池化)之后; head: "
             "CNN 全连接头 Linear→Norm→ReLU; both: 两者\nfinal: ViT 编码器末端 final norm "
             "(全局平均池化之前)\nMLP 的挂载位置由结构固定，只接受 none/auto");

    help.section("Transformer 专用");
    help.opt("--d-model <n>", "模型维度 (默认: 64)");
    help.opt("--num-heads <n>", "注意力头数 (默认: 4)");
    help.opt("--num-layers <n>", "Transformer 层数 (默认: 2)");
    help.opt("--d-ff <n>", "FFN 中间维度 (默认: 128)");
    help.opt("--patch-size <n>", "patch 大小 (默认: 7；28/7=4 → 16 patches)");
    help.opt("--eval-samples <n>", "评估样本数 (默认: 200，避免评估过慢)");

    help.section("CNN 专用 (LeNet-5 风格)");
    help.opt("--cnn-channels <c1,c2,...>", "每个卷积层输出通道 (默认: 6,16)");
    help.opt("--cnn-kernels <k1,k2,...>", "每个卷积核大小 (默认: 5,5)");
    help.opt("--cnn-pool <n>", "每个卷积后的 MaxPool 窗口 (默认: 2；0=无池化)");
    help.opt("--cnn-fc <d1,d2,...>", "展平后的全连接头 (默认: 120,10；末位为类别数)");

    help.section("学习率调度");
    help.opt("--lr-schedule <type>", "学习率调度: fixed/constant/cosine (默认: fixed)\ncosine: "
                                     "余弦退火 (epoch 级)，lr 从初始值衰减到 min-lr");
    help.opt("--warmup-epochs <n>", "线性预热轮数 (默认: 0，即不预热)");
    help.opt("--min-lr <lr>", "余弦退火最低学习率 (默认: 1e-6)");
    help.opt("--lr-per-epoch <v1,v2,...>", "手动指定每轮学习率 (逗号分隔，优先级最高)");

    help.section("混合精度 (docs/development/05-mixed-precision.md)");
    help.opt("--f16", "快捷方式: f16 存储 (param/compute=F16，stable/optimizer=F32)");
    help.opt("--t1_58", "快捷方式: 精度预设 t1_58 = f16 存储 + "
                        "三值权重\n(param=T1_58，compute=F16，stable/optimizer=F32；等价于 --f16 "
                        "再把 param 换成 t1_58)");
    help.opt("--precision-param <f16|f32|t1_58>",
             "权重/参数精度 (默认: f32)；t1_58 = 三值权重 BitLinear（1.58-bit）；"
             "本入口仅 MLP 架构支持（transformer/CNN 由层能力校验报错），"
             "GPT 见 text_train；docs/internal/21-quantized-weights.md");
    help.opt("--precision-compute <f16|f32>", "常规算子计算精度 (默认: f32)");
    help.opt("--precision-stable <f16|f32>", "数值敏感算子精度 (默认: f32)");
    help.opt("--precision-optimizer <f16|f32>", "优化器状态精度 (默认: f32)");
}

// ==================== 命令行参数 ====================
struct TrainConfig
{
    ArchType arch = ArchType::MLP;
    std::string save_path = "mnist_model.nnmodel";
    std::string dataset_path = "datasets/mnist_data";
    std::string resume_path;
    std::string optimizer_name = "adam";
    int epochs = 10;
    Scalar lr = 0.001;
    Scalar weight_decay = 0.01f;  // AdamW 权重衰减系数
    std::size_t batch_size = 64;
    bool load_existing = false;
    bool gpu_enabled = false;
    std::string gpu_device;      // --gpu 的可选设备选择子（空 = 自动选卡）
    int max_train_samples = -1;  // -1 表示使用全部
    bool shuffle_steps = true;   // 每 epoch 打乱 batch 顺序

    // MLP 参数
    std::vector<std::size_t> layer_dims;
    // 归一化（两者都可未指定 = auto → build_spec 按架构取默认：
    //   MLP = layernorm + 结构内置挂载；CNN = batchnorm@conv；ViT = layernorm@final）
    std::optional<nn::NormType> norm_type;    // --norm（未指定/显式 auto = 架构默认）
    std::optional<nn::NormPlace> norm_place;  // --norm-place（同上）

    // Transformer 参数
    std::size_t d_model = nn::MNIST_TF_D_MODEL;
    std::size_t num_heads = nn::MNIST_TF_NUM_HEADS;
    std::size_t d_ff = nn::MNIST_TF_D_FF;
    std::size_t num_layers = nn::MNIST_TF_NUM_LAYERS;
    std::size_t patch_size = nn::MNIST_PATCH_SIZE;
    std::size_t eval_samples = 200;  // Transformer 评估样本上限

    // CNN 参数（LeNet-5 风格默认）
    std::size_t cnn_in_channels = 1;
    std::size_t cnn_in_size = 28;
    std::size_t cnn_pool = 2;
    std::vector<std::size_t> cnn_channels;  // 每卷积输出通道
    std::vector<std::size_t> cnn_kernels;   // 每卷积核大小
    std::vector<std::size_t> cnn_fc_dims;   // 全连接头（不含展平输入）

    // 学习率调度
    std::string lr_schedule = "fixed";  // fixed / cosine
    int warmup_epochs = 0;              // 线性预热轮数
    Scalar min_lr = 1e-6f;              // 余弦退火最低 lr
    std::vector<Scalar> lr_per_epoch;   // 手动指定每轮 lr（为空则自动计算）

    // 混合精度控制（docs/development/05-mixed-precision.md §9.1）
    nn::PrecisionProfile precision;     // 默认全 F32（零回归）
};

TrainConfig parse_args(int argc, char* argv[])
{
    TrainConfig cfg;
    nn::cli::TrainCommonArgs common;
    // 程序专属默认值（覆盖 TrainCommonArgs 的默认值）
    common.batch_size = 64;
    common.weight_decay = 0.01f;
    common.min_lr = 1e-6f;
    common.lr_schedule = "fixed";

    for (int i = 1; i < argc; ++i)
    {
        std::string arg = argv[i];
        if (arg == "--help" || arg == "-h")
        {
            print_usage(argv[0]);
            std::exit(0);
        }
        // 通用训练参数委托给 nn::cli::parse_train_common_args
        else if (nn::cli::parse_train_common_args(argc, argv, i, common)) { continue; }
        else if (arg == "--arch" && i + 1 < argc)
        {
            std::string v = argv[++i];
            if (v == "mlp") cfg.arch = ArchType::MLP;
            else if (v == "transformer" || v == "tf") cfg.arch = ArchType::Transformer;
            else if (v == "cnn") cfg.arch = ArchType::CNN;
            else
            {
                std::cerr << "未知 --arch: " << v << "，可选: mlp, transformer, cnn\n";
                std::exit(1);
            }
        }
        else if (arg == "--resume" && i + 1 < argc)
        {
            cfg.resume_path = argv[++i];
            cfg.load_existing = true;
        }
        else if (arg == "--save" && i + 1 < argc) { cfg.save_path = argv[++i]; }
        else if (arg == "--dataset" && i + 1 < argc) { cfg.dataset_path = argv[++i]; }
        else if (arg == "--layer-dims" && i + 1 < argc)
        {
            std::string dims_str = argv[++i];
            std::stringstream ss(dims_str);
            std::string token;
            while (std::getline(ss, token, ','))
            {
                auto v = nn::parse_number<std::size_t>(token);
                if (!v)
                {
                    std::cerr << "无效层维度: " << v.error().message << "\n";
                    std::exit(1);
                }
                if (*v == 0)
                {
                    std::cerr << "层维度不能为 0\n";
                    std::exit(1);
                }
                cfg.layer_dims.push_back(*v);
            }
            if (cfg.layer_dims.size() < 2)
            {
                std::cerr << "--layer-dims 至少需要 2 个维度\n";
                std::exit(1);
            }
        }
        else if (arg == "--norm" && i + 1 < argc)
        {
            std::string v = argv[++i];
            if (v == "auto") cfg.norm_type = std::nullopt;          // 回到按架构默认
            else if (v == "layernorm") cfg.norm_type = nn::NormType::LayerNorm;
            else if (v == "rmsnorm") cfg.norm_type = nn::NormType::RMSNorm;
            else if (v == "batchnorm") cfg.norm_type = nn::NormType::BatchNorm;
            else
            {
                std::cerr << "无效 --norm: " << v
                          << "，可选: auto, layernorm, rmsnorm, batchnorm\n";
                std::exit(1);
            }
        }
        else if (arg == "--norm-place" && i + 1 < argc)
        {
            std::string v = argv[++i];
            if (v == "auto") cfg.norm_place = std::nullopt;   // 回到按架构默认
            else if (v == "none") cfg.norm_place = nn::NormPlace::None;
            else if (v == "conv") cfg.norm_place = nn::NormPlace::Conv;
            else if (v == "head") cfg.norm_place = nn::NormPlace::Head;
            else if (v == "both") cfg.norm_place = nn::NormPlace::Both;
            else if (v == "final") cfg.norm_place = nn::NormPlace::Final;
            else
            {
                std::cerr << "无效 --norm-place: " << v
                          << "，可选: auto, none, conv, head, both, final\n";
                std::exit(1);
            }
        }
        else if (arg == "--d-model" && i + 1 < argc)
        {
            auto v = nn::parse_number<std::size_t>(argv[++i]);
            if (!v)
            {
                std::cerr << "无效 --d-model: " << v.error().message << "\n";
                std::exit(1);
            }
            cfg.d_model = *v;
        }
        else if (arg == "--num-heads" && i + 1 < argc)
        {
            auto v = nn::parse_number<std::size_t>(argv[++i]);
            if (!v)
            {
                std::cerr << "无效 --num-heads: " << v.error().message << "\n";
                std::exit(1);
            }
            cfg.num_heads = *v;
        }
        else if (arg == "--num-layers" && i + 1 < argc)
        {
            auto v = nn::parse_number<std::size_t>(argv[++i]);
            if (!v)
            {
                std::cerr << "无效 --num-layers: " << v.error().message << "\n";
                std::exit(1);
            }
            cfg.num_layers = *v;
        }
        else if (arg == "--d-ff" && i + 1 < argc)
        {
            auto v = nn::parse_number<std::size_t>(argv[++i]);
            if (!v)
            {
                std::cerr << "无效 --d-ff: " << v.error().message << "\n";
                std::exit(1);
            }
            cfg.d_ff = *v;
        }
        else if (arg == "--patch-size" && i + 1 < argc)
        {
            auto v = nn::parse_number<std::size_t>(argv[++i]);
            if (!v)
            {
                std::cerr << "无效 --patch-size: " << v.error().message << "\n";
                std::exit(1);
            }
            if (*v == 0 || nn::MNIST_IMG_SIZE % *v != 0)
            {
                std::cerr << "--patch-size 必须能整除 " << nn::MNIST_IMG_SIZE << "（当前: " << *v
                          << "）\n";
                std::exit(1);
            }
            cfg.patch_size = *v;
        }
        else if (arg == "--max-samples" && i + 1 < argc)
        {
            auto v = nn::parse_number<int>(argv[++i]);
            if (!v)
            {
                std::cerr << "无效 --max-samples: " << v.error().message << "\n";
                std::exit(1);
            }
            cfg.max_train_samples = *v;
        }
        else if (arg == "--eval-samples" && i + 1 < argc)
        {
            auto v = nn::parse_number<std::size_t>(argv[++i]);
            if (!v)
            {
                std::cerr << "无效 --eval-samples: " << v.error().message << "\n";
                std::exit(1);
            }
            cfg.eval_samples = *v;
        }
        else if (arg == "--cnn-channels" && i + 1 < argc)
        {
            std::string dims_str = argv[++i];
            std::stringstream ss(dims_str);
            std::string token;
            while (std::getline(ss, token, ','))
            {
                auto v = nn::parse_number<std::size_t>(token);
                if (!v)
                {
                    std::cerr << "无效 --cnn-channels: " << v.error().message << "\n";
                    std::exit(1);
                }
                if (*v == 0)
                {
                    std::cerr << "--cnn-channels 不能为 0\n";
                    std::exit(1);
                }
                cfg.cnn_channels.push_back(*v);
            }
            if (cfg.cnn_channels.empty())
            {
                std::cerr << "--cnn-channels 至少需要一个值\n";
                std::exit(1);
            }
        }
        else if (arg == "--cnn-kernels" && i + 1 < argc)
        {
            std::string dims_str = argv[++i];
            std::stringstream ss(dims_str);
            std::string token;
            while (std::getline(ss, token, ','))
            {
                auto v = nn::parse_number<std::size_t>(token);
                if (!v)
                {
                    std::cerr << "无效 --cnn-kernels: " << v.error().message << "\n";
                    std::exit(1);
                }
                if (*v == 0)
                {
                    std::cerr << "--cnn-kernels 不能为 0\n";
                    std::exit(1);
                }
                cfg.cnn_kernels.push_back(*v);
            }
            if (cfg.cnn_kernels.empty())
            {
                std::cerr << "--cnn-kernels 至少需要一个值\n";
                std::exit(1);
            }
        }
        else if (arg == "--cnn-pool" && i + 1 < argc)
        {
            auto v = nn::parse_number<std::size_t>(argv[++i]);
            if (!v)
            {
                std::cerr << "无效 --cnn-pool: " << v.error().message << "\n";
                std::exit(1);
            }
            if (*v != 0 && *v > nn::MNIST_IMG_SIZE)
            {
                std::cerr << "--cnn-pool 不能大于输入边长 " << nn::MNIST_IMG_SIZE
                          << "（当前: " << *v << "）\n";
                std::exit(1);
            }
            cfg.cnn_pool = *v;
        }
        else if (arg == "--cnn-fc" && i + 1 < argc)
        {
            std::string dims_str = argv[++i];
            std::stringstream ss(dims_str);
            std::string token;
            while (std::getline(ss, token, ','))
            {
                auto v = nn::parse_number<std::size_t>(token);
                if (!v)
                {
                    std::cerr << "无效 --cnn-fc: " << v.error().message << "\n";
                    std::exit(1);
                }
                if (*v == 0)
                {
                    std::cerr << "--cnn-fc 不能为 0\n";
                    std::exit(1);
                }
                cfg.cnn_fc_dims.push_back(*v);
            }
            if (cfg.cnn_fc_dims.size() < 2)
            {
                std::cerr << "--cnn-fc 至少需要 2 个维度\n";
                std::exit(1);
            }
        }
        else if (arg == "--shuffle-steps" && i + 1 < argc)
        {
            std::string v = argv[++i];
            if (v == "true" || v == "1") cfg.shuffle_steps = true;
            else if (v == "false" || v == "0") cfg.shuffle_steps = false;
            else
            {
                std::cerr << "无效 --shuffle-steps: " << v << "，可选: true, false\n";
                std::exit(1);
            }
        }
        else if (arg == "--f16")
        {
            cfg.precision = nn::profile_f16();   // param+compute f16（stable/optimizer f32）
        }
        else if (arg == "--t1_58")
        {
            // 精度预设 t1_58 = 三值权重 + f16 存储（= --f16 再把 param 换成 t1_58）
            cfg.precision = nn::profile_t1_58();
        }
        else if (arg == "--precision-param" && i + 1 < argc)
        {
            cfg.precision.param = parse_precision(argv[++i], "precision-param",
                                                  /*allow_t1_58=*/true);
        }
        else if (arg == "--precision-compute" && i + 1 < argc)
        {
            cfg.precision.compute = parse_precision(argv[++i], "precision-compute");
        }
        else if (arg == "--precision-stable" && i + 1 < argc)
        {
            cfg.precision.stable = parse_precision(argv[++i], "precision-stable");
        }
        else if (arg == "--precision-optimizer" && i + 1 < argc)
        {
            cfg.precision.optimizer = parse_precision(argv[++i], "precision-optimizer");
        }
        else
        {
            std::cerr << "未知参数: " << arg << "\n使用 --help 查看用法\n";
            std::exit(1);
        }
    }

    // 从通用参数回填到程序专属配置
    cfg.epochs = common.epochs;
    cfg.lr = common.lr;
    cfg.batch_size = common.batch_size;
    cfg.optimizer_name = common.optimizer;
    cfg.weight_decay = common.weight_decay;
    cfg.gpu_enabled = common.use_gpu;
    cfg.gpu_device = common.gpu_device;
    cfg.lr_schedule = common.lr_schedule;
    cfg.warmup_epochs = common.warmup_epochs;
    cfg.min_lr = common.min_lr;
    cfg.lr_per_epoch = std::move(common.lr_per_epoch);

    return cfg;
}

// ==================== 构建模型规格 ====================
// 从 CLI 配置构建 CNN 配置（未指定的项用 LeNet-5 默认补齐）
nn::CnnConfig build_cnn_config(const TrainConfig& cfg)
{
    nn::CnnConfig c;
    c.in_channels = cfg.cnn_in_channels;
    c.in_size = cfg.cnn_in_size;
    c.pool = cfg.cnn_pool;

    std::vector<std::size_t> channels = cfg.cnn_channels;
    std::vector<std::size_t> kernels = cfg.cnn_kernels;
    if (channels.empty() && kernels.empty())
    {
        channels = {6, 16};
        kernels = {5, 5};
    }
    else if (channels.empty()) { channels.assign(kernels.size(), 6); }
    else if (kernels.empty()) { kernels.assign(channels.size(), 5); }
    else if (channels.size() != kernels.size())
    {
        std::cerr << "--cnn-channels 与 --cnn-kernels 长度必须一致\n";
        std::exit(1);
    }
    for (std::size_t i = 0; i < channels.size(); ++i)
        c.convs.push_back({channels[i], kernels[i]});

    c.fc_dims = cfg.cnn_fc_dims.empty() ? std::vector<std::size_t>{120, 10} : cfg.cnn_fc_dims;
    return c;
}

nn::ModelSpec build_spec(const TrainConfig& cfg)
{
    if (cfg.arch == ArchType::Transformer)
    {
        // auto（未指定）→ ViT 规范形态：LayerNorm@final（块 pre-norm + 末端 ln_f）
        const nn::NormPlace place = cfg.norm_place.value_or(nn::NormPlace::Final);
        if (place != nn::NormPlace::None && place != nn::NormPlace::Final)
        {
            std::cerr << "--norm-place 的 conv/head/both 仅适用于 --arch cnn；"
                      << "Transformer 只接受 none/final\n";
            std::exit(1);
        }
        return nn::make_mnist_transformer_spec(
            cfg.patch_size, cfg.d_model, cfg.num_heads, cfg.d_ff, cfg.num_layers,
            cfg.norm_type.value_or(nn::NormType::LayerNorm), place);
    }
    if (cfg.arch == ArchType::CNN)
    {
        // auto（未指定）→ CNN 规范形态：BatchNorm@conv（4 epoch A/B 实测最优）
        const nn::NormPlace place = cfg.norm_place.value_or(nn::NormPlace::Conv);
        if (place == nn::NormPlace::Final)
        {
            std::cerr << "--norm-place final 仅适用于 --arch transformer；"
                      << "CNN 接受 none/conv/head/both\n";
            std::exit(1);
        }
        nn::CnnConfig c = build_cnn_config(cfg);
        c.norm_type = cfg.norm_type.value_or(nn::NormType::BatchNorm);
        c.norm_place = place;
        std::vector<nn::CnnConvSpec> convs = c.convs;
        return nn::make_cnn_spec(c.in_channels, c.in_size, c.pool, convs, c.fc_dims, c.norm_type,
                                 c.norm_place);
    }
    if (cfg.norm_place && *cfg.norm_place != nn::NormPlace::None)
    {
        std::cerr << "MLP 的归一化挂载位置由结构固定（Linear→Norm→激活），"
                  << "请去掉 --norm-place（或改为 none/auto）\n";
        std::exit(1);
    }
    // MLP（结构内置 Linear→Norm→激活；auto = layernorm）
    nn::ModelSpec spec;
    auto& m = spec.emplace<nn::MlpSpec>();
    m.layer_dims = cfg.layer_dims.empty() ? nn::MNIST_LAYER_DIMS : cfg.layer_dims;
    m.norm_type = cfg.norm_type.value_or(nn::NormType::LayerNorm);
    // 三值权重：param=t1_58 → 线性层用 BitLinear（规格是加载时的权威来源，
    // 缺键 = None 保证旧文件零破坏）。见 docs 21 §4.7。
    m.weight_quant = (cfg.precision.param == nn::Precision::T1_58) ? nn::WeightQuant::T1_58
                                                                   : nn::WeightQuant::None;
    return spec;
}

// ==================== 主函数 ====================
int main(int argc, char* argv[])
{
    TrainConfig cfg = parse_args(argc, argv);

    // ── 危险精度组合启动期告警（仅警告，不拒绝；docs/internal/24 §2.3 F1）────
    // optimizer=f16（含四字段全 f16）只打印一次到 stderr：不改变退出码、不阻断
    // 训练、不静默降级；`--f16` 与合法组合返回空串（静默）。
    if (const std::string warn = nn::cli::dangerous_precision_warning(cfg.precision); !warn.empty())
        std::cerr << warn;

    // ── 构建规格 ─────────────────────────────────────────────
    nn::ModelSpec spec = build_spec(cfg);

    // ── 如果 --resume，从文件读取规格覆盖 CLI 参数 ──────────
    if (cfg.load_existing)
    {
        // 角色校验（v7，docs/internal/23 §2.1）：推理模型文件不含训练参数 →
        // 明确拒绝；v5/v6 老 .bin 无 role 字段 → 按训练文件处理（零破坏）。
        {
            uint32_t resume_version = 0;
            auto role_r = nn::peek_model_role(cfg.resume_path, &resume_version);
            if (role_r && resume_version >= 7 && *role_r != nn::ModelRole::Checkpoint)
            {
                std::cerr << "错误: --resume 需要训练断点文件（.nnckpt，Checkpoint 角色），但 "
                          << cfg.resume_path << " 是 " << nn::model_role_name(*role_r)
                          << "；它不含训练参数。\n";
                return 1;
            }
        }
        auto spec_result = nn::peek_model_spec(cfg.resume_path);
        if (spec_result)
        {
            if (spec_result->is_mlp())
            {
                std::cout << "从模型文件读取 MLP 规格\n";
                spec = std::move(*spec_result);
                cfg.arch = ArchType::MLP;
                cfg.norm_type = spec.as<nn::MlpSpec>()->norm_type;
            }
            else if (spec_result->is_transformer())
            {
                std::cout << "从模型文件读取 Transformer 规格\n";
                spec = std::move(*spec_result);
                cfg.arch = ArchType::Transformer;
                const auto* t = spec.as<nn::TransformerSpec>();
                cfg.norm_type = t->norm_type;
                cfg.norm_place = t->norm_place;
                cfg.patch_size = t->patch_size != 0 ? t->patch_size : nn::MNIST_PATCH_SIZE;
                cfg.d_model = t->d_model;
                cfg.num_heads = t->num_heads;
                cfg.d_ff = t->d_ff;
                cfg.num_layers = t->num_layers;
            }
            else if (spec_result->is_cnn())
            {
                std::cout << "从模型文件读取 CNN 规格\n";
                spec = std::move(*spec_result);
                cfg.arch = ArchType::CNN;
                const auto* c = spec.as<nn::CnnSpec>();
                cfg.norm_type = c->norm_type;
                cfg.norm_place = c->norm_place;
                cfg.cnn_in_channels = c->cnn_in_channels;
                cfg.cnn_in_size = c->cnn_in_size;
                cfg.cnn_pool = c->cnn_pool;
                cfg.cnn_channels = c->cnn_channels;
                cfg.cnn_kernels = c->cnn_kernels;
                cfg.cnn_fc_dims = c->layer_dims;
            }
            else
            {
                std::cerr << "模型文件类型不支持 (type=" << spec_result->type_name() << ")\n";
                return 1;
            }
        }
        else
        {
            std::cerr << "读取模型规格失败: " << spec_result.error().message
                      << "，使用命令行参数。\n";
        }
    }

    // ── 打印配置 ─────────────────────────────────────────────
    std::cout << "========================================\n";
    std::cout << "  MNIST 手写数字训练\n";
    std::cout << "========================================\n";
    std::cout << "  架构: "
              << (cfg.arch == ArchType::Transformer ? "Transformer (ViT)"
                  : cfg.arch == ArchType::CNN       ? "CNN (LeNet)"
                                                    : "MLP")
              << "\n";

    if (cfg.arch == ArchType::CNN)
    {
        nn::CnnConfig c = build_cnn_config(cfg);
        std::cout << "  卷积: ";
        for (std::size_t i = 0; i < c.convs.size(); ++i)
        {
            std::cout << "Conv(" << c.convs[i].out_channels << ",k" << c.convs[i].kernel << ")";
            if (c.pool > 0) std::cout << "+Pool" << c.pool;
            if (i < c.convs.size() - 1) std::cout << " -> ";
        }
        std::cout << " -> Flatten\n  全连接: ";
        for (std::size_t i = 0; i < c.fc_dims.size(); ++i)
        {
            std::cout << c.fc_dims[i];
            if (i < c.fc_dims.size() - 1) std::cout << " -> ";
        }
        std::cout << "\n";
    }
    else if (cfg.arch == ArchType::Transformer)
    {
        const std::size_t grid = nn::MNIST_IMG_SIZE / cfg.patch_size;
        const std::size_t num_patches = grid * grid;
        std::cout << "  Patch: " << nn::MNIST_IMG_SIZE << "/" << cfg.patch_size << " → " << grid
                  << "×" << grid << "=" << num_patches << " patches\n";
        std::cout << "  d_model: " << cfg.d_model << "  heads: " << cfg.num_heads
                  << "  layers: " << cfg.num_layers << "  d_ff: " << cfg.d_ff << "\n";
    }
    else
    {
        const auto& dims =
            spec.is_mlp() ? spec.as<nn::MlpSpec>()->layer_dims : nn::MNIST_LAYER_DIMS;
        const auto p_norm = spec.is_mlp()           ? spec.as<nn::MlpSpec>()->norm_type
                            : spec.is_transformer() ? spec.as<nn::TransformerSpec>()->norm_type
                                                    : spec.as<nn::CnnSpec>()->norm_type;
        const std::string_view norm_name = (p_norm == nn::NormType::RMSNorm)     ? "RMSNorm"
                                           : (p_norm == nn::NormType::BatchNorm) ? "BatchNorm"
                                                                                 : "LayerNorm";
        std::cout << "  网络: ";
        for (std::size_t i = 0; i < dims.size(); ++i)
        {
            std::cout << dims[i];
            // norm+GeLU 挂在隐藏层 Linear 的输出维度上：dims[1]..dims[size-2]。
            // 首元素 dims[0] 是输入、末元素 dims[size-1] 是 logits 输出，
            // 两者都不挂 norm/激活（CE 损失需要原始 logits）。
            if (i > 0 && i < dims.size() - 1) std::cout << "(" << norm_name << "+GeLU)";
            if (i < dims.size() - 1) std::cout << " -> ";
        }
        std::cout << "\n";
    }

    const auto q_norm = spec.is_transformer() ? spec.as<nn::TransformerSpec>()->norm_type
                        : spec.is_cnn()       ? spec.as<nn::CnnSpec>()->norm_type
                                              : spec.as<nn::MlpSpec>()->norm_type;
    const auto q_place = spec.is_transformer() ? spec.as<nn::TransformerSpec>()->norm_place
                         : spec.is_cnn()       ? spec.as<nn::CnnSpec>()->norm_place
                                               : nn::NormPlace::None;
    std::cout << "  归一化: "
              << ((q_norm == nn::NormType::RMSNorm)     ? "RMSNorm"
                  : (q_norm == nn::NormType::BatchNorm) ? "BatchNorm"
                                                        : "LayerNorm");
    if (q_place != nn::NormPlace::None) std::cout << " @ " << nn::norm_place_name(q_place);
    std::cout << "\n";
    std::cout << "  优化器: " << cfg.optimizer_name << "  学习率: " << cfg.lr << "\n";
    std::cout << "  轮数: " << cfg.epochs << "  批大小: " << cfg.batch_size << "\n";
    std::cout << "  GPU: " << (cfg.gpu_enabled ? "启用" : "禁用")
              << "  打乱: " << (cfg.shuffle_steps ? "启用" : "禁用") << "\n";
    std::cout << "  模型: " << (cfg.load_existing ? cfg.resume_path : "(从头训练)") << " -> "
              << cfg.save_path << "\n";
    std::cout << "========================================\n\n";

    // ── 创建计算引擎 ─────────────────────────────────────────
    // 引擎必须先于 model 构造并晚于 model 析构（model 持有 engine 的非拥有指针）
    nn::cli::EngineConfig eng_cfg;
    eng_cfg.use_gpu = cfg.gpu_enabled;
    eng_cfg.gpu_device = cfg.gpu_device;
    auto engine_res = nn::cli::create_engine(eng_cfg, std::cout);
    NN_EXIT(engine_res, 1, "引擎创建失败: ");
    auto raw_engine = std::move(*engine_res);

    // ── 多精度：边界 cast 已下沉基类（NVI，原 PrecisionEngine；同 text_train）──
    // 三值（param=t1_58）与"f16 存储"是两件事：前者 latent 恒 f32、只有量化缓冲
    // 是 f16，后者才是"所有算子输出按 P 舍入"的边界 cast 路径 → 提示分开打。
    if (cfg.precision.param == nn::Precision::T1_58 && !spec.is_cnn())
    {
        std::cout << "[精度] 三值权重已启用（T1_58 / BitLinear：量化 forward + STE backward，"
                     "latent 恒 f32）\n"
                     "  [范围] P1 支持 MLP 路径；docs/internal/21-quantized-weights.md\n";
    }
    if (cfg.precision.param == nn::Precision::F16 || cfg.precision.compute == nn::Precision::F16 ||
        cfg.precision.stable == nn::Precision::F16 || cfg.precision.optimizer == nn::Precision::F16)
    {
        std::cout << "[精度] f16 存储已启用（基类边界 cast）\n"
                     "  [注意] 边界 cast 的 transient 放大：峰值可能高于 f32，"
                     "见 docs/development/05-mixed-precision.md §12.5\n";
    }
    nn::ComputeEngine* engine = raw_engine.get();

    // ── 加载数据 ─────────────────────────────────────────────
    std::cout << "加载数据: " << cfg.dataset_path << " ..." << std::endl;
    const std::size_t train_max =
        (cfg.max_train_samples > 0) ? static_cast<std::size_t>(cfg.max_train_samples) : 0;
    auto csv_train_result = nn::cli::load_mnist_csv(cfg.dataset_path + "/train.csv", train_max);
    NN_EXIT(csv_train_result, 1, "Error: ");
    auto [train_x, train_y] = std::move(*csv_train_result);

    auto csv_test_result = nn::cli::load_mnist_csv(cfg.dataset_path + "/test.csv");
    NN_EXIT(csv_test_result, 1, "Error: ");
    auto [test_x, test_y] = std::move(*csv_test_result);
    std::cout << "训练集: " << train_x.cols() << " 样本, 测试集: " << test_x.cols() << " 样本\n"
              << std::endl;

    // ── 构建模型（绑定引擎） ─────────────────────────────────
    // 显式告知而不是静默失效：CNN 构建器目前**不接收**精度 profile
    //（roadmap P2「RAPT/CNN f16」），所以 CNN + 非 f32 选项实际不生效。
    if (spec.is_cnn() && !nn::is_profile_f32(cfg.precision))
    {
        std::cout << "[精度] 注意：CNN 架构当前不支持精度配置（含三值 T1_58），"
                     "本选项**未生效**（run at f32）\n";
    }
    auto model_result = nn::build_mnist_model_from_spec(*engine, spec, cfg.precision);
    NN_EXIT(model_result, 1, "构建模型失败: ");
    auto model = std::move(*model_result);
    model.set_training(true);  // 训练模式：BatchNorm 使用 batch 统计量并更新 running 统计

    // ── 精度配置 ──
    // 不在这里再注入：`build_mnist_model_from_spec` 已在 add 之前用
    // `Model::set_default_precision_profile` 注入（权重按精度创建），这里的
    // 二次调用对 MLP 是冗余的；而按 D3(b)，profile 在 init 后**不可变**
    //（再注入即 fail-fast）。见 docs/internal/21-quantized-weights.md §4.3.2。
    {
        const auto& pp = cfg.precision;
        if (pp.param != nn::Precision::F32 || pp.compute != nn::Precision::F32 ||
            pp.stable != nn::Precision::F32 || pp.optimizer != nn::Precision::F32)
        {
            std::cout << "精度配置: param=" << nn::precision_name(pp.param)
                      << " compute=" << nn::precision_name(pp.compute)
                      << " stable=" << nn::precision_name(pp.stable)
                      << " optimizer=" << nn::precision_name(pp.optimizer) << "\n";
        }
    }

    if (cfg.load_existing)
    {
        // 训练侧载入 = 可训练意图（P1-7）：三值 Model 角色的打包载荷按文件 τ
        // 反量化成 f32 latent，否则 `backward()` 会落在只读部署态上报错。
        // ⚠ 本路径的 role 门禁（下面）仍只收 Checkpoint 角色 —— `.nnckpt` 的三值层
        // 写 TernaryLatent，两种意图同结果，故这里传 Trainable 是**与语义一致的前置**
        // （mnist 侧的 role 语义接线是 P1-2 的遗留项，见 docs/history/history.md）。
        auto load_result = nn::load_model(cfg.resume_path, model, nullptr, nullptr,
                                          nn::WeightLoadIntent::Trainable);
        if (load_result) { std::cout << "已加载模型: " << cfg.resume_path << "\n" << std::endl; }
        else
        {
            std::cerr << "加载模型失败: " << load_result.error().message << "，将从头训练。\n"
                      << std::endl;
        }
    }

    // ── 训练生命周期容器（P2b，docs/internal/29）─────────────────
    // Session 同时拥有 Model + Optimizer（成员声明顺序保证 optimizer 先析构），
    // 结构性消除"优化器必须早于参数所有者销毁"的调用约定。model 在此前已完成
    // resume 载入（--resume 需要 model 存在），故顺序 = build → resume → create。
    // activation_offload / checkpoint_every 保持默认（迁移前本入口从未对 model
    // 调用 set_activation_offload / set_checkpoint_every）。
    nn::TrainingConfig train_cfg;
    train_cfg.optimizer = cfg.optimizer_name;   // 等价于迁移前的 create_optimizer(name,…)
    train_cfg.lr = cfg.lr;
    train_cfg.weight_decay = cfg.weight_decay;
    train_cfg.precision = cfg.precision;        // 只作用于优化器状态（同 create_optimizer 透传）
    // beta1/beta2 保留 TrainingConfig 默认 0.9/0.999（= 迁移前 create_optimizer 默认值，
    // 本 CLI 无对应参数）；clip_grad_norm 保留 0（迁移前不做梯度裁剪）。
    auto session_result = nn::TrainingSession::create(std::move(model), std::move(train_cfg));
    NN_EXIT(session_result, 1, "错误：未知优化器名称");
    nn::TrainingSession session = std::move(*session_result);

    Scalar optimizer_current_lr = cfg.lr;

    // ── 学习率调度配置（委托给 nn::cli::compute_epoch_lr） ──
    nn::cli::LrScheduleConfig lr_sched_cfg;
    lr_sched_cfg.base_lr = cfg.lr;
    lr_sched_cfg.min_lr = cfg.min_lr;
    lr_sched_cfg.warmup_epochs = cfg.warmup_epochs;
    lr_sched_cfg.total_epochs = cfg.epochs;
    lr_sched_cfg.schedule = cfg.lr_schedule;
    lr_sched_cfg.lr_per_epoch = cfg.lr_per_epoch;

    nn::CrossEntropyLoss ce_loss;
    ce_loss.set_precision_profile(cfg.precision);   // loss 链 = profile.stable（§9.1）
    const std::size_t num_batches = train_x.cols() / cfg.batch_size;
    if (num_batches == 0)
    {
        std::cerr << "训练样本数 (" << train_x.cols() << ") 小于 batch_size (" << cfg.batch_size
                  << ")，请减小 --batch-size 或增大 --max-samples\n";
        return 1;
    }

    // ── 预分配 batch 缓冲区 ──────────────────────────────────
    nn::Matrix x_batch(train_x.rows(), cfg.batch_size);
    nn::Matrix y_batch(train_y.rows(), cfg.batch_size);

    std::vector<std::size_t> sample_indices(train_x.cols());
    for (std::size_t i = 0; i < sample_indices.size(); ++i)
        sample_indices[i] = i;
    std::mt19937_64 shuffle_rng{std::random_device{}()};

    auto t_start = std::chrono::steady_clock::now();

    for (int epoch = 0; epoch < cfg.epochs; ++epoch)
    {
        // ── 学习率调度：每 epoch 开始时调整 ──
        Scalar epoch_lr = nn::cli::compute_epoch_lr(lr_sched_cfg, epoch);
        if (epoch_lr != optimizer_current_lr)
        {
            session.set_lr(epoch_lr);
            optimizer_current_lr = epoch_lr;
        }

        auto ep_start = std::chrono::steady_clock::now();
        Scalar total_loss = 0.0;

        if (cfg.shuffle_steps)
            std::shuffle(sample_indices.begin(), sample_indices.end(), shuffle_rng);

        for (std::size_t batch = 0; batch < num_batches; ++batch)
        {
            const std::size_t start = batch * cfg.batch_size;

            // ── 提取 batch（按 shuffle 顺序逐列拷贝） ──
            const std::size_t R_x = train_x.rows();
            const std::size_t R_y = train_y.rows();
            const std::size_t C_train = train_x.cols();
            const auto x_src = train_x.span().data();
            const auto y_src = train_y.span().data();
            auto x_dst = x_batch.span().data();
            auto y_dst = y_batch.span().data();
            for (std::size_t b = 0; b < cfg.batch_size; ++b)
            {
                const std::size_t src_col = sample_indices[start + b];
                for (std::size_t r = 0; r < R_x; ++r)
                    x_dst[r * cfg.batch_size + b] = x_src[r * C_train + src_col];
                for (std::size_t r = 0; r < R_y; ++r)
                    y_dst[r * cfg.batch_size + b] = y_src[r * C_train + src_col];
            }

            // ── Matrix → Tensor（上传到引擎设备） ──
            auto x_tensor_r = engine->from_matrix(x_batch);
            NN_EXIT(x_tensor_r, 1, "\nfrom_matrix(x_batch) failed: ");
            auto y_tensor_r = engine->from_matrix(y_batch);
            NN_EXIT(y_tensor_r, 1, "\nfrom_matrix(y_batch) failed: ");

            // ── 批量录制：forward + loss + backward 录制到单一 command buffer ──
            auto bb = engine->begin_batch();
            NN_EXIT(bb, 1, "\nbegin_batch failed: ");

            // ── 前向 ──
            auto out_r = session.model().forward(*x_tensor_r);
            NN_EXIT(out_r, 1, "\nForward pass failed: ");

            // ── 计算损失 ──
            auto loss_result = ce_loss.forward(*engine, *out_r, *y_tensor_r);
            NN_EXIT(loss_result, 1, "\nLoss computation failed: ");
            Scalar loss = *loss_result;
            total_loss += loss;

            // ── 反向 ──
            auto grad_r = ce_loss.backward();
            NN_EXIT(grad_r, 1, "\nLoss backward failed: ");

            auto bwd_r = session.model().backward(*grad_r);
            NN_EXIT(bwd_r, 1, "\nModel backward failed: ");

            // ── 提交并等待所有录制的命令 ──
            auto eb = engine->end_batch();
            NN_EXIT(eb, 1, "\nend_batch failed: ");

            // ── 优化器 step + 梯度清零（整段包进单次 begin/end_batch，
            //    与 text_train 一致；否则 GPU 下逐原语同步提交，铁律 6）──
            auto obb = engine->begin_batch();
            NN_EXIT(obb, 1, "\nbegin_batch (optimizer) failed: ");

            auto step_result = session.step();
            if (!step_result)
            {
                std::cerr << "\n优化器 step 失败: " << step_result.error().message << '\n';
                (void)engine->end_batch();
                return 1;
            }

            auto zero_result = session.zero_grad();
            if (!zero_result)
            {
                std::cerr << "\n优化器 zero_grad 失败: " << zero_result.error().message << '\n';
                (void)engine->end_batch();
                return 1;
            }

            auto oeb = engine->end_batch();
            NN_EXIT(oeb, 1, "\nend_batch (optimizer) failed: ");

            // ── 进度显示 ──
            if ((batch + 1) % 10 == 0 || batch + 1 == num_batches)
            {
                auto batch_now = std::chrono::steady_clock::now();
                Scalar batch_ms =
                    std::chrono::duration<Scalar, std::milli>(batch_now - ep_start).count();
                std::cout << "\r  Epoch " << epoch + 1 << "/" << cfg.epochs << "  batch "
                          << batch + 1 << "/" << num_batches << "  loss: " << std::fixed
                          << std::setprecision(4) << loss << "  time: " << std::setprecision(0)
                          << batch_ms << "ms"
                          << "   " << std::flush;
            }
        }

        auto ep_end = std::chrono::steady_clock::now();
        Scalar ep_sec = std::chrono::duration<Scalar>(ep_end - ep_start).count();

        Scalar avg_loss = total_loss / num_batches;
        // MLP 全量评估，Transformer 截取前 eval_samples 个样本评估
        // 评估分块大小取训练 batch：CNN 的 im2col 展开是 k²·C_in 倍，
        // 不分块时全量 60000 样本单次 forward 需 ~6.4 GB 显存 → OOM。
        const std::size_t eval_n = (cfg.arch == ArchType::Transformer) ? cfg.eval_samples : 0;
        auto train_acc_r = nn::cli::evaluate_mnist(session.model(), *engine, train_x, train_y,
                                                   eval_n, cfg.batch_size);
        auto test_acc_r = nn::cli::evaluate_mnist(session.model(), *engine, test_x, test_y, eval_n,
                                                  cfg.batch_size);
        if (!train_acc_r || !test_acc_r)
        {
            const auto& err = !train_acc_r ? train_acc_r.error() : test_acc_r.error();
            std::cerr << "\n  评估失败: " << err.message << std::endl;
            return 1;
        }
        Scalar train_acc = *train_acc_r;
        Scalar test_acc = *test_acc_r;

        std::cout << "\r  Epoch " << epoch + 1 << "/" << cfg.epochs << "  lr=" << std::scientific
                  << std::setprecision(4) << optimizer_current_lr << "  loss=" << std::fixed
                  << std::setprecision(4) << avg_loss << "  train_acc=" << std::setprecision(2)
                  << train_acc * 100.0 << "%"
                  << "  test_acc=" << test_acc * 100.0 << "%"
                  << "  time=" << std::setprecision(1) << ep_sec << "s" << std::endl;
    }

    auto t_end = std::chrono::steady_clock::now();
    Scalar total_sec = std::chrono::duration<Scalar>(t_end - t_start).count();

    // ── 保存模型 ─────────────────────────────────────────────
    // 推理模型（Model 角色）：三值层写打包形态 + τ（不含训练参数）
    auto save_result =
        nn::save_model(cfg.save_path, session.model(), spec, {}, nn::ModelRole::Model);
    NN_EXIT(save_result, 1, "保存模型失败: ");
    std::cout << "\n训练完成! 总耗时: " << std::fixed << std::setprecision(1) << total_sec << "s"
              << std::endl;

    return 0;
}
