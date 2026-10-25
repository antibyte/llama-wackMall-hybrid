#include "models.h"
#include <cmath>
#include <stdexcept>

static ggml_tensor * dory_l2_norm(ggml_context * ctx, ggml_tensor * x, float eps) {
    return ggml_l2_norm(ctx, x, eps);
}

void llama_model_dory::load_arch_hparams(llama_model_loader & ml) {
    ml.get_key(LLM_KV_INPUT_LAYER_COUNT, n_input);
    ml.get_key(LLM_KV_RECURRENT_LAYER_COUNT, n_recurrent);
    ml.get_key(LLM_KV_OUTPUT_LAYER_COUNT, n_output);
    ml.get_key(LLM_KV_NUM_LOOPS, n_loops);
    ml.get_key(LLM_KV_RECURRENT_KV_CACHE_MODE, recurrent_kv_cache_mode, false);
    if (recurrent_kv_cache_mode != "per_loop" && recurrent_kv_cache_mode != "last_loop") {
        throw std::runtime_error("Dory recurrent_kv_cache_mode must be per_loop or last_loop");
    }
    ml.get_key(LLM_KV_LAYER_PATTERN, pattern);
    uint32_t n_profile = 0;
    ml.get_arr_n(LLM_KV_ROPE_PROFILE, n_profile);
    if (n_profile > LLAMA_MAX_LAYERS) {
        throw std::runtime_error("Dory RoPE profile is too large");
    }
    ml.get_arr(LLM_KV_ROPE_PROFILE, profile);
    ml.get_key(LLM_KV_INIT_STD, init_std);
    ml.get_key(LLM_KV_ALPHA_INIT, alpha_init);
    ml.get_key(LLM_KV_GATE_INIT, gate_init);
    ml.get_key(LLM_KV_ROPE_FREQ_BASE, theta_1);
    ml.get_key(LLM_KV_ROPE_FREQ_BASE_2, theta_2);
    ml.get_key(LLM_KV_ATTENTION_SLIDING_WINDOW, hparams.n_swa);

    const uint64_t n_physical = uint64_t(n_input) + n_recurrent + n_output;
    const uint64_t n_virtual = uint64_t(n_input) + uint64_t(n_recurrent) * n_loops + n_output;
    if (!n_input || !n_recurrent || !n_output || !n_loops || n_loops > 4 ||
            n_virtual > LLAMA_MAX_LAYERS || n_physical != hparams.n_layer_all ||
            pattern.size() != n_physical || profile.size() != n_physical ||
            pattern.find_first_not_of("S*-") != std::string::npos ||
            !(init_std > 0 && std::isfinite(init_std)) ||
            !(alpha_init > 0 && std::isfinite(alpha_init)) ||
            !(gate_init > 0 && std::isfinite(gate_init)) ||
            !(theta_1 > 0 && std::isfinite(theta_1)) || !(theta_2 > 0 && std::isfinite(theta_2)) ||
            !hparams.n_swa || pattern.find('S') == std::string::npos || pattern.find('*') == std::string::npos) {
        throw std::runtime_error("unsupported or invalid Dory recurrence metadata");
    }
    const auto nh = hparams.n_head(0);
    const auto nk = hparams.n_head_kv(0);
    if (!nh || !nk || nh % nk || !hparams.n_embd_head_k() ||
            hparams.n_embd_head_k() != hparams.n_embd_head_v() || hparams.n_rot() != hparams.n_embd_head_k()) {
        throw std::runtime_error("invalid Dory attention dimensions");
    }
    const auto nf = hparams.n_ff(0);
    if (!nf) {
        throw std::runtime_error("invalid Dory feed-forward dimension");
    }
    for (auto p : profile) {
        if (p < 1 || p > 2) {
            throw std::runtime_error("invalid Dory RoPE profile");
        }
    }
    for (uint32_t i = 0; i < n_input; ++i) {
        physical.push_back(i);
    }
    for (uint32_t k = 0; k < n_loops; ++k) {
        for (uint32_t i = 0; i < n_recurrent; ++i) {
            physical.push_back(n_input + i);
        }
    }
    for (uint32_t i = 0; i < n_output; ++i) {
        physical.push_back(n_input + n_recurrent + i);
    }
    hparams.n_layer_all = (uint32_t) n_virtual;
    hparams.swa_type = LLAMA_SWA_TYPE_STANDARD;
    hparams.rope_freq_base_train_swa = theta_2;
    for (uint32_t il = 0; il < n_virtual; ++il) {
        const uint32_t p = physical[il];
        const bool recurrent = p >= n_input && p < n_input + n_recurrent;
        cache_layer.push_back(recurrent && recurrent_kv_cache_mode == "last_loop" ? p : il);
        hparams.n_head_arr[il] = nh;
        hparams.n_head_kv_arr[il] = pattern[p] == '-' ? 0 : nk;
        hparams.n_ff_arr[il] = nf;
        hparams.is_swa_impl[il] = pattern[p] == 'S';
    }
    type = LLM_TYPE_UNKNOWN;
}

