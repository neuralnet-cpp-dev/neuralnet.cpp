// ── CausalSelfAttention 数值梯度检查（gradcheck） ──────────────────────────
//
// 目的：数值梯度检查 attention 内部的反向路径（batched_matmul / softmax
//       backward / 掩码），与 GPT 整链 gradcheck 分层定位问题来源。
//       batch=1 时绕过 rearrange_3d：若 batch=1 仍失败，问题在 attention
//       内部而非布局重排路径。
//
// 用法：attn_gradcheck [--gpu] [--batch N] [--seq N] [--tol <f>] [--doc]
// ─────────────────────────────────────────────────────────────────────────

#include <nn_error_macros.hpp>
#include <neuralnet.cpp/nn.hpp>
#include <neuralnet.cpp/cli/cli_engine_factory.hpp>

#include <array>
#include <cmath>
#include <cstdlib>
#include <iostream>
#include <random>
#include <string>
#include <string_view>
#include "test_common.hpp"

using nn::CausalSelfAttention;
using nn::ComputeEngine;
using nn::Matrix;
using nn::PosEncodingType;
using nn::Scalar;
using nn::Tensor;
using nn::TensorRef;

namespace
{


Scalar eval_loss(ComputeEngine& engine, CausalSelfAttention& attn, const Tensor& x,
                 const Tensor& go)
{
    auto y = attn.forward(x);
    if (!y)
    {
        std::cerr << "  [eval] forward failed: " << y.error().message << "\n";
        std::abort();
    }
    auto y_m = engine.to_matrix(*y);
    auto go_m = engine.to_matrix(go);
    return dot(*y_m, *go_m);
}


bool check_grad_tensor(ComputeEngine& engine, CausalSelfAttention& attn, const Tensor& x,
                       const Tensor& go, Tensor& param, const Matrix& base,
                       const Matrix& grad_analytical, const std::string& name, Scalar eps,
                       Scalar tol)
{
    bool ok = true;
    std::size_t bad = 0;
    Scalar max_err{0};
    for (std::size_t r = 0; r < base.rows(); ++r)
    {
        for (std::size_t c = 0; c < base.cols(); ++c)
        {
            const Scalar orig = base.at_unchecked(r, c);
            Matrix pp = base;
            pp.set_value_unchecked(r, c, orig + eps);
            auto r_p = engine.write(param, pp.span());
            if (!r_p) return false;
            const Scalar lp = eval_loss(engine, attn, x, go);
            Matrix pm = base;
            pm.set_value_unchecked(r, c, orig - eps);
            auto r_m = engine.write(param, pm.span());
            if (!r_m) return false;
            const Scalar lm = eval_loss(engine, attn, x, go);
            auto r_r = engine.write(param, base.span());
            if (!r_r) return false;
            const Scalar num = (lp - lm) / (Scalar{2} * eps);
            const Scalar ana = grad_analytical.at_unchecked(r, c);
            const Scalar err = std::fabs(num - ana);
            if (err > max_err) max_err = err;
            if (!approx(num, ana, tol))
            {
                ok = false;
                if (bad < 5)
                    std::cout << "  [FAIL] " << name << "(" << r << "," << c << ") num=" << num
                              << " ana=" << ana << " err=" << err << "\n";
                ++bad;
            }
        }
    }
    std::cout << "  " << name << ": " << (ok ? "OK" : "FAIL") << "  max_err=" << max_err
              << "  bad=" << bad << "\n";
    return ok;
}

} // namespace

