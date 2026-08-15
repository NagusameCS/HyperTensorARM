
/*
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::.................:::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::.............................::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::......................................:::::::::::::::::::::::::::
 * ::::::::::::::::::::::::......................*%:....................::::::::::::::::::::::::
 * ::::::::::::::::::::::.......................+@@@-......................::::::::::::::::::::::
 * ::::::::::::::::::::........................+@@@@@:.......................:::::::::::::::::::
 * ::::::::::::::::::.........................=@@@@@@@:........................:::::::::::::::::
 * ::::::::::::::::..........................:@@@@@@@@@-........................:::::::::::::::
 * :::::::::::::::..........................-@@@@@@@@@@@=.........................:::::::::::::
 * :::::::::::::...........................=@@@@@@@@@@@@@-.........................::::::::::::::
 * ::::::::::::...........................-@@@@@@@@@@@@@@@..........................:::::::::::
 * :::::::::::............................:%@@@@@@@@@@@@@+...........................:::::::::
 * ::::::::::..............................=@@@@@@@@@@@@%:............................:::::::::
 * ::::::::::...............................*@@@@@@@@@@@=..............................::::::::
 * :::::::::................................:@@@@@@@@@@%:...............................::::::
 * ::::::::..................................*@@@@@@@@@-................................::::::::
 * ::::::::..................:@@+:...........:@@@@@@@@@.............:+-..................:::::::
 * :::::::...................*@@@@@@*-:.......%@@@@@@@+........:-*@@@@@..................:::::::
 * :::::::..................:@@@@@@@@@@@%:....*@@@@@@@:....:=%@@@@@@@@@=.................:::::::
 * :::::::..................*@@@@@@@@@@@@#....=@@@@@@@....:*@@@@@@@@@@@#..................::::::
 * :::::::.................:@@@@@@@@@@@@@@-...=@@@@@@@....*@@@@@@@@@@@@@:.................::::::
 * :::::::.................*@@@@@@@@@@@@@@@:..=@@@@@@#...+@@@@@@@@@@@@@@=.................::::::
 * :::::::................:@@@@@@@@@@@@@@@@*..=@@@@@@#..+@@@@@@@@@@@@@@@+.................::::::
 * :::::::................=@@@@@@@@@@@@@@@@@-.#@@@@@@@.-@@@@@@@@@@@@@@@@*................:::::::
 * :::::::...............:#@@@@@@@@@@@@@@@@@*.@@@@@@@@:@@@@@@@@@@@@@@@@@%:...............:::::::
 * ::::::::..............:*@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@%:...............:::::::
 * ::::::::................:*@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@-...............::::::::
 * :::::::::.................:=#@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@%-.................::::::::
 * ::::::::::....................:#@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@=...................::::::::::
 * ::::::::::.......................:*@@@@@@@@@@@@@@@@@@@@@@@@@#-.....................:::::::::
 * :::::::::::.........................:=@@@@@@@@@@@@@@@@@@*:........................:::::::::::
 * ::::::::::::......................:=%@@@@@@@@@@@@@@@@@@@@#:......................::::::::::::
 * :::::::::::::.............+#%@@@@@@@@@@@@@@%-::*-.:%@@@@@@@@%=:.................::::::::::::::
 * :::::::::::::::...........:#@@@@@@@@@@@#--+%@@@@@@@#=:=%@@@@@@@@@@-............::::::::::::::::
 * ::::::::::::::::............-@@@@@@+-=#@@@@@@@@@@@@@@@@#=-=#@@@@*:............::::::::::::::::
 * ::::::::::::::::::...........:==:...-@@@@@@@@@@@@@@@@@@@@:...:=-............:::::::::::::::::
 * :::::::::::::::::::...................@@@@@@@@@@@@@@@@@-..................::::::::::::::::::::
 * ::::::::::::::::::::::................:#@@@@@@@@@@@@@*:.................::::::::::::::::::::::
 * ::::::::::::::::::::::::...............:*@@%+-.:=#@%-................::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::.............:........................:::::::::::::::::::::::::::
 * :::::::::::::::::::::::::::::::...............................:::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::.....................:::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 * ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
 */

