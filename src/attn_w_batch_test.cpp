// ── attn_w_batch_test.cpp — GPU 注意力 W 表达式 batch 行号回归测试（ctest）──
//
// 守什么：GPU 融合 matmul 尾链必须按**全局行号**（而非 batch 内行号）读取
// (rows,1) 全网格输入（注意力的 m/l）——按 batch 内行号读会在 batch>1 或
// 多头（BH>1）时读错 m/l → GPU 前向错误。本测试用同一随机权重、同一输入
// 对比 CausalSelfAttention 的 CPU/GPU forward，覆盖 4 组配置
// (batch, heads) = (1,1)(2,1)(1,2)(2,2)（BH 最大 4），
// 任一 max_abs > 1e-3 判失败。
//
// 用法：
//   attn_w_batch_test              依次跑 4 组配置（ctest 默认）
//   attn_w_batch_test <b> <h> <s>  单配置模式（调试）
//
// 退出码：0 = 全部一致；2 = CPU 引擎创建失败；77 = GPU 不可用（ctest SKIP）；
//         3 = CPU/GPU 不一致。
// ────────────────────────────────────────────────────────────────────────────
#include <nn_error_macros.hpp>

#include <cmath>
#include <iostream>
#include <random>
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
using nn::Matrix;
using nn::Scalar;


int main(int argc, char** argv)
{
    auto cpu_res = nn::cli::create_engine(nn::cli::EngineConfig{}, std::cout);
    NN_EXIT(cpu_res, 2, "CPU 引擎创建失败: ");
    nn::cli::EngineConfig gcfg;
    gcfg.use_gpu = true;
    auto gpu_res = nn::cli::create_engine(gcfg, std::cout);
    NN_EXIT(gpu_res, 77, "GPU 不可用，跳过: ");
    nn::ComputeEngine& cpu = **cpu_res;
    nn::ComputeEngine& gpu = **gpu_res;

    const std::size_t d_model = 16;
    std::size_t batch = 0, heads = 0, seq = 5;
    if (argc >= 4)
    {
        batch = std::stoul(argv[1]);
        heads = std::stoul(argv[2]);
        seq = std::stoul(argv[3]);
    }

    std::mt19937_64 rng(123);
    std::uniform_real_distribution<Scalar> dist(-1, 1);

    auto run_cfg = [&](std::size_t b, std::size_t h) -> bool
    {
        std::cout << "attn W batch 行号回归: d_model=" << d_model << " heads=" << h
                  << " seq=" << seq << " batch=" << b << " (BH=" << b * h << ")\n";
        nn::CausalSelfAttention attn_cpu(d_model, h, seq, seq, nn::PosEncodingType::Learned);
        nn::CausalSelfAttention attn_gpu(d_model, h, seq, seq, nn::PosEncodingType::Learned);
        {
            auto r = attn_cpu.init(cpu);
            if (!r)
            {
                std::cerr << "cpu init: " << r.error().message << "\n";
                return false;
            }
        }
        {
            auto r = attn_gpu.init(gpu);
            if (!r)
            {
                std::cerr << "gpu init: " << r.error().message << "\n";
                return false;
            }
        }

        // 权重同步：CPU 随机 → GPU
        {
            auto pc = attn_cpu.parameters();
            auto pg = attn_gpu.parameters();
            for (std::size_t i = 0; i < pc.size(); ++i)
            {
                auto cm = cpu.to_matrix(pc[i].get());
                if (!cm)
                {
                    std::cerr << "to_matrix cpu failed\n";
                    return false;
                }
                auto cp = gpu.write(pg[i].get(), cm->span());
                if (!cp)
                {
                    std::cerr << "write gpu failed: " << cp.error().message << "\n";
                    return false;
                }
            }
        }

        const std::size_t total = seq * b;
        Matrix x_m(d_model, total);
        for (std::size_t i = 0; i < x_m.size(); ++i)
            x_m.span()[i] = dist(rng);

        auto xc = cpu.from_matrix(x_m);
        auto xg = gpu.from_matrix(x_m);
        if (!xc || !xg)
        {
            std::cerr << "from_matrix failed\n";
            return false;
        }

        auto yc = attn_cpu.forward(*xc);
        auto yg = attn_gpu.forward(*xg);
        if (!yc)
        {
            std::cout << "CPU forward 失败: " << yc.error().message << "\n";
            return false;
        }
        if (!yg)
        {
            std::cout << "GPU forward 失败: " << yg.error().message << "\n";
            return false;
        }

        auto ycm = cpu.to_matrix(*yc);
        auto ygm = gpu.to_matrix(*yg);
        if (!ycm || !ygm)
        {
            std::cerr << "to_matrix failed\n";
            return false;
        }

        Scalar max_abs = 0;
        std::size_t bad = 0;
        const auto sc = ycm->span();
        const auto sg = ygm->span();
        for (std::size_t i = 0; i < ycm->size(); ++i)
        {
            const Scalar d = std::fabs(sc[i] - sg[i]);
            if (d > max_abs) max_abs = d;
            if (d > 1e-3f) ++bad;
        }
        std::cout << "  max_abs_diff=" << max_abs << "  bad_cells(>1e-3)=" << bad << " / "
                  << ycm->size() << "  " << (max_abs <= 1e-3f ? "✅ 一致" : "❌ 不一致") << "\n";
        return max_abs <= 1e-3f;
    };

    int failed = 0;
    if (batch > 0 && heads > 0)
    {
        if (!run_cfg(batch, heads)) ++failed;
    }
    else
    {
        // ctest 默认：4 组配置全跑（任一组 BH>1 即可暴露 batch 内行号读错）
        const std::size_t cfgs[4][2] = {{1, 1}, {2, 1}, {1, 2}, {2, 2}};
        for (auto& c : cfgs)
            if (!run_cfg(c[0], c[1])) ++failed;
    }
    return failed > 0 ? 3 : 0;
}
