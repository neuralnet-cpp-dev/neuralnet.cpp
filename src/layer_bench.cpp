// ───────────────────────────────────────────────────────────────────────────
//  layer_bench.cpp — 各 Layer 前向/反向吞吐量基准（CPU / Vulkan GPU）
//
//  用法：
//    layer_bench [--gpu] [--all | --layer <name>[,...]]
//                [--forward-only] [--iter <n>] [--warmup <n>]
//                [尺寸参数]
//
//  尺寸参数（默认值见 BenchConfig）：
//    --in/--out/--batch/--seq/--dmodel/--heads/--dff/--cin/--cout/--kernel/--hw/--rows/--cols
//
//  层名：linear swiglu layernorm rmsnorm softmax mha causal_attn
//        feedforward transformer gpt_block conv2d maxpool
//
//  编译/注册：CMake target layer_bench（Debug/Release 均可）。
// ───────────────────────────────────────────────────────────────────────────

#include <chrono>
#include <cstdint>
#include <cstdio>
#include <cstdlib>
#include <cstring>
#include <functional>
#include <iostream>
#include <random>
#include <string>
#include <string_view>
#include <utility>
#include <vector>

#include <nn_error_macros.hpp>
import nn.cli;
import nn.core;
import nn.dataset;
import nn.domain;
import nn.engine;
import nn.expr;
import nn.kvrecord;
import nn.layer;
import nn.loss;
import nn.model;
import nn.opt;
import nn.tokenizer;
import nn.train;
using nn::cli::Help;
using nn::ComputeEngine;
using nn::Matrix;
using nn::Model;
using nn::Scalar;
using nn::Tensor;


namespace
{

// ═══════════════════════════════════════════════════════════════════════════
//  BenchConfig — CLI 参数与默认尺寸
// ═══════════════════════════════════════════════════════════════════════════
struct BenchConfig
{
    bool gpu = false;
    bool all = false;
    bool forward_only = false;
    bool f16 = false;   // 打包算子（matmul_q*）跑 f16 存储变体
    std::vector<std::string> layers;
    int iter = 10;
    int warmup = 2;
    int inner = 1;   // 每次计时内重复执行次数（摊薄 submit/wait 的固定开销）

    // 默认尺寸（GPT 小规模，CPU 秒级可测）
    std::size_t in = 1024, out = 1024;
    std::size_t dmodel = 768, heads = 12, dff = 3072;
    std::size_t batch = 1, seq = 512;
    std::size_t cin = 3, cout = 64, kernel = 3, hw = 32;
    std::size_t rows = 768, cols = 512;

    // 算子级尺寸（matmul: (m,k)·(k,n)；逐元素/归约: (m,n)）
    std::size_t m = 1024, n = 1024, k = 1024;

    // 扫描原语尺寸（scan_prefix / scan_suffix）：行块 = batch*heads*dk、列 = seq
    std::size_t dk = 32;

    // --hash：算子模式额外打印输出张量的**位级哈希**（kernel 改写前后的一比一
    //   oracle：逐位不变的优化必须哈希相同；哈希覆盖 f32 原始位型，不做容差比较）
    bool hash = false;