/* =============================================================================
 * Transformer Inference Engine with KV-Cache
 *
 * Autoregressive decoding with incremental KV-cache.
 *
 * Components:
 *   - KV-cache: O(1) per-token attention
 *   - RMSNorm
 *   - SwiGLU feed-forward network
 *   - Causal masking
 *   - SSE2-vectorized operations
 * =============================================================================*/

#include "runtime/nn/transformer.h"
#include "kernel/mm/tensor_mm.h"

/* SSE2 vector type (4 floats, 16-byte aligned) */
typedef float v4f __attribute__((vector_size(16)));

/* Fast sqrt — ARM64 uses fsqrt, x86 uses sqrtss */
static inline float tf_sqrtf(float x)
{
    float result;
#if defined(__aarch64__)
    __asm__("fsqrt %s0, %s1" : "=w"(result) : "w"(x));
#else
    __asm__("sqrtss %1, %0" : "=x"(result) : "x"(x));
#endif
    return result;
}

/*  */
/*  KV-Cache Management                                                       */
/*  */

void kv_cache_init(kv_cache_t *cache, int max_seq, int head_dim,
                   int num_heads, int num_layers)
{
    cache->len = 0;
    cache->max_seq  = max_seq;
    cache->head_dim = head_dim;
    cache->num_heads  = num_heads;
    cache->num_layers = num_layers;

    uint64_t total = (uint64_t)num_layers * num_heads * max_seq * head_dim;
    cache->k_cache = (float *)tensor_alloc(total * sizeof(float));
    cache->v_cache = (float *)tensor_alloc(total * sizeof(float));
    if (cache->k_cache) {
        for (uint64_t i = 0; i < total; i++) cache->k_cache[i] = 0.0f;
    }
    if (cache->v_cache) {
        for (uint64_t i = 0; i < total; i++) cache->v_cache[i] = 0.0f;
    }
}

void kv_cache_destroy(kv_cache_t *cache)
{
    if (!cache) return;
    if (cache->k_cache) { tensor_free(cache->k_cache); cache->k_cache = (float *)0; }
    if (cache->v_cache) { tensor_free(cache->v_cache); cache->v_cache = (float *)0; }
    cache->len = 0;
}

void kv_cache_reset(kv_cache_t *cache)
{
    cache->len = 0;
}

/* Get pointer to K-cache for a specific layer and head at position pos */
static float *kv_k_at(kv_cache_t *cache, int layer, int head, int pos)
{
    if (pos < 0 || pos >= cache->max_seq) return NULL;
    int stride = cache->max_seq * cache->head_dim;
    int offset = (layer * cache->num_heads + head) * stride + pos * cache->head_dim;
    return cache->k_cache + offset;
}

/* Get pointer to V-cache for a specific layer and head at position pos */
static float *kv_v_at(kv_cache_t *cache, int layer, int head, int pos)
{
    if (pos < 0 || pos >= cache->max_seq) return NULL;
    int stride = cache->max_seq * cache->head_dim;
    int offset = (layer * cache->num_heads + head) * stride + pos * cache->head_dim;
    return cache->v_cache + offset;
}

/*  */
/*  RMSNorm — Root Mean Square Layer Normalization                            */
/*  Used by LLaMA, PaLM, Gemma. Faster than LayerNorm (no mean subtraction). */
/*  */

void tf_rmsnorm(float *out, const float *x, const float *w, int dim)
{
    /* Compute 1/rms = 1/sqrt(mean(x^2) + eps) */
    float ss = 0.0f;
    for (int i = 0; i < dim; i++)
        ss += x[i] * x[i];
    ss = ss / (float)dim + 1e-5f;

    /* Fast inverse square root */
    float inv_rms = 1.0f / tf_sqrtf(ss);

    /* Normalize and scale */
    int i = 0;
    for (; i + 4 <= dim; i += 4) {
        v4f vx = *(const v4f *)(x + i);
        v4f vw = *(const v4f *)(w + i);
        v4f vs = { inv_rms, inv_rms, inv_rms, inv_rms };
        *(v4f *)(out + i) = vx * vs * vw;
    }
    for (; i < dim; i++)
        out[i] = x[i] * inv_rms * w[i];
}

/*  */
/*  SwiGLU Feed-Forward Network                                                */
/*  FFN(x) = W2 · (SiLU(W1 · x) ⊙ (W3 · x))                                */
/*  Used by LLaMA, PaLM, Mixtral. Better than ReLU FFN.                       */
/*  */