int main(int argc, char* argv[])
{
    Scalar tol = 5e-2f;
    bool use_gpu = false;
    std::size_t batch = 2;
    std::size_t seq = 8;
    std::string pos_enc_name = "learned";
    bool use_doc = false;
    for (int i = 1; i < argc; ++i)
    {
        std::string a = argv[i];
        if (a == "--tol" && i + 1 < argc) tol = static_cast<Scalar>(std::atof(argv[++i]));
        else if (a == "--batch" && i + 1 < argc)
            batch = static_cast<std::size_t>(std::atoi(argv[++i]));
        else if (a == "--seq" && i + 1 < argc) seq = static_cast<std::size_t>(std::atoi(argv[++i]));
        else if (a == "--pos-enc" && i + 1 < argc) pos_enc_name = argv[++i];
        else if (a == "--doc") use_doc = true;
        else if (a == "--gpu") use_gpu = true;
        else if (a == "--help")
        {
            std::cout << "用法: attn_gradcheck [--gpu] [--batch N] [--seq N] [--tol <f>] "
                         "[--pos-enc learned|sinusoidal|alibi|rope] [--doc]\n";
            return 0;
        }
    }

    nn::cli::EngineConfig ecfg;
    ecfg.use_gpu = use_gpu;
    auto engine_res = nn::cli::create_engine(ecfg, std::cout);
    NN_EXIT(engine_res, 1, "引擎创建失败: ");
    auto engine = std::move(*engine_res);
    ComputeEngine& eng = *engine;

    const std::size_t d_model = 16;
    const std::size_t num_heads = 2;   // d_k = 8

    PosEncodingType pos_enc = PosEncodingType::Learned;
    if (pos_enc_name == "rope") pos_enc = PosEncodingType::RoPE;
    else if (pos_enc_name == "sinusoidal") pos_enc = PosEncodingType::Sinusoidal;
    else if (pos_enc_name == "alibi") pos_enc = PosEncodingType::ALiBi;

    std::cout << "========================================\n";
    std::cout << "  CausalSelfAttention 数值梯度检查 (gradcheck)\n";
    std::cout << "========================================\n";
    std::cout << "  d_model=" << d_model << " heads=" << num_heads << " seq=" << seq
              << " batch=" << batch << " tol=" << tol << " pos_enc=" << pos_enc_name
              << " doc=" << (use_doc ? 1 : 0) << "\n";

    CausalSelfAttention attn(d_model, num_heads, seq, seq, pos_enc);
    NN_EXIT(attn.init(eng), 1, "CausalSelfAttention init 失败: ");
    if (use_doc)
    {
        // 文档感知：每样本两文档（前/后半）、样本错开基线 → 覆盖 backward
        //   的 CausalDocScoreMask 分支（Doc；叠加 --pos-enc alibi 即 AlibiDoc）。
        //   本用例专门验证该分支的梯度：仅 forward 通过不足以验证
        //   （梯度跨文档串扰 forward 抓不住）
        std::vector<std::size_t> ids(batch * seq, 0);
        for (std::size_t b = 0; b < batch; ++b)
            for (std::size_t t = 0; t < seq; ++t)
                ids[b * seq + t] = b * 2 + (t < seq / 2 ? std::size_t{0} : std::size_t{1});
        attn.set_doc_ids(ids);
    }

    std::mt19937_64 rng(123);
    std::uniform_real_distribution<Scalar> dist(-1, 1);

    const std::size_t total = seq * batch;
    Matrix x_m(d_model, total);
    Matrix go_m(d_model, total);
    for (std::size_t i = 0; i < x_m.size(); ++i)
        x_m.span()[i] = dist(rng);
    for (std::size_t i = 0; i < go_m.size(); ++i)
        go_m.span()[i] = dist(rng);

    auto x = eng.from_matrix(x_m);
    NN_EXIT(x, 1, "from_matrix(x) failed\n");
    auto go = eng.from_matrix(go_m);
    NN_EXIT(go, 1, "from_matrix(go) failed\n");

    auto y_fwd = attn.forward(*x);
    NN_EXIT(y_fwd, 1, "forward failed: ");

    auto params = attn.parameters();
    auto grads = attn.param_gradients();
    for (auto& g : grads)
    {
        auto rz = eng.zero(g.get());
        NN_EXIT(rz, 1, "zero failed\n");
    }
    auto gx = attn.backward(*go);
    NN_EXIT(gx, 1, "backward failed: ");

    const Scalar eps = 1e-3f;
    bool all_pass = true;
    static constexpr std::array<std::string_view, 8> tags{"wq.w", "wq.b", "wk.w", "wk.b",
                                                          "wv.w", "wv.b", "wo.w", "wo.b"};
    for (std::size_t p = 0; p < params.size(); ++p)
    {
        auto pm = eng.to_matrix(params[p].get());
        auto gm = eng.to_matrix(grads[p].get());
        std::string name = (p < 8) ? std::string(tags[p]) : ("param[" + std::to_string(p) + "]");
        all_pass &=
            check_grad_tensor(eng, attn, *x, *go, params[p].get(), *pm, *gm, name, eps, tol);
    }

    // 输入梯度
    {
        auto gxm = eng.to_matrix(*gx);
        auto xt = eng.clone(*x);
        all_pass &= check_grad_tensor(eng, attn, *xt, *go, *xt, x_m, *gxm, "grad_x", eps, tol);
    }

    std::cout << "----------------------------------------\n";
    std::cout << "  结果: " << (all_pass ? "✅ 全部通过" : "❌ 存在失败") << "\n";
    return all_pass ? 0 : 1;
}