void llama_model_dory::load_arch_tensors(llama_model_loader &) {
    LLAMA_LOAD_LOCALS;
    tok_embd = create_tensor(tn(LLM_TENSOR_TOKEN_EMBD, "weight"), {n_embd, n_vocab}, 0);
    output = create_tensor(tn(LLM_TENSOR_OUTPUT, "weight"), {n_embd, n_vocab}, 0);
    logit_scale = create_tensor(tn(LLM_TENSOR_OUTPUT_SCALE, "weight"), {n_vocab}, 0);
    scale.resize(n_layer);
    std::vector<int> first(pattern.size(), -1);
    for (int il = 0; il < n_layer; ++il) {
        const int p = (int) physical[il];
        if (first[p] >= 0) {
            layers[il] = layers[first[p]];
            scale[il] = scale[first[p]];
            continue;
        }
        first[p] = il;
        auto & l = layers[il];
        auto & s = scale[il];
        s.alpha = create_tensor(tn(LLM_TENSOR_RESIDUAL_ALPHA, "weight", p), {n_embd}, 0);
        if (pattern[p] == '-') {
            l.ffn_gate = create_tensor(tn(LLM_TENSOR_FFN_GATE, "weight", p), {n_embd, n_ff}, 0);
            l.ffn_up = create_tensor(tn(LLM_TENSOR_FFN_UP, "weight", p), {n_embd, n_ff}, 0);
            l.ffn_down = create_tensor(tn(LLM_TENSOR_FFN_DOWN, "weight", p), {n_ff, n_embd}, 0);
            s.suv_gate = create_tensor(tn(LLM_TENSOR_FFN_GATE_SCALE, "weight", p), {n_ff}, 0);
            s.suv_up = create_tensor(tn(LLM_TENSOR_FFN_UP_SCALE, "weight", p), {n_ff}, 0);
        } else {
            const int64_t nq = n_head * n_embd_head_k;
            const int64_t nkv = hparams.n_head_kv(il) * n_embd_head_k;
            l.wq = create_tensor(tn(LLM_TENSOR_ATTN_Q, "weight", p), {n_embd, nq}, 0);
            l.wk = create_tensor(tn(LLM_TENSOR_ATTN_K, "weight", p), {n_embd, nkv}, 0);
            l.wv = create_tensor(tn(LLM_TENSOR_ATTN_V, "weight", p), {n_embd, nkv}, 0);
            l.wo = create_tensor(tn(LLM_TENSOR_ATTN_OUT, "weight", p), {nq, n_embd}, 0);
            l.wqkv_gate = create_tensor(tn(LLM_TENSOR_ATTN_GATE, "weight", p), {n_embd, nq}, 0);
            s.sqk = create_tensor(tn(LLM_TENSOR_ATTN_QK_SCALE, "weight", p), {nq}, 0);
            s.gate = create_tensor(tn(LLM_TENSOR_ATTN_GATE_SCALE, "weight", p), {nq}, 0);
        }
    }
}

std::unique_ptr<llm_graph_context> llama_model_dory::build_arch_graph(const llm_graph_params & params) const {
    return std::make_unique<graph>(*this, params);
}