void tf_swiglu_ffn(float *out, const float *x,
                   const float *w1, const float *w2, const float *w3,
                   int dim, int ff_dim)
{
    /* Scratch space for intermediate FFN results */
    static float gate[TF_MAX_DIM * 4] __attribute__((aligned(16)));
    static float up[TF_MAX_DIM * 4]   __attribute__((aligned(16)));

    /* gate = W1 · x  [ff_dim] */
    for (int i = 0; i < ff_dim; i++) {
        float sum = 0.0f;
        const float *row = w1 + i * dim;
        int j = 0;
        for (; j + 4 <= dim; j += 4) {
            v4f vr = *(const v4f *)(row + j);
            v4f vx = *(const v4f *)(x + j);
            v4f prod = vr * vx;
            union { v4f v; float f[4]; } u = { .v = prod };
            sum += u.f[0] + u.f[1] + u.f[2] + u.f[3];
        }
        for (; j < dim; j++)
            sum += row[j] * x[j];
        gate[i] = sum;
    }

    /* up = W3 · x  [ff_dim] */
    for (int i = 0; i < ff_dim; i++) {
        float sum = 0.0f;
        const float *row = w3 + i * dim;
        int j = 0;
        for (; j + 4 <= dim; j += 4) {
            v4f vr = *(const v4f *)(row + j);
            v4f vx = *(const v4f *)(x + j);
            v4f prod = vr * vx;
            union { v4f v; float f[4]; } u = { .v = prod };
            sum += u.f[0] + u.f[1] + u.f[2] + u.f[3];
        }
        for (; j < dim; j++)
            sum += row[j] * x[j];
        up[i] = sum;
    }

    /* SwiGLU: hidden = SiLU(gate) * up */
    tensor_cpu_silu(gate, gate, ff_dim);
    tensor_cpu_mul(gate, gate, up, ff_dim);

    /* out = W2 · hidden  [dim] */
    for (int i = 0; i < dim; i++) {
        float sum = 0.0f;
        const float *row = w2 + i * ff_dim;
        int j = 0;
        for (; j + 4 <= ff_dim; j += 4) {
            v4f vr = *(const v4f *)(row + j);
            v4f vg = *(const v4f *)(gate + j);
            v4f prod = vr * vg;
            union { v4f v; float f[4]; } u = { .v = prod };
            sum += u.f[0] + u.f[1] + u.f[2] + u.f[3];
        }
        for (; j < ff_dim; j++)
            sum += row[j] * gate[j];
        out[i] = sum;
    }
}

/*  */
/*  Cached Self-Attention (Single Token Decode)                                */
/*                                                                             */
/*  The KEY innovation: for position `pos`, we only compute Q/K/V for the      */
/*  NEW token, append K/V to the cache, and compute attention against ALL       */
/*  cached K/V. This is O(pos * head_dim) instead of O(pos^2 * head_dim).      */
/*  */

void tf_cached_attention(float *out, const float *q, const float *k,
                         const float *v, kv_cache_t *cache,
                         int layer, int head, int pos)
{
    int d = cache->head_dim;
    int seq_so_far = pos + 1; /* number of tokens to attend over */

    /* Step 1: Append new K and V to cache */
    float *k_slot = kv_k_at(cache, layer, head, pos);
    float *v_slot = kv_v_at(cache, layer, head, pos);
    if (!k_slot || !v_slot) return; /* pos out of range */
    for (int i = 0; i < d; i++) {
        k_slot[i] = k[i];
        v_slot[i] = v[i];
    }

    /* Step 2: Compute attention scores: score[j] = q · K_cached[j] / sqrt(d) */
    static float scores[TF_MAX_SEQ] __attribute__((aligned(16)));
    float scale = 1.0f / tf_sqrtf((float)d);

    for (int j = 0; j < seq_so_far; j++) {
        const float *kj = kv_k_at(cache, layer, head, j);
        float dot = 0.0f;
        int i = 0;
        for (; i + 4 <= d; i += 4) {
            v4f vq = *(const v4f *)(q + i);
            v4f vk = *(const v4f *)(kj + i);
            v4f prod = vq * vk;
            union { v4f vv; float f[4]; } u = { .vv = prod };
            dot += u.f[0] + u.f[1] + u.f[2] + u.f[3];
        }
        for (; i < d; i++)
            dot += q[i] * kj[i];
        scores[j] = dot * scale;
    }

    /* Causal masking is implicit — we only attend to positions 0..pos */

    /* Step 3: Softmax over scores[0..pos] */
    tensor_cpu_softmax(scores, scores, seq_so_far);

    /* Step 4: Weighted sum of V: out = sum_j(scores[j] * V_cached[j]) */
    for (int i = 0; i < d; i++)
        out[i] = 0.0f;

    for (int j = 0; j < seq_so_far; j++) {
        const float *vj = kv_v_at(cache, layer, head, j);
        float s = scores[j];
        int i = 0;
        v4f vs = { s, s, s, s };
        for (; i + 4 <= d; i += 4)
            *(v4f *)(out + i) += vs * *(const v4f *)(vj + i);
        for (; i < d; i++)
            out[i] += s * vj[i];
    }
}

