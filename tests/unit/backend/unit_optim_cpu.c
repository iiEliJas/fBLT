#include "test_helpers.h"
#include "test_suite.h"

#include <stdio.h>
#include <string.h>

#include "ops/optim.h"
#include "core/allocator.h"
#include "core/tensor.h"
#include "models/model.h"
#include "models/model_builder.h"
#include "train_optim.h"

// Single-parameter check
static int test_sgd_step_known_value(void) {
    blt_arena *arena = blt_arena_create(64 * 1024, BLT_BACKEND_CPU);
    if (!arena) {
        return 0;
    }

    size_t shape[1] = {4};
    blt_tensor param = blt_tensor_create(arena, shape, 1, BLT_DTYPE_FP32);
    blt_tensor grad = blt_tensor_create(arena, shape, 1, BLT_DTYPE_FP32);

    float *p = (float *)param.data;
    float *g = (float *)grad.data;
    p[0] = 1.0f;
    p[1] = -2.0f;
    p[2] = 0.5f;
    p[3] = 10.0f;
    g[0] = 0.1f;
    g[1] = 0.2f;
    g[2] = -1.0f;
    g[3] = 4.0f;

    float lr = 0.5f;
    blt_sgd_step(&param, &grad, lr);

    // expected[i] = p_before[i] - lr * g_before[i]
    float expected[4] = {1.0f - 0.5f * 0.1f, -2.0f - 0.5f * 0.2f, 0.5f - 0.5f * -1.0f, 10.0f - 0.5f * 4.0f};

    int ok = 1;
    for (size_t i = 0; i < 4; ++i) {
        float diff = p[i] - expected[i];
        if (diff < 0) diff = -diff;
        if (diff > 1e-6f) {
            ok = 0;
        }
    }
    TEST_ASSERT(ok);

    blt_arena_destroy(arena);
    return ok;
}

// No-op check: grad = 0 leaves param unchanged
static int test_sgd_step_zero_grad(void) {
    blt_arena *arena = blt_arena_create(64 * 1024, BLT_BACKEND_CPU);
    if (!arena) {
        return 0;
    }

    size_t shape[1] = {3};
    blt_tensor param = blt_tensor_create(arena, shape, 1, BLT_DTYPE_FP32);
    blt_tensor grad = blt_tensor_create(arena, shape, 1, BLT_DTYPE_FP32); // zero-init

    float *p = (float *)param.data;
    p[0] = 3.14f;
    p[1] = -7.0f;
    p[2] = 42.0f;
    float before[3] = {p[0], p[1], p[2]};

    blt_sgd_step(&param, &grad, 0.1f);

    int ok = (p[0] == before[0]) && (p[1] == before[1]) && (p[2] == before[2]);
    TEST_ASSERT(ok);

    blt_arena_destroy(arena);
    return ok;
}

// Loop-update drift check: repeated SGD steps toward a fixed pseudo-gradient
// dont accumulate error beyond floating-point tolerance
static int test_sgd_step_loop(void) {
    blt_arena *arena = blt_arena_create(64 * 1024, BLT_BACKEND_CPU);
    if (!arena) {
        return 0;
    }

    size_t shape[1] = {1};
    blt_tensor param = blt_tensor_create(arena, shape, 1, BLT_DTYPE_FP32);
    blt_tensor grad = blt_tensor_create(arena, shape, 1, BLT_DTYPE_FP32);

    float *p = (float *)param.data;
    float *g = (float *)grad.data;
    p[0] = 100.0f;
    g[0] = 1.0f;
    float lr = 1.0f;

    for (int step = 0; step < 100; ++step) {
        blt_sgd_step(&param, &grad, lr);
    }

    // 100 steps of param -= 1.0 * 1.0 starting at 100.0 -> 0.0
    float diff = p[0] - 0.0f;
    if (diff < 0) diff = -diff;
    int ok = diff <= 1e-3f;
    TEST_ASSERT(ok);

    blt_arena_destroy(arena);
    return ok;
}

// Fill every gradient tensor with a deterministic pattern. Gradient tensors are
// arena-backed and are not guaranteed to be zeroed, so leaving them untouched
// would make this test read whatever the allocator handed back.
static void fill_grads_det(float *t, const blt_param_info *info, void *ctx) {
    uint64_t *s = (uint64_t *)ctx;
    for (size_t i = 0; i < info->numel; i++) {
        *s += 0x9E3779B97F4A7C15ULL;
        const uint32_t r = (uint32_t)(*s >> 40);
        t[i] = ((float)(r % 2001) - 1000.0f) / 500.0f; // [-2, 2)
    }
}