llama_model_dory::graph::graph(const llama_model_dory & model, const llm_graph_params & params) : llm_graph_context(params) {
    ggml_tensor * cur = build_inp_embd(model.tok_embd);
    ggml_tensor * pos = build_inp_pos();
    ggml_tensor * out_ids = build_inp_out_ids();
    auto * attn = build_attn_inp_kv_iswa();
    ggml_tensor * input_h = nullptr;
    const int recurrent_end = (int) model.n_input + (int) model.n_recurrent * (int) model.n_loops;
    const auto f32 = [&](ggml_tensor * x) {
        return x->type == GGML_TYPE_F32 ? x : ggml_cast(ctx0, x, GGML_TYPE_F32);
    };

    for (int il = 0; il < n_layer; ++il) {
        const int p = (int) model.physical[il];
        const auto & l = model.layers[il];
        const auto & s = model.scale[il];
        if (il == (int) model.n_input) {
            input_h = cur;
        }
        if (il >= (int) model.n_input && il < recurrent_end && (il - (int) model.n_input) % (int) model.n_recurrent == 0) {
            cur = dory_l2_norm(ctx0, ggml_add(ctx0, cur, input_h), 1e-6f);
        }
        ggml_tensor * residual = cur;
        if (model.pattern[p] == '-') {
            auto * g = build_lora_mm(l.ffn_gate, cur);
            auto * u = build_lora_mm(l.ffn_up, cur);
            g = ggml_mul(ctx0, g, ggml_scale(ctx0, f32(s.suv_gate), sqrtf((float) n_embd)));
            u = ggml_mul(ctx0, u, ggml_scale(ctx0, f32(s.suv_up), sqrtf((float) n_embd)));
            cur = dory_l2_norm(ctx0, ggml_mul(ctx0, ggml_silu(ctx0, g), u), 1e-6f);
            cur = build_lora_mm(l.ffn_down, cur);
        } else {
            const auto hd = hparams.n_embd_head_k(il);
            const auto nh = hparams.n_head(il);
            const auto nk = hparams.n_head_kv(il);
            auto qkv = build_qkv(l, cur, hd, nh, nk, il);
            auto * q = qkv.q;
            auto * k = qkv.k;
            auto * v = qkv.v;
            if (model.profile[p] != 0) {
                const float theta = model.profile[p] == 2 ? model.theta_2 : model.theta_1;
                q = ggml_rope_ext(ctx0, q, pos, nullptr, hd, rope_type, n_ctx_orig, theta, 1.0f, 0.0f, 1.0f, 0.0f, 0.0f);
                k = ggml_rope_ext(ctx0, k, pos, nullptr, hd, rope_type, n_ctx_orig, theta, 1.0f, 0.0f, 1.0f, 0.0f, 0.0f);
            }
            // rms(q, eps/n) * (sq / sqrt(n)) is the per-head L2, and rms+mul fuses on CUDA.
            const float hd_f = (float) hd;
            const float sq_k = sqrtf(sqrtf(hd_f)) / model.init_std;
            auto * sq = ggml_sqr(ctx0, ggml_scale(ctx0, f32(s.sqk), sq_k));
            sq = ggml_reshape_3d(ctx0, sq, hd, nh, 1);
            q = ggml_rms_norm(ctx0, q, 1e-6f / hd_f);
            q = ggml_mul(ctx0, q, sq);
            k = dory_l2_norm(ctx0, k, 1e-6f);
            auto * gate = build_lora_mm(l.wqkv_gate, cur);
            auto * sg = ggml_sqr(ctx0, ggml_scale(ctx0, f32(s.gate), sqrtf(model.gate_init) / model.init_std));
            gate = ggml_sigmoid(ctx0, ggml_mul(ctx0, gate, sg));
            cur = build_attn(attn, nullptr, nullptr, nullptr, q, k, v, nullptr, nullptr, nullptr,
                    1.0f / sqrtf((float) hd), (int) model.cache_layer[il]);
            cur = dory_l2_norm(ctx0, ggml_mul(ctx0, cur, gate), 1e-6f);
            cur = build_lora_mm(l.wo, cur);
        }
        auto * alpha = ggml_abs(ctx0, ggml_scale(ctx0, f32(s.alpha), model.alpha_init / model.init_std));
        auto * a = dory_l2_norm(ctx0, residual, 1e-6f);
        auto * b = dory_l2_norm(ctx0, cur, 1e-6f);
        auto * diff = ggml_sub(ctx0, b, a);
        auto * mixed = ggml_mul(ctx0, diff, alpha);
        auto * summed = ggml_add(ctx0, a, mixed);
        cur = dory_l2_norm(ctx0, summed, 1e-6f);
        if (il >= (int) model.n_input && il < recurrent_end &&
                (il + 1 - (int) model.n_input) % (int) model.n_recurrent == 0) {
            cur = dory_l2_norm(ctx0, cur, 1e-6f);
        }
        cb(cur, "l_out", il);
    }
    if (out_ids) {
        cur = ggml_get_rows(ctx0, cur, out_ids);
    }
    res->t_embd = cur;
    cb(cur, "result_norm", -1);
    cur = build_lora_mm(model.output, cur);
    cur = ggml_mul(ctx0, cur, ggml_scale(ctx0, f32(model.logit_scale), 1.0f / model.init_std));
    cb(cur, "result_output", -1);
    res->t_logits = cur;
    ggml_build_forward_expand(gf, cur);
}