/*  */
/*  Full Transformer Forward (Single Token)                                    */
/*  Processes one token through all layers, updating KV-cache.                 */
/*  This is the inner loop of autoregressive generation.                       */
/*  */

void tf_forward_token(tf_model_t *model, float *logits,
                      const float *tok_embed, int pos)
{
    int dim = model->dim;
    int num_heads = model->num_heads;
    int head_dim = model->head_dim;

    /* Working buffers */
    static float x[TF_MAX_DIM]      __attribute__((aligned(16)));
    static float xn[TF_MAX_DIM]     __attribute__((aligned(16)));
    static float q[TF_MAX_DIM]      __attribute__((aligned(16)));
    static float k[TF_MAX_DIM]      __attribute__((aligned(16)));
    static float v[TF_MAX_DIM]      __attribute__((aligned(16)));
    static float attn_out[TF_MAX_DIM] __attribute__((aligned(16)));
    static float ffn_out[TF_MAX_DIM]  __attribute__((aligned(16)));
    static float head_buf[TF_MAX_DIM] __attribute__((aligned(16)));

    /* Start with token embedding */
    for (int i = 0; i < dim; i++)
        x[i] = tok_embed[i];

    /* Process each transformer layer */
    for (int L = 0; L < model->num_layers; L++) {
        tf_block_weights_t *blk = &model->layers[L];

        /* === Self-Attention === */
        /* 1. RMSNorm */
        tf_rmsnorm(xn, x, blk->rms_att, dim);

        /* 2. Compute Q, K, V projections: Q = Wq·xn, K = Wk·xn, V = Wv·xn */
        for (int i = 0; i < dim; i++) {
            float sq = 0, sk = 0, sv = 0;
            for (int j = 0; j < dim; j++) {
                float xj = xn[j];
                sq += blk->wq[i * dim + j] * xj;
                sk += blk->wk[i * dim + j] * xj;
                sv += blk->wv[i * dim + j] * xj;
            }
            q[i] = sq;
            k[i] = sk;
            v[i] = sv;
        }

        /* 3. Multi-head attention with KV-cache */
        for (int i = 0; i < dim; i++)
            attn_out[i] = 0.0f;

        for (int h = 0; h < num_heads; h++) {
            float *qh = q + h * head_dim;
            float *kh = k + h * head_dim;
            float *vh = v + h * head_dim;

            tf_cached_attention(head_buf, qh, kh, vh,
                                &model->cache, L, h, pos);

            /* Concatenate head outputs */
            for (int i = 0; i < head_dim; i++)
                attn_out[h * head_dim + i] = head_buf[i];
        }

        /* 4. Output projection: attn = Wo · attn_out */
        for (int i = 0; i < dim; i++) {
            float sum = 0.0f;
            const float *row = blk->wo + i * dim;
            int j = 0;
            for (; j + 4 <= dim; j += 4) {
                v4f vr = *(const v4f *)(row + j);
                v4f va = *(const v4f *)(attn_out + j);
                v4f prod = vr * va;
                union { v4f vv; float f[4]; } u = { .vv = prod };
                sum += u.f[0] + u.f[1] + u.f[2] + u.f[3];
            }
            for (; j < dim; j++)
                sum += row[j] * attn_out[j];
            head_buf[i] = sum;
        }

        /* 5. Residual connection */
        for (int i = 0; i < dim; i++)
            x[i] += head_buf[i];

        /* === Feed-Forward Network (SwiGLU) === */
        /* 6. RMSNorm */
        tf_rmsnorm(xn, x, blk->rms_ffn, dim);

        /* 7. SwiGLU FFN + residual */
        tf_swiglu_ffn(ffn_out, xn, blk->w1, blk->w2, blk->w3,
                      dim, model->ff_dim);
        for (int i = 0; i < dim; i++)
            x[i] += ffn_out[i];
    }

    /* Final RMSNorm */
    tf_rmsnorm(xn, x, model->rms_final, dim);

    /* Logits = embedding^T · xn (weight-tied output) */
    for (int v = 0; v < model->vocab_size; v++) {
        float sum = 0.0f;
        const float *row = model->tok_embed + v * dim;
        int j = 0;
        for (; j + 4 <= dim; j += 4) {
            v4f vr = *(const v4f *)(row + j);
            v4f vx = *(const v4f *)(xn + j);
            v4f prod = vr * vx;
            union { v4f vv; float f[4]; } u = { .vv = prod };
            sum += u.f[0] + u.f[1] + u.f[2] + u.f[3];
        }
        for (; j < dim; j++)
            sum += row[j] * xn[j];
        logits[v] = sum;
    }
}