    // 算子级模式：非空时跑算子（--op <name|all>）
    std::vector<std::string> ops;
};

// ═══════════════════════════════════════════════════════════════════════════
//  工具
// ═══════════════════════════════════════════════════════════════════════════
double ms_since(std::chrono::steady_clock::time_point t0)
{ return std::chrono::duration<double, std::milli>(std::chrono::steady_clock::now() - t0).count(); }

// 随机填充 Matrix 并上传到引擎设备
Tensor make_input(ComputeEngine& e, std::size_t rows, std::size_t cols)
{
    Matrix m(rows, cols);
    std::mt19937 g(1234u);
    std::uniform_real_distribution<Scalar> d(-1.0f, 1.0f);
    auto s = m.span();
    for (std::size_t i = 0; i < s.size(); ++i)
        s[i] = d(g);
    auto t = e.from_matrix(std::move(m));
    if (!t) std::abort();
    return std::move(*t);
}

// f16 版输入（定义在后；打包算子与 --f16 的稠密侧共用）
Tensor make_input_f16(ComputeEngine& e, std::size_t rows, std::size_t cols);

// ═══════════════════════════════════════════════════════════════════════════
//  LayerSpec — 单个层的构建/输入形状/FLOP 估算
// ═══════════════════════════════════════════════════════════════════════════
struct LayerSpec
{
    const char* name;
    // 构建单层模型；返回 false 表示构建失败
    std::function<bool(Model&, const BenchConfig&)> build;
    // 输入张量形状 (rows, cols)
    std::function<std::pair<std::size_t, std::size_t>(const BenchConfig&)> shape;
    // 前向 FLOP 估算（用于 GFLOPS）
    std::function<double(const BenchConfig&)> flops;
    // 每次迭代的 token 数（sequence 层 = batch*seq；MLP 类 = batch）
    std::function<std::size_t(const BenchConfig&)> tokens;
};

bool build_linear(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::Linear>(c.in, c.out);
    return r.has_value();
}
std::pair<std::size_t, std::size_t> shape_linear(const BenchConfig& c)
{ return {c.in, c.batch}; }
double flops_linear(const BenchConfig& c)
{ return 2.0 * c.in * c.out * c.batch; }
std::size_t tok_linear(const BenchConfig& c)
{ return c.batch; }

bool build_swiglu(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::SwiGLU>(c.dff);
    return r.has_value();
}
std::pair<std::size_t, std::size_t> shape_swiglu(const BenchConfig& c)
{ return {2 * c.dff, c.batch}; }
double flops_swiglu(const BenchConfig& c)
{ return 8.0 * 2 * c.dff * c.batch; }
std::size_t tok_swiglu(const BenchConfig& c)
{ return c.batch; }

bool build_layernorm(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::LayerNorm>(c.dmodel);
    return r.has_value();
}
bool build_rmsnorm(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::RMSNorm>(c.dmodel);
    return r.has_value();
}
std::pair<std::size_t, std::size_t> shape_norm(const BenchConfig& c)
{ return {c.dmodel, c.batch * c.seq}; }
double flops_norm(const BenchConfig& c)
{ return 6.0 * c.dmodel * c.batch * c.seq; }
std::size_t tok_norm(const BenchConfig& c)
{ return c.batch * c.seq; }

bool build_softmax(Model& m, [[maybe_unused]] const BenchConfig& c)
{
    auto r = m.template add<nn::Softmax>();
    return r.has_value();
}
std::pair<std::size_t, std::size_t> shape_softmax(const BenchConfig& c)
{ return {c.rows, c.cols}; }
double flops_softmax(const BenchConfig& c)
{ return 6.0 * c.rows * c.cols; }
std::size_t tok_softmax(const BenchConfig& c)
{ return c.rows > 0 ? 1u : 0u; }

bool build_mha(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::MultiHeadAttention>(c.dmodel, c.heads, c.seq);
    return r.has_value();
}
bool build_causal(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::CausalSelfAttention>(c.dmodel, c.heads, c.seq, c.seq);
    return r.has_value();
}
std::pair<std::size_t, std::size_t> shape_attn(const BenchConfig& c)
{ return {c.dmodel, c.batch * c.seq}; }
double flops_attn(const BenchConfig& c)
{
    const double T = static_cast<double>(c.batch) * c.seq;
    return 6.0 * c.dmodel * c.dmodel * T + 4.0 * T * T * c.dmodel;
}
std::size_t tok_attn(const BenchConfig& c)
{ return c.batch * c.seq; }

bool build_feedforward(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::FeedForward>(c.dmodel, c.dff);
    return r.has_value();
}
double flops_feedforward(const BenchConfig& c)
{ return 4.0 * c.dmodel * c.dff * c.batch * c.seq; }

bool build_transformer(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::TransformerEncoderLayer>(c.dmodel, c.heads, c.dff, c.seq);
    return r.has_value();
}
double flops_transformer(const BenchConfig& c)
{ return flops_attn(c) + flops_feedforward(c) + flops_norm(c) * 2.0; }

bool build_gpt_block(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::GPTBlock>(c.dmodel, c.heads, c.dff, c.seq, c.seq);
    return r.has_value();
}

bool build_conv(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::Conv2D>(c.cin, c.cout, c.kernel, /*stride=*/1, /*pad=*/c.kernel / 2,
                                        c.hw, c.hw);
    return r.has_value();
}
std::pair<std::size_t, std::size_t> shape_conv(const BenchConfig& c)
{ return {c.cin * c.hw * c.hw, c.batch}; }
double flops_conv(const BenchConfig& c)
{ return 2.0 * c.cout * c.cin * c.kernel * c.kernel * c.hw * c.hw * c.batch; }
std::size_t tok_conv(const BenchConfig& c)
{ return c.batch; }

bool build_maxpool(Model& m, const BenchConfig& c)
{
    auto r = m.template add<nn::MaxPool2D>(c.cin, c.hw, c.hw, /*pool=*/2, /*stride=*/2);
    return r.has_value();
}
std::pair<std::size_t, std::size_t> shape_maxpool(const BenchConfig& c)
{ return {c.cin * c.hw * c.hw, c.batch}; }
double flops_maxpool(const BenchConfig& c)
{
    const std::size_t oh = (c.hw - 2) / 2 + 1;
    const std::size_t ow = (c.hw - 2) / 2 + 1;
    return 1.0 * c.cin * oh * ow * c.batch;
}
std::size_t tok_maxpool(const BenchConfig& c)
{ return c.batch; }

// ── 层注册表 ──────────────────────────────────────────────────────────────
const std::vector<LayerSpec>& layer_registry()
{
    static const std::vector<LayerSpec> reg = {
        {"linear", build_linear, shape_linear, flops_linear, tok_linear},
        {"swiglu", build_swiglu, shape_swiglu, flops_swiglu, tok_swiglu},
        {"layernorm", build_layernorm, shape_norm, flops_norm, tok_norm},
        {"rmsnorm", build_rmsnorm, shape_norm, flops_norm, tok_norm},
        {"softmax", build_softmax, shape_softmax, flops_softmax, tok_softmax},
        {"mha", build_mha, shape_attn, flops_attn, tok_attn},
        {"causal_attn", build_causal, shape_attn, flops_attn, tok_attn},
        {"feedforward", build_feedforward, shape_norm, flops_feedforward, tok_norm},
        {"transformer", build_transformer, shape_norm, flops_transformer, tok_norm},
        {"gpt_block", build_gpt_block, shape_norm, flops_transformer, tok_norm},
        {"conv2d", build_conv, shape_conv, flops_conv, tok_conv},
        {"maxpool", build_maxpool, shape_maxpool, flops_maxpool, tok_maxpool},
    };
    return reg;
}

// ═══════════════════════════════════════════════════════════════════════════
//  算子级基准（基础原语：matmul 及其变体、逐元素、归约、广播、转置）
// ═══════════════════════════════════════════════════════════════════════════
struct OpCtx
{
    Tensor a, b, c;    // 主操作数/输出
    Tensor aux;        // 辅助（行/列向量等）
    std::vector<Tensor> extra;   // 第三及以后的输入（扫描原语的 K/V/P/R…）
};

struct OpSpec
{
    const char* name;
    // setup: 一次性创建输入张量（不计时）
    std::function<void(ComputeEngine&, const BenchConfig&, OpCtx&)> setup;
    // run: 每次迭代执行算子（计时）
    std::function<void(ComputeEngine&, const BenchConfig&, OpCtx&)> run;
    // 工作量：is_flops 时 = FLOPs；否则 = 读写字节数
    std::function<double(const BenchConfig&)> work;
    bool is_flops;     // true → GFLOPS; false → GB/s
};

void setup_matmul(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    // --f16：操作数按 f16 上传（= BitLinear 走稠密缓冲时的 compute=f16 形态），
    // 与打包侧 --f16 同一口径 → 这一对才是"打包 vs 稠密"的公平 A/B。
    ctx.a = c.f16 ? make_input_f16(e, c.m, c.k) : make_input(e, c.m, c.k);
    ctx.b = c.f16 ? make_input_f16(e, c.k, c.n) : make_input(e, c.k, c.n);
}
// transB=1：B 存储为 (N,K) 按 B^T 使用 → 每个变体独立建自己的操作数（此处
// (n,k)，不可与 plain 共用 (k,n)）。形状错配的坑：k==n 时方阵恰好掩盖错配，
// k≠n 时 backend 返回 K mismatch，run 若不查 Result（*expected 不查错 = UB）
// 就会测出 0.000ms / 超物理 GFLOPS 的垃圾值——故 run 必须查错并中止。
void setup_matmul_bt(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    ctx.a = make_input(e, c.m, c.k);
    ctx.b = make_input(e, c.n, c.k);
}
// transA=1：A 存储为 (K,M) 按 A^T 使用 → 操作数必须建 (k,m)
void setup_matmul_at(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    ctx.a = make_input(e, c.k, c.m);
    ctx.b = make_input(e, c.k, c.n);
}
// matmul 系 run：检查 Result（错误时打印并中止，杜绝 *expected UB 静默垃圾值）
void run_matmul(ComputeEngine& e, const BenchConfig&, OpCtx& ctx)
{
    // 输出精度跟随标记：--f16 时不额外付一次边界 cast（同 BitLinear 的 f16 路径）
    auto r =
        e.matmul(ctx.a, ctx.b, false, false,
                 ctx.a.precision() == nn::Precision::F16 ? nn::Precision::F16 : nn::Precision::F32);
    if (!r)
    {
        std::printf("matmul error: %s\n", r.error().message.c_str());
        std::abort();
    }
    ctx.c = std::move(*r);
}
void run_matmul_bt(ComputeEngine& e, const BenchConfig&, OpCtx& ctx)
{
    auto r = e.matmul(ctx.a, ctx.b, false, true);
    if (!r)
    {
        std::printf("matmul_bt error: %s\n", r.error().message.c_str());
        std::abort();
    }
    ctx.c = std::move(*r);
}
void run_matmul_at(ComputeEngine& e, const BenchConfig&, OpCtx& ctx)
{
    auto r = e.matmul(ctx.a, ctx.b, true, false);
    if (!r)
    {
        std::printf("matmul_at error: %s\n", r.error().message.c_str());
        std::abort();
    }
    ctx.c = std::move(*r);
}
double work_matmul(const BenchConfig& c)
{ return 2.0 * c.m * c.n * c.k; }

void setup_batched(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    ctx.a = make_input(e, c.batch * c.m, c.k);
    ctx.b = make_input(e, c.batch * c.k, c.n);
}
void run_batched(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    auto r = e.batched_matmul(ctx.a, ctx.b, c.batch);
    if (!r)
    {
        std::printf("batched_matmul error: %s\n", r.error().message.c_str());
        std::abort();
    }
    ctx.c = std::move(*r);
}
double work_batched(const BenchConfig& c)
{ return 2.0 * c.batch * c.m * c.n * c.k; }

void setup_add(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    ctx.a = make_input(e, c.m, c.n);
    ctx.b = make_input(e, c.m, c.n);
}
void run_add(ComputeEngine& e, const BenchConfig&, OpCtx& ctx)
{ (void)e.add_inplace(ctx.a, ctx.b); }
double bytes_add(const BenchConfig& c)
{ return 3.0 * c.m * c.n * sizeof(Scalar); }

void setup_exp(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{ ctx.a = make_input(e, c.m, c.n); }
double bytes_binary(const BenchConfig& c)
{ return 2.0 * c.m * c.n * sizeof(Scalar); }

void run_row_reduce(ComputeEngine& e, const BenchConfig&, OpCtx& ctx)
{ ctx.c = *e.row_reduce_sum(ctx.a); }
void run_col_reduce(ComputeEngine& e, const BenchConfig&, OpCtx& ctx)
{ ctx.c = *e.col_reduce_sum(ctx.a); }
// 归约实际搬运 = 读全矩阵 (m*n) + 写输出（row_reduce 输出 (m,1) → m 个；
// col_reduce 输出 (1,n) → n 个）。**不能记 2*m*n**——输出只有向量级，按全量
// 记会把 GB/s 虚高 ~2×（5244² 下虚报 440 GB/s，超过 448 理论峰值，物理不可能）。
double bytes_row_reduce(const BenchConfig& c)
{ return (c.m * c.n + c.m) * sizeof(Scalar); }
double bytes_col_reduce(const BenchConfig& c)
{ return (c.m * c.n + c.n) * sizeof(Scalar); }

void run_transpose(ComputeEngine& e, const BenchConfig&, OpCtx& ctx)
{ ctx.c = *e.transpose(ctx.a); }
double bytes_transpose(const BenchConfig& c)
{ return 2.0 * c.m * c.n * sizeof(Scalar); }

void run_scale(ComputeEngine& e, const BenchConfig&, OpCtx& ctx)
{ (void)e.scale_inplace(ctx.a, Scalar{0.5f}); }

// ── RLA / RAPT 扫描原语（P4-2b）：状态扫描的顺序依赖是靠 barrier 串起来的，
//    kernel 天生是**延迟敏感**而非吞吐敏感型 —— 所以口径记 ms（附 GFLOPS 仅作
//    横向参照，数值必然很低），配对 A/B 看的是同一形状下的 ms 变化。
//    形状（与 RAPT 训练同口径）：K/V/P/R (B*H*dk, seq)、A0/B0 (H*dk, dk)、
//    boundary (1, B*seq)；输出 (B*H*5*dk, seq) 或 (B*H*3*dk, seq)。
//    boundary 全 0 = 无文档边界（稳态扫描；全非零会让每 t 复位，属另一个工况）。

Tensor make_zeros(ComputeEngine& e, std::size_t rows, std::size_t cols)
{
    Matrix m(rows, cols);
    auto t = e.from_matrix(std::move(m));
    if (!t) std::abort();
    return std::move(*t);
}

Tensor make_scan_input(ComputeEngine& e, const BenchConfig& c, std::size_t rows, std::size_t cols)
{ return c.f16 ? make_input_f16(e, rows, cols) : make_input(e, rows, cols); }

void setup_scan_prefix(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    if (c.heads == 0 || c.dk == 0)
    {
        std::printf("scan_prefix: heads/dk 不能为 0\n");
        std::abort();
    }
    const std::size_t rows = c.batch * c.heads * c.dk;
    ctx.a = make_scan_input(e, c, rows, c.seq);            // K
    ctx.b = make_scan_input(e, c, rows, c.seq);            // V
    ctx.extra.push_back(make_scan_input(e, c, rows, c.seq));            // P
    ctx.extra.push_back(make_scan_input(e, c, rows, c.seq));            // R
    ctx.extra.push_back(make_scan_input(e, c, c.heads * c.dk, c.dk));   // A0
    ctx.extra.push_back(make_scan_input(e, c, c.heads * c.dk, c.dk));   // B0
    ctx.aux = make_zeros(e, 1, c.batch * c.seq);                        // boundary
}
void run_scan_prefix(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    auto r =
        e.scan_prefix_outer(ctx.a, ctx.b, ctx.extra[0], ctx.extra[1], ctx.extra[2], ctx.extra[3],
                            /*has_state=*/true, c.dk, c.heads, /*causal=*/true, ctx.aux,
                            /*has_bnd=*/true, c.f16 ? nn::Precision::F16 : nn::Precision::F32);
    if (!r)
    {
        std::printf("scan_prefix error: %s\n", r.error().message.c_str());
        std::abort();
    }
    ctx.c = std::move(*r);
}
// 每 (t, 头) 的浮点工作量：[0)/[1)/[2) 三个 dk×dk 的 matvec = 3·2dk²，[3)/[4)
// 是 O(dk) 的标量在内，量级上忽略（口径与 kernel 的真实算力占比一致）。
double flops_scan_prefix(const BenchConfig& c)
{
    return 6.0 * static_cast<double>(c.dk) * static_cast<double>(c.dk) *
           static_cast<double>(c.heads) * static_cast<double>(c.batch) * static_cast<double>(c.seq);
}

void setup_scan_suffix(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    if (c.heads == 0 || c.dk == 0)
    {
        std::printf("scan_suffix: heads/dk 不能为 0\n");
        std::abort();
    }
    const std::size_t rows = c.batch * c.heads * c.dk;
    ctx.extra.push_back(make_scan_input(e, c, rows * c.dk, c.seq));   // D (B*H*dk², seq)
    ctx.a = make_scan_input(e, c, rows, c.seq);            // X
    ctx.b = make_scan_input(e, c, rows, c.seq);            // Y
    ctx.aux = make_zeros(e, 1, c.batch * c.seq);           // boundary
}
void run_scan_suffix(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    auto r =
        e.scan_suffix_outer(ctx.extra[0], ctx.a, ctx.b, c.dk, c.heads, /*causal=*/true, ctx.aux,
                            /*has_bnd=*/true, c.f16 ? nn::Precision::F16 : nn::Precision::F32);
    if (!r)
    {
        std::printf("scan_suffix error: %s\n", r.error().message.c_str());
        std::abort();
    }
    ctx.c = std::move(*r);
}
double flops_scan_suffix(const BenchConfig& c)
{ return flops_scan_prefix(c); }

// ── 三值打包权重 GEMM（P2 / F3）与稠密 GEMM 的配对 A/B ───────────────────
// 口径（docs 21 §5 的 P2 准入门槛）：同一 (m,k)·(k,n) 形状、同一份随机数造的
// latent 权重；稠密侧走 matmul（f16 缓冲），打包侧走 matmul_q（0.25 B/权重）。
// matmul_q 的 work 记 2*m*n*k，GFLOPS 可与 --op matmul 直接比。
//
// matmul_q_bw / matmul_q_t_bw 是**权重带宽口径**（打包权重实际字节 / 时间）：
// 小 n（自回归解码）下 GEMM 是权重带宽受限，GFLOPS 会随 n 线性掉，带宽口径
// 才看得出离显存峰值有多远 —— 单列一档，避免用 GFLOPS 掩盖真相。
//
// --f16 时打包侧跑 f16 存储变体（B/C 均 half）= BitLinear 的 compute=f16 路径。

// 造 latent (rows,len) → τ 逐行 absmean → 引擎 trit_pack（即被测路径本身）
void make_packed(ComputeEngine& e, std::size_t rows, std::size_t len, Tensor& packed, Tensor& tau)
{
    if (!e.describe().ternary_gemm)
    {
        std::printf("  该引擎不支持三值打包 GEMM（describe().ternary_gemm == false）\n");
        std::abort();
    }
    Matrix w(rows, len);
    std::mt19937 g(4321u);
    std::uniform_real_distribution<Scalar> d(-1.0f, 1.0f);
    auto s = w.span();
    for (std::size_t i = 0; i < s.size(); ++i)
        s[i] = d(g);
    Matrix tm(rows, 1);
    for (std::size_t r = 0; r < rows; ++r)
    {
        double acc = 0.0;
        for (std::size_t c = 0; c < len; ++c)
            acc += std::fabs(static_cast<double>(w.at(r, c)));
        tm.set_value(r, 0, static_cast<Scalar>(acc / static_cast<double>(len)));
    }
    auto wt = e.from_matrix(std::move(w));
    auto tt = e.from_matrix(std::move(tm));
    if (!wt || !tt)
    {
        std::printf("matmul_q setup: 上传失败\n");
        std::abort();
    }
    auto pk = e.trit_pack(*wt, *tt);
    if (!pk)
    {
        std::printf("matmul_q setup: trit_pack 失败: %s\n", pk.error().message.c_str());
        std::abort();
    }
    packed = std::move(*pk);
    tau = std::move(*tt);
}

// f16 输入（打包路径的 compute=f16 变体：B 与输出均 half）
Tensor make_input_f16(ComputeEngine& e, std::size_t rows, std::size_t cols)
{
    Matrix m(rows, cols);
    std::mt19937 g(1234u);
    std::uniform_real_distribution<Scalar> d(-1.0f, 1.0f);
    auto s = m.span();
    for (std::size_t i = 0; i < s.size(); ++i)
        s[i] = d(g);
    auto t = e.from_matrix(std::move(m), nn::Precision::F16);
    if (!t) std::abort();
    return std::move(*t);
}

void setup_matmul_q(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    make_packed(e, c.m, c.k, ctx.a, ctx.aux);
    ctx.b = c.f16 ? make_input_f16(e, c.k, c.n) : make_input(e, c.k, c.n);
}
void run_matmul_q(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    auto r = e.matmul_q(ctx.a, ctx.aux, ctx.b, c.f16 ? nn::Precision::F16 : nn::Precision::F32);
    if (!r)
    {
        std::printf("matmul_q error: %s\n", r.error().message.c_str());
        std::abort();
    }
    ctx.c = std::move(*r);
}
// A 存 (K,M)：τ 按**存储行** k 取（转发形态，反向 dX 走这条）
void setup_matmul_q_t(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    make_packed(e, c.k, c.m, ctx.a, ctx.aux);
    ctx.b = c.f16 ? make_input_f16(e, c.k, c.n) : make_input(e, c.k, c.n);
}
void run_matmul_q_t(ComputeEngine& e, const BenchConfig& c, OpCtx& ctx)
{
    auto r =
        e.matmul_q_t(ctx.a, ctx.aux, ctx.b, c.m, c.f16 ? nn::Precision::F16 : nn::Precision::F32);
    if (!r)
    {
        std::printf("matmul_q_t error: %s\n", r.error().message.c_str());
        std::abort();
    }
    ctx.c = std::move(*r);
}
// 权重带宽口径：打包 A 的实际字节（m*k/4 B）+ τ（4 B/存储行）
double bytes_packed(const BenchConfig& c)
{ return c.m * c.k / 4.0 + 4.0 * c.m; }
double bytes_packed_t(const BenchConfig& c)
{ return c.m * c.k / 4.0 + 4.0 * c.k; }

const std::vector<OpSpec>& op_registry()
{
    static const std::vector<OpSpec> reg = {
        {"matmul", setup_matmul, run_matmul, work_matmul, true},
        {"matmul_bt", setup_matmul_bt, run_matmul_bt, work_matmul, true},
        {"matmul_at", setup_matmul_at, run_matmul_at, work_matmul, true},
        {"matmul_q", setup_matmul_q, run_matmul_q, work_matmul, true},
        {"matmul_q_t", setup_matmul_q_t, run_matmul_q_t, work_matmul, true},
        {"matmul_q_bw", setup_matmul_q, run_matmul_q, bytes_packed, false},
        {"matmul_q_t_bw", setup_matmul_q_t, run_matmul_q_t, bytes_packed_t, false},
        {"batched_matmul", setup_batched, run_batched, work_batched, true},
        {"add_inplace", setup_add, run_add, bytes_add, false},
        {"row_reduce_sum", setup_exp, run_row_reduce, bytes_row_reduce, false},
        {"col_reduce_sum", setup_exp, run_col_reduce, bytes_col_reduce, false},
        {"transpose", setup_exp, run_transpose, bytes_transpose, false},
        {"scale_inplace", setup_exp, run_scale, bytes_binary, false},
        {"scan_prefix", setup_scan_prefix, run_scan_prefix, flops_scan_prefix, true},
        {"scan_suffix", setup_scan_suffix, run_scan_suffix, flops_scan_suffix, true},
    };
    return reg;
}

void bench_op(ComputeEngine& engine, const BenchConfig& cfg, const OpSpec& spec)
{
    OpCtx ctx;
    spec.setup(engine, cfg, ctx);
    const bool is_flops = spec.is_flops;
    const double work = spec.work(cfg);
    const std::string_view unit = is_flops ? "GFLOPS" : "GB/s";
    const double scale = is_flops ? 1e9 : 1e9;  // 除以秒，再除以 1e9 得 G-单位

    // warmup
    for (int i = 0; i < cfg.warmup; ++i)
        spec.run(engine, cfg, ctx);

    double best = 1e30;
    for (int i = 0; i < cfg.iter; ++i)
    {
        auto t0 = std::chrono::steady_clock::now();
        for (int j = 0; j < cfg.inner; ++j)
            spec.run(engine, cfg, ctx);
        best = std::min(best, ms_since(t0) / static_cast<double>(cfg.inner));
    }
    const double g = (work / (best / 1000.0)) / scale;
    std::printf("  %-14s : %8.3f ms  %10.1f %s\n", spec.name, best, g, unit.data());

    // 位级哈希（--hash）：对输出张量的原始位型做 FNV-1a 64。**逐位不变**的 kernel
    // 改写必须哈希相同——比"看误差有几位相同"强：任何一位差异都会换哈希。
    // 刻意放在计时之后：`to_matrix` 会改变池/流水线状态，放计时前会污染 ms。
    if (cfg.hash)
    {
        auto out_m = engine.to_matrix(ctx.c);
        if (!out_m)
        {
            std::printf("  哈希：to_matrix 失败\n");
            std::abort();
        }
        std::uint64_t h = 1469598103934665603ull;
        for (const auto& v : out_m->span())
        {
            std::uint32_t bits;
            std::memcpy(&bits, &v, sizeof(bits));
            for (int k = 0; k < 4; ++k)
            {
                h ^= (bits >> (8 * k)) & 0xffu;
                h *= 1099511628211ull;
            }
        }
        std::printf("  %-14s : hash=%016llx  (rows=%zu cols=%zu)\n", spec.name,
                    static_cast<unsigned long long>(h), out_m->rows(), out_m->cols());
    }
}

// ═══════════════════════════════════════════════════════════════════════════
//  基准单层
// ═══════════════════════════════════════════════════════════════════════════
void bench_layer(ComputeEngine& engine, const BenchConfig& cfg, const LayerSpec& spec)
{
    Model model(engine);
    if (!spec.build(model, cfg))
    {
        std::printf("  %-14s : build failed\n", spec.name);
        return;
    }
    model.set_training(!cfg.forward_only);

    const auto [r, c] = spec.shape(cfg);
    const Tensor x = make_input(engine, r, c);

    // 首次 forward 取输出形状
    auto first = model.forward(x);
    if (!first)
    {
        std::printf("  %-14s : forward failed: %s\n", spec.name, first.error().message.c_str());
        return;
    }
    Tensor grad = make_input(engine, first->rows(), first->cols());

    const double fwd_flops = spec.flops(cfg);
    const std::size_t tok = spec.tokens(cfg);

    // warmup
    for (int i = 0; i < cfg.warmup; ++i)
    {
        (void)model.forward(x);
        if (!cfg.forward_only) (void)model.backward(grad);
    }

    // 计时
    double best_fwd = 1e30, best_train = 1e30;
    for (int i = 0; i < cfg.iter; ++i)
    {
        auto t0 = std::chrono::steady_clock::now();
        auto o = model.forward(x);
        double dt = ms_since(t0);
        if (o) best_fwd = std::min(best_fwd, dt);

        if (!cfg.forward_only)
        {
            (void)model.zero_grad();
            t0 = std::chrono::steady_clock::now();
            (void)model.forward(x);
            (void)model.backward(grad);
            dt = ms_since(t0);
            best_train = std::min(best_train, dt);
        }
    }

    const double fwd_gflops = (fwd_flops / (best_fwd / 1000.0)) / 1e9;
    std::printf("  %-14s : fwd %8.3f ms  %9.1f GFLOPS", spec.name, best_fwd, fwd_gflops);
    if (!cfg.forward_only)
    {
        const double train_s = best_train / 1000.0;
        const double tok_s = (train_s > 0) ? static_cast<double>(tok) / train_s : 0.0;
        std::printf("  |  train %8.3f ms  %9.0f tok/s", best_train, tok_s);
    }
    std::printf("\n");
}

// ═══════════════════════════════════════════════════════════════════════════
//  CLI 解析
// ═══════════════════════════════════════════════════════════════════════════
void print_help(const char* prog)
{
    nn::cli::Help help(std::cout, prog, "层 / 算子吞吐量基准");

    help.usage("[--gpu] [--all | --layer <name>[,...] | --op <name|all>[,...]] [选项]");

    help.section("选项");
    help.opt("--gpu", "使用 Vulkan GPU (默认 CPU)");
    help.opt("--all", "测试全部层");
    help.opt("--layer <n>", "指定层 (逗号分隔可多个)");
    help.opt("--op <n>", "指定算子 (matmul 等；all 测试全部算子)");
    help.opt("--forward-only", "仅前向 (默认前向+反向)");
    help.opt("--f16", "打包算子 (matmul_q*) 跑 f16 存储变体 (B/C 均 half)");
    help.opt("--iter <n>", "迭代次数 (默认: 10)");
    help.opt("--warmup <n>", "预热次数 (默认: 2)");
    help.opt("--inner <n>", "每次计时内重复执行次数 (默认: 1；小 n 的 GEMM 用它摊薄\nsubmit/wait "
                            "固定开销 —— 否则测到的是启动开销不是内核)");
    help.opt("--in/--out <n>", "Linear 输入/输出维度");
    help.opt("--dmodel/--heads/--dff <n>", "序列层维度");
    help.opt("--batch/--seq <n>", "batch / 序列长度");
    help.opt("--cin/--cout/--kernel/--hw <n>", "卷积尺寸");
    help.opt("--rows/--cols <n>", "Softmax 形状");
    help.opt("--m/--n/--k <n>", "算子尺寸 (matmul: (m,k)·(k,n)；逐元素/归约: (m,n))");
    help.opt("--dk <n>", "扫描原语 head 维 (scan_prefix/scan_suffix；默认 32)");
    help.opt("--hash", "额外打印输出张量的位级哈希 (FNV-1a 64；kernel 改写逐位不变的 oracle)");
    help.opt("--help, -h", "显示此帮助信息");

    help.section("层名");
    help.text("linear swiglu layernorm rmsnorm softmax mha causal_attn");
    help.text("feedforward transformer gpt_block conv2d maxpool");

    help.section("算子");
    help.text("matmul matmul_bt matmul_at batched_matmul add_inplace");
    help.text("row_reduce_sum col_reduce_sum transpose scale_inplace");
    help.text("matmul_q matmul_q_t (三值打包 GEMM) matmul_q_bw matmul_q_t_bw (权重带宽口径)");
    help.text("scan_prefix scan_suffix (RLA/RAPT 状态扫描；尺寸: --batch/--heads/--dk/--seq)");
}


size_t parse_size(const char* val)
{
    NN_EXIT(val, 0);
    return static_cast<size_t>(std::strtoull(val, nullptr, 10));
}

} // namespace

int main(int argc, char* argv[])
{
    BenchConfig cfg;
    for (int i = 1; i < argc; ++i)
    {
        std::string a = argv[i];
        if (a == "--gpu") { cfg.gpu = true; }
        else if (a == "--all") { cfg.all = true; }
        else if (a == "--forward-only") { cfg.forward_only = true; }
        else if (a == "--f16") { cfg.f16 = true; }
        else if (a == "--layer" && i + 1 < argc)
        {
            std::string val = argv[++i];
            std::string cur;
            for (char ch : val)
            {
                if (ch == ',')
                {
                    if (!cur.empty()) cfg.layers.push_back(cur);
                    cur.clear();
                }
                else cur.push_back(ch);
            }
            if (!cur.empty()) cfg.layers.push_back(cur);
        }
        else if (a == "--iter" && i + 1 < argc)
        {
            cfg.iter = static_cast<int>(parse_size(argv[++i]));
        }
        else if (a == "--warmup" && i + 1 < argc)
        {
            cfg.warmup = static_cast<int>(parse_size(argv[++i]));
        }
        else if (a == "--inner" && i + 1 < argc)
        {
            cfg.inner = static_cast<int>(parse_size(argv[++i]));
        }
        else if (a == "--in") { cfg.in = parse_size(argv[++i]); }
        else if (a == "--out") { cfg.out = parse_size(argv[++i]); }
        else if (a == "--dmodel") { cfg.dmodel = parse_size(argv[++i]); }
        else if (a == "--heads") { cfg.heads = parse_size(argv[++i]); }
        else if (a == "--dff") { cfg.dff = parse_size(argv[++i]); }
        else if (a == "--batch") { cfg.batch = parse_size(argv[++i]); }
        else if (a == "--seq") { cfg.seq = parse_size(argv[++i]); }
        else if (a == "--cin") { cfg.cin = parse_size(argv[++i]); }
        else if (a == "--cout") { cfg.cout = parse_size(argv[++i]); }
        else if (a == "--kernel") { cfg.kernel = parse_size(argv[++i]); }
        else if (a == "--hw") { cfg.hw = parse_size(argv[++i]); }
        else if (a == "--rows") { cfg.rows = parse_size(argv[++i]); }
        else if (a == "--cols") { cfg.cols = parse_size(argv[++i]); }
        else if (a == "--op" && i + 1 < argc)
        {
            std::string val = argv[++i];
            std::string cur;
            for (char ch : val)
            {
                if (ch == ',')
                {
                    if (!cur.empty()) cfg.ops.push_back(cur);
                    cur.clear();
                }
                else cur.push_back(ch);
            }
            if (!cur.empty()) cfg.ops.push_back(cur);
        }
        else if (a == "--m") { cfg.m = parse_size(argv[++i]); }
        else if (a == "--n") { cfg.n = parse_size(argv[++i]); }
        else if (a == "--k") { cfg.k = parse_size(argv[++i]); }
        else if (a == "--dk") { cfg.dk = parse_size(argv[++i]); }
        else if (a == "--hash") { cfg.hash = true; }
        else if (a == "--help" || a == "-h")
        {
            print_help(argv[0]);
            return 0;
        }
        else
        {
            std::printf("未知参数: %s（--help 查看用法）\n", a.c_str());
            return 2;
        }
    }

    // 选择引擎（CPU/GPU），失败硬报错不回退
    if (cfg.inner < 1) cfg.inner = 1;
    auto engine_r = nn::cli::create_engine(nn::cli::EngineConfig{cfg.gpu});
    NN_EXIT(engine_r, 2, "引擎创建失败: %s\n");
    ComputeEngine& engine = **engine_r;
    const bool op_mode = !cfg.ops.empty();
    std::printf("=== layer_bench (%s%s) ===\n", cfg.gpu ? "GPU" : "CPU",
                op_mode ? ", ops" : (cfg.forward_only ? ", forward-only" : ", fwd+bwd"));

    // 算子模式：--op <name|all>
    if (op_mode)
    {
        std::vector<const OpSpec*> to_run;
        const auto& oreg = op_registry();
        for (const auto& want : cfg.ops)
        {
            if (want == "all")
            {
                for (const auto& s : oreg)
                    to_run.push_back(&s);
                continue;
            }
            bool found = false;
            for (const auto& s : oreg)
            {
                if (want == s.name)
                {
                    to_run.push_back(&s);
                    found = true;
                    break;
                }
            }
            if (!found) std::printf("未知算子: %s\n", want.c_str());
        }
        if (to_run.empty())
        {
            std::printf("未指定有效算子；用 --op all 或 --op matmul 等\n");
            return 2;
        }
        for (const auto* spec : to_run)
            bench_op(engine, cfg, *spec);
        return 0;
    }

    // 确定要跑的层
    std::vector<const LayerSpec*> to_run;
    const auto& reg = layer_registry();
    if (cfg.all)
    {
        for (const auto& s : reg)
            to_run.push_back(&s);
    }
    else if (!cfg.layers.empty())
    {
        for (const auto& want : cfg.layers)
        {
            bool found = false;
            for (const auto& s : reg)
            {
                if (want == s.name)
                {
                    to_run.push_back(&s);
                    found = true;
                    break;
                }
            }
            if (!found) std::printf("未知层: %s\n", want.c_str());
        }
        if (to_run.empty())
        {
            std::printf("未指定有效层；用 --all 或 --layer <name>\n");
            return 2;
        }
    }
    else
    {
        std::printf("请指定 --all / --layer <name> / --op <name>\n");
        return 2;
    }

    for (const auto* spec : to_run)
        bench_layer(engine, cfg, *spec);
    return 0;
}
