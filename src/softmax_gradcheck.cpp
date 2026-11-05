// ── Softmax 数值梯度检查（gradcheck） ─────────────────────────────────────
//
// 目的：单独验证 Softmax 的 forward/backward 与中心差分一致。attention
//       反向链中 grad_Q/grad_K 均由 grad_S = softmax.backward(grad_A) 派生
//       （grad_V 不经 Softmax），单独隔离验证便于分层定位问题来源。
//
// 用法：softmax_gradcheck [--gpu] [--rows N] [--cols N] [--tol <f>]
// ─────────────────────────────────────────────────────────────────────────

#include <nn_error_macros.hpp>

#include <cmath>
#include <cstdlib>
#include <iostream>
#include <random>
#include <string>
#include "test_common.hpp"
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
using nn::cli::EngineConfig;
using nn::cli::create_engine;
using nn::ComputeEngine;
using nn::Matrix;
using nn::Scalar;
using nn::Softmax;
using nn::Tensor;


namespace
{


Scalar eval_loss(ComputeEngine& engine, Softmax& sm, const Tensor& x, const Tensor& go)
{
    auto y = sm.forward(x);
    auto y_m = engine.to_matrix(*y);
    auto go_m = engine.to_matrix(go);
    return dot(*y_m, *go_m);
}


bool check_input_grad(ComputeEngine& engine, Softmax& sm, const Tensor& go, const Tensor& grad_x,
                      const Matrix& x_m, Scalar eps, Scalar tol)
{
    bool ok = true;
    std::size_t bad = 0;
    Scalar max_err{0};
    auto gxm = engine.to_matrix(grad_x);
    for (std::size_t r = 0; r < x_m.rows(); ++r)
        for (std::size_t c = 0; c < x_m.cols(); ++c)
        {
            const Scalar orig = x_m.at_unchecked(r, c);
            Matrix pp = x_m;
            pp.set_value_unchecked(r, c, orig + eps);
            auto xt = engine.from_matrix(pp);
            const Scalar lp = eval_loss(engine, sm, *xt, go);
            Matrix pm = x_m;
            pm.set_value_unchecked(r, c, orig - eps);
            auto xt2 = engine.from_matrix(pm);
            const Scalar lm = eval_loss(engine, sm, *xt2, go);
            const Scalar num = (lp - lm) / (Scalar{2} * eps);
            const Scalar ana = gxm->at_unchecked(r, c);
            const Scalar err = std::fabs(num - ana);
            if (err > max_err) max_err = err;
            if (!approx(num, ana, tol))
            {
                ok = false;
                if (bad < 8)
                    std::cout << "  [FAIL] (" << r << "," << c << ") num=" << num << " ana=" << ana
                              << " err=" << err << "\n";
                ++bad;
            }
        }
    std::cout << "  grad_x: " << (ok ? "OK" : "FAIL") << "  max_err=" << max_err << "  bad=" << bad
              << "\n";
    return ok;
}

} // namespace

int main(int argc, char* argv[])
{
    Scalar tol = 1e-2f;
    bool use_gpu = false;
    std::size_t rows = 8;
    std::size_t cols = 8;
    for (int i = 1; i < argc; ++i)
    {
        std::string a = argv[i];
        if (a == "--tol" && i + 1 < argc) tol = static_cast<Scalar>(std::atof(argv[++i]));
        else if (a == "--rows" && i + 1 < argc)
            rows = static_cast<std::size_t>(std::atoi(argv[++i]));
        else if (a == "--cols" && i + 1 < argc)
            cols = static_cast<std::size_t>(std::atoi(argv[++i]));
        else if (a == "--gpu") use_gpu = true;
        else if (a == "--help")
        {
            std::cout << "用法: softmax_gradcheck [--gpu] [--rows N] [--cols N] [--tol <f>]\n";
            return 0;
        }
    }

    nn::cli::EngineConfig ecfg;
    ecfg.use_gpu = use_gpu;
    auto engine_res = nn::cli::create_engine(ecfg, std::cout);
    NN_EXIT(engine_res, 1, "引擎创建失败: ");
    auto engine = std::move(*engine_res);
    ComputeEngine& eng = *engine;

    std::cout << "========================================\n";
    std::cout << "  Softmax 数值梯度检查 (gradcheck)\n";
    std::cout << "========================================\n";
    std::cout << "  rows=" << rows << " cols=" << cols << " tol=" << tol << "\n";

    Softmax sm;
    (void)sm.init(eng);   // M6 段 C：层由 init 绑定引擎
    std::mt19937_64 rng(123);
    std::uniform_real_distribution<Scalar> dist(-2, 2);
    Matrix x_m(rows, cols);
    Matrix go_m(rows, cols);
    for (std::size_t i = 0; i < x_m.size(); ++i)
        x_m.span()[i] = dist(rng);
    for (std::size_t i = 0; i < go_m.size(); ++i)
        go_m.span()[i] = dist(rng);

    auto x = eng.from_matrix(x_m);
    auto go = eng.from_matrix(go_m);
    auto y_fwd = sm.forward(*x);
    auto gx = sm.backward(*go);

    const Scalar eps = 1e-3f;
    bool all_pass = check_input_grad(eng, sm, *go, *gx, x_m, eps, tol);
    std::cout << "----------------------------------------\n";
    std::cout << "  结果: " << (all_pass ? "✅ 全部通过" : "❌ 存在失败") << "\n";
    return all_pass ? 0 : 1;
}