/*  */
/*  Demo: Transformer Inference with KV-Cache                                  */
/*  */

/* Pseudo-random deterministic weights for demo */
static float demo_tok_embed[32 * 64]  __attribute__((aligned(16)));  /* 32 tokens, dim=64 */
static float demo_rms_final[64]       __attribute__((aligned(16)));

/* Per-layer weights (small demo model: 2 layers, dim=64, 4 heads, ff=128) */
static float demo_wq[2][64 * 64]  __attribute__((aligned(16)));
static float demo_wk[2][64 * 64]  __attribute__((aligned(16)));
static float demo_wv[2][64 * 64]  __attribute__((aligned(16)));
static float demo_wo[2][64 * 64]  __attribute__((aligned(16)));
static float demo_w1[2][64 * 128] __attribute__((aligned(16)));
static float demo_w2[2][128 * 64] __attribute__((aligned(16)));
static float demo_w3[2][64 * 128] __attribute__((aligned(16)));
static float demo_rms_att[2][64]  __attribute__((aligned(16)));
static float demo_rms_ffn[2][64]  __attribute__((aligned(16)));
static tf_block_weights_t demo_block_weights[2];

static void init_demo_weights(void)
{
    /* Initialize embeddings */
    for (int i = 0; i < 32 * 64; i++)
        demo_tok_embed[i] = ((float)((i * 7 + 3) % 97) - 48.0f) * 0.02f;
    for (int i = 0; i < 64; i++)
        demo_rms_final[i] = 1.0f; /* Start with identity scaling */

    /* Initialize per-layer weights */
    for (int L = 0; L < 2; L++) {
        int seed = L * 10000;
        for (int i = 0; i < 64 * 64; i++) {
            demo_wq[L][i] = ((float)(((seed + i) * 13 + 7) % 89) - 44.0f) * 0.01f;
            demo_wk[L][i] = ((float)(((seed + i) * 11 + 3) % 83) - 41.0f) * 0.01f;
            demo_wv[L][i] = ((float)(((seed + i) * 17 + 11) % 79) - 39.0f) * 0.01f;
            demo_wo[L][i] = ((float)(((seed + i) * 19 + 5) % 97) - 48.0f) * 0.01f;
        }
        for (int i = 0; i < 64 * 128; i++) {
            demo_w1[L][i] = ((float)(((seed + i) * 23 + 13) % 71) - 35.0f) * 0.01f;
            demo_w3[L][i] = ((float)(((seed + i) * 29 + 17) % 67) - 33.0f) * 0.01f;
        }
        for (int i = 0; i < 128 * 64; i++)
            demo_w2[L][i] = ((float)(((seed + i) * 31 + 19) % 73) - 36.0f) * 0.01f;
        for (int i = 0; i < 64; i++) {
            demo_rms_att[L][i] = 1.0f;
            demo_rms_ffn[L][i] = 1.0f;
        }

        demo_block_weights[L].wq = demo_wq[L];
        demo_block_weights[L].wk = demo_wk[L];
        demo_block_weights[L].wv = demo_wv[L];
        demo_block_weights[L].wo = demo_wo[L];
        demo_block_weights[L].w1 = demo_w1[L];
        demo_block_weights[L].w2 = demo_w2[L];
        demo_block_weights[L].w3 = demo_w3[L];
        demo_block_weights[L].rms_att = demo_rms_att[L];
        demo_block_weights[L].rms_ffn = demo_rms_ffn[L];
    }
}

