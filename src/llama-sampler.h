#pragma once

#include "llama.h"

#include <vector>

struct llama_vocab;
struct llama_grammar;

// sampler chain

struct llama_sampler_chain {
    llama_sampler_chain_params params;

    // has .backend_init() been called?
    bool is_init = false;

    uint32_t n_nodes = 0;

    struct info {
        bool is_backend;

        llama_sampler * ptr;
    };

    std::vector<info> samplers;

    // pre-allocated buffer for llama_sampler_sample to avoid repeated allocations
    std::vector<llama_token_data> cur;

    // per-step token constraint (e.g. grammar / reasoning budget) applied to the logits
    // before backend sampling: the mask is a vocab-sized 0/1 F32 input, and the graph does
    // logits += log(mask) (log(1)=0 keep, log(0)=-INF discard)
    struct ggml_tensor * constraint_mask = nullptr;   // GPU input tensor, created in backend_apply
    std::vector<float>   constraint_mask_buf = {};     // CPU buffer filled per step in backend_set_input

    // timing

    mutable int64_t t_sample_us;

    mutable int32_t n_sample;
};

uint32_t llama_sampler_backend_n_nodes(const llama_sampler * sampler);
void llama_sampler_backend_begin(llama_sampler * sampler);

struct llama_sampler * llama_sampler_init_dry_testing(
        float   dry_multiplier,
        float   dry_base,
        int32_t dry_allowed_length,
        int32_t dry_penalty_last_n,
        const std::vector<std::vector<llama_token>> & seq_breakers);