// Round-trip the AdamW moments and the bias-correction counter through disk.
// This is what lets a run be extended without the optimizer restarting cold.
static int test_adamw_state_roundtrip(void) {
    blt_arena *model_arena = blt_arena_create(64 * 1024 * 1024, BLT_BACKEND_CPU);
    blt_arena *opt_arena = blt_arena_create(64 * 1024 * 1024, BLT_BACKEND_CPU);
    if (!model_arena || !opt_arena) return 0;

    blt_model_config cfg;
    blt_model_config_defaults(&cfg, 16, 32, 1, 1, 1, 64, 0);
    blt_model *model = blt_model_create(model_arena, &cfg);
    blt_model_grad *grad = blt_model_grad_create(model_arena, model);

    adamw_state *s = adamw_state_create(opt_arena, model);
    if (!s || s->n == 0) return 0;

    uint64_t rng = 0xC0FFEEULL;
    blt_model_visit_params(model, grad, fill_grads_det, &rng, 1);

    blt_adamw_config acfg = {
        .lr = 0.01f, .beta1 = 0.9f, .beta2 = 0.999f, .eps = 1e-8f, .weight_decay = 0.01f, .step = 0};
    for (int k = 0; k < 3; k++) adamw_all(model, grad, s, &acfg);
    if (s->step != 3) return 0;

    // Keep a copy of every moment to compare against after the round trip. em and
    // esq are separate buffers, so each needs its own cursor.
    size_t n_em = 0, n_esq = 0;
    for (size_t i = 0; i < s->n; i++) {
        n_em += s->flat[i].em.numel;
        n_esq += s->flat[i].esq.numel;
    }
    float *em_copy = (float *)malloc(n_em * sizeof(float));
    float *esq_copy = (float *)malloc(n_esq * sizeof(float));
    if (!em_copy || !esq_copy) return 0;
    size_t ke = 0, ks = 0;
    for (size_t i = 0; i < s->n; i++) {
        memcpy(em_copy + ke, s->flat[i].em.data, s->flat[i].em.numel * sizeof(float));
        ke += s->flat[i].em.numel;
        memcpy(esq_copy + ks, s->flat[i].esq.data, s->flat[i].esq.numel * sizeof(float));
        ks += s->flat[i].esq.numel;
    }

    // The moments must be non-trivial, otherwise an all-zero file would pass.
    int nonzero = 0;
    for (size_t i = 0; i < n_em; i++) {
        if (em_copy[i] != 0.0f) {
            nonzero = 1;
            break;
        }
    }
    if (!nonzero) return 0;

    adamw_state_save(s, 4242, "optim_roundtrip.fbop");

    // Scramble the live state so a no-op load cannot pass.
    for (size_t i = 0; i < s->n; i++) {
        memset(s->flat[i].em.data, 0, s->flat[i].em.numel * sizeof(float));
        memset(s->flat[i].esq.data, 0, s->flat[i].esq.numel * sizeof(float));
    }
    s->step = 0;

    size_t got_step = 0;
    adamw_state_load(s, &got_step, "optim_roundtrip.fbop");
    remove("optim_roundtrip.fbop");

    int ok = 1;
    ok &= (s->step == 3);
    ok &= (got_step == 4242);

    ke = 0;
    ks = 0;
    double worst = 0.0;
    for (size_t i = 0; i < s->n; i++) {
        const float *em = (const float *)s->flat[i].em.data;
        const float *esq = (const float *)s->flat[i].esq.data;
        for (size_t e = 0; e < s->flat[i].em.numel; e++) {
            const double d1 = fabs((double)em[e] - (double)em_copy[ke + e]);
            if (d1 > worst) worst = d1;
        }
        ke += s->flat[i].em.numel;
        for (size_t e = 0; e < s->flat[i].esq.numel; e++) {
            const double d2 = fabs((double)esq[e] - (double)esq_copy[ks + e]);
            if (d2 > worst) worst = d2;
        }
        ks += s->flat[i].esq.numel;
    }
    ok &= (worst == 0.0);
    printf("    adamw roundtrip: pairs=%zu step=%zu global_step=%zu worst moment delta=%.3e\n", s->n, s->step, got_step,
           worst);

    free(em_copy);
    free(esq_copy);
    blt_arena_destroy(opt_arena);
    blt_arena_destroy(model_arena);
    return ok;
}

int run_optim_backend_tests(void) {
    int ok = 1;
    ok &= test_sgd_step_known_value();
    ok &= test_sgd_step_zero_grad();
    ok &= test_sgd_step_loop();
    ok &= test_adamw_state_roundtrip();
    return ok;
}