void tf_run_demos(void)
{
    kprintf("\n============================================================\n");
    kprintf("  TRANSFORMER ENGINE WITH KV-CACHE\n");
    kprintf("  Transformer Engine with KV-Cache\n");
    kprintf("============================================================\n");

    init_demo_weights();

    /* Build demo model: 2-layer transformer, dim=64, 4 heads, ff=128, vocab=32 */
    tf_model_t model;
    model.dim = 64;
    model.num_heads = 4;
    model.head_dim = 16;
    model.ff_dim = 128;
    model.num_layers = 2;
    model.vocab_size = 32;
    model.max_seq = 128;
    model.layers = demo_block_weights;
    model.tok_embed = demo_tok_embed;
    model.rms_final = demo_rms_final;

    /* Initialize KV-cache */
    kv_cache_init(&model.cache, model.max_seq, model.head_dim,
                  model.num_heads, model.num_layers);

    kprintf("  Architecture: %d-layer transformer, dim=%d, %d heads\n",
            model.num_layers, model.dim, model.num_heads);
    kprintf("  FFN: SwiGLU (dim=%d->%d->%d)\n", model.dim, model.ff_dim, model.dim);
    kprintf("  Norm: RMSNorm (LLaMA-style)\n");
    kprintf("  KV-Cache: %d max tokens, %d bytes/token\n",
            model.max_seq,
            model.num_heads * model.head_dim * 2 * model.num_layers * (int)sizeof(float));
    kprintf("  Vocab: %d tokens, total params: ~%d\n", model.vocab_size,
            model.num_layers * (4 * model.dim * model.dim +  /* QKV+O */
                                3 * model.dim * model.ff_dim + /* FFN */
                                2 * model.dim) +               /* norms */
            model.vocab_size * model.dim);

    /* === Demo 1: Autoregressive token generation === */
    kprintf("\n  --- Autoregressive Generation (8 tokens) ---\n");
    kv_cache_reset(&model.cache);

    float logits[32] __attribute__((aligned(16)));
    int tokens[8];
    tokens[0] = 1; /* Start token */

    kprintf("  Generating: [1]");
    for (int t = 0; t < 8; t++) {
        /* Get embedding for current token */
        float *embed = demo_tok_embed + tokens[t] * model.dim;

        /* Forward through transformer */
        tf_forward_token(&model, logits, embed, t);

        /* Greedy decode: pick argmax */
        int next = tensor_cpu_argmax(logits, model.vocab_size);
        if (t < 7) tokens[t + 1] = next;
        kprintf(" %d", next);
    }
    kprintf("\n  KV-cache: %d tokens cached\n", 8);

    /* === Demo 2: KV-Cache speedup benchmark === */
    kprintf("\n  --- KV-Cache Speedup Benchmark ---\n");

    int bench_len = 32; /* generate 32 tokens */
    int iters = 100;

    /* Without KV-cache: full recompute at each step */
    uint64_t t0 = rdtsc_fenced();
    for (int r = 0; r < iters; r++) {
        kv_cache_reset(&model.cache);
        for (int t = 0; t < bench_len; t++) {
            float *embed = demo_tok_embed + (t % model.vocab_size) * model.dim;
            tf_forward_token(&model, logits, embed, t);
        }
    }
    uint64_t t1 = rdtsc_fenced();
    uint64_t cached_us = perf_cycles_to_us(t1 - t0);

    /* Without KV-cache: recompute all tokens from scratch each step.
     * We simulate this by resetting cache and reprocessing all prior tokens. */
    uint64_t t2 = rdtsc_fenced();
    for (int r = 0; r < iters; r++) {
        for (int t = 0; t < bench_len; t++) {
            /* Reprocess all tokens 0..t from scratch */
            kv_cache_reset(&model.cache);
            for (int s = 0; s <= t; s++) {
                float *embed = demo_tok_embed + (s % model.vocab_size) * model.dim;
                tf_forward_token(&model, logits, embed, s);
            }
        }
    }
    uint64_t t3 = rdtsc_fenced();
    uint64_t nocache_us = perf_cycles_to_us(t3 - t2);

    uint64_t per_token_cached = cached_us / (iters * bench_len);
    uint64_t per_token_nocache = nocache_us / (iters * bench_len);

    kprintf("  Sequence length: %d tokens, %d iterations\n", bench_len, iters);
    kprintf("  With KV-cache:    %lu us/token\n", per_token_cached);
    kprintf("  Without KV-cache: %lu us/token (full recompute)\n", per_token_nocache);
    if (per_token_cached > 0) {
        uint64_t sp10 = (per_token_nocache * 10) / per_token_cached;
        kprintf("  KV-cache speedup: %lu.%lux\n", sp10 / 10, sp10 % 10);
    }

    /* === Demo 3: Throughput at various sequence lengths === */
    kprintf("\n  --- Throughput vs Sequence Length ---\n");

    int lengths[] = { 4, 8, 16, 32, 64 };
    for (int li = 0; li < 5; li++) {
        int slen = lengths[li];
        kv_cache_reset(&model.cache);

        uint64_t st0 = rdtsc_fenced();
        int gen_iters = 500 / slen; /* adjust iterations for longer sequences */
        if (gen_iters < 10) gen_iters = 10;
        for (int r = 0; r < gen_iters; r++) {
            kv_cache_reset(&model.cache);
            for (int t = 0; t < slen; t++) {
                float *embed = demo_tok_embed + (t % model.vocab_size) * model.dim;
                tf_forward_token(&model, logits, embed, t);
            }
        }
        uint64_t st1 = rdtsc_fenced();
        uint64_t total_tokens = (uint64_t)gen_iters * slen;
        uint64_t total_us = perf_cycles_to_us(st1 - st0);
        uint64_t tok_per_sec = (total_us > 0) ? (total_tokens * 1000000ULL / total_us) : 0;
        uint64_t us_per_tok = (total_tokens > 0) ? (total_us / total_tokens) : 0;
        kprintf("  seq=%d: %lu tok/s, %lu us/tok\n", slen, tok_per_sec, us_per_tok);
    }

    /* === Demo 4: RMSNorm benchmark === */
    kprintf("\n  --- Component Benchmarks ---\n");
    {
        float x[64] __attribute__((aligned(16)));
        float w[64] __attribute__((aligned(16)));
        float out[64] __attribute__((aligned(16)));
        for (int i = 0; i < 64; i++) { x[i] = (float)i * 0.1f; w[i] = 1.0f; }

        uint64_t rt0 = rdtsc_fenced();
        for (int r = 0; r < 10000; r++)
            tf_rmsnorm(out, x, w, 64);
        uint64_t rt1 = rdtsc_fenced();
        kprintf("  RMSNorm dim=64: %lu ns\n", perf_cycles_to_ns(rt1 - rt0) / 10000);
    }

    /* SwiGLU benchmark */
    {
        static float x[64] __attribute__((aligned(16)));
        static float out[64] __attribute__((aligned(16)));
        for (int i = 0; i < 64; i++) x[i] = (float)i * 0.05f;

        uint64_t ft0 = rdtsc_fenced();
        for (int r = 0; r < 1000; r++)
            tf_swiglu_ffn(out, x, demo_w1[0], demo_w2[0], demo_w3[0], 64, 128);
        uint64_t ft1 = rdtsc_fenced();
        /* FLOPs: 2 matmuls (64*128 each) + 1 matmul (128*64) + SiLU + mul = ~49K */
        uint64_t ffn_flops = (2ULL * 64 * 128 * 2 + 2ULL * 128 * 64) * 1000;
        uint64_t ffn_us = perf_cycles_to_us(ft1 - ft0);
        uint64_t ffn_mflops = (ffn_us > 0) ? (ffn_flops / ffn_us) : 0;
        kprintf("  SwiGLU FFN 64->128->64: %lu us/1000, %lu MFLOPS\n",
                ffn_us, ffn_mflops);
    }

    kprintf("\n============================================================\n");
    kprintf("  Transformer: KV-cache, RMSNorm, SwiGLU, Multi-Head Attn\n");
    kprintf("  Architecture: GPT/LLaMA-class, running bare-metal.\n");
    kprintf("============================================================\n");
}
