/* fishomni -- Fish Audio drama-3 (FishOmniModel): speech from text, 44.1 kHz mono.
 *
 * ============================== THE MODEL ==============================
 *
 * Three networks (fish-speech's fish_speech/models/text2semantic/fish_omni/, Fish Audio's own
 * reference, and its S2 codec):
 *
 *   Backbone: the language model of Qwen3.5-35B-A3B, unchanged -- 40 layers of 2048, three gated
 *   delta-net layers to one gated attention layer (16 query heads over 2 KV heads of 256, NeoX
 *   rotary on 64 dims at theta 1e7), a routed feed-forward in every layer (256 experts of 512, 8 a
 *   token, and a gated shared expert of 512), (1 + w) norms. Only the routed experts are fp8
 *   (`quant_method: bsgemm-moe`, E4M3 with an f32 scale a 128 x 128 block); everything else is
 *   bf16. A prompt row is a token; an audio row is one frame of the codec's ten codes, embedded as
 *   (E_lm[248099 + c0] + E_cb[4096 + c1]) / sqrt 2: the first code through its semantic token,
 *   the second through section 1 of the codebook table.
 *
 *   Tower: 13 MTP-style layers that write a frame's codes 1..9 from the backbone's hidden state:
 *   four "shared" layers that inject code 0, then nine "per-codebook" layers, layer k injecting
 *   code k - 1 and its head drawing code k. Each layer is m = eh_proj([enorm(e); hnorm(h)]), one
 *   pre-norm block (gated attention with (1 + w) q/k norms and GPT-J rotary on 64 dims at 1e7, a
 *   SwiGLU of 6144), and a final norm. The attention is causal across time, over a cache of its
 *   own at the backbone's positions: the layers are bound as layers 40..52 of the backbone's
 *   full-attention KV group. The first shared layer also adds the summed embeddings of the input
 *   frame's codes 2..9, the ones the backbone never saw.
 *
 *   Codec: Fish S2's modified DAC decoder: ten codebooks of dimension 8 (one of 4096, nine of
 *   1024), each projected to 1024 and summed; an 8-layer transformer (16 heads of 64, a causal
 *   window of 128 frames); two 2x upsamplings with ConvNeXt blocks; four transposed convolutions
 *   (8, 8, 4, 2) with snake residual units; 2048 samples a frame.
 *
 * ============================== THE PASSES ==============================
 *
 * The core's audio generator in its chunked form, one branch a request (no guidance):
 *
 *   PROMPT  the backbone over the whole prompt; the last row's hidden state into the lane; the
 *           tower teacher-forced over every row. A prompt is text, so every row's label is text
 *           and every layer's code embedding is zero; the tower still runs, because its attention
 *           reads those rows' keys and values from every later frame. The last row's tower pass is
 *           the first frame's, and FRAME 0 overwrites it.
 *   FRAME   frame j of every lane in flight. The main token is drawn from the hidden state of the
 *           row before the frame's (the prompt's last row for frame 0) over 4097 candidates (the
 *           end of speech and the 4096 semantic tokens), with Fish's repetition-aware choice
 *           between two draws; then the tower at that row's position draws codes 1..9; then the
 *           frame goes into the lane's history and the backbone runs over its embedding at the
 *           frame's own row.
 *   VOCODE  a few kept frames of one lane through the codec, re-decoding the frames its outputs
 *           reach back to (every layer is causal), so no state is carried between chunks.
 *
 * ============================== TENSOR PARALLEL ==============================
 *
 * Two ranks. The backbone splits as Qwen3.6-35B-A3B does (heads, delta-net heads, expert width).
 * The tower splits by heads and feed-forward width, an all-reduce after each output projection.
 * The candidate head, the code tables, the nine heads, the samplers and the codec are
 * replicated: every rank draws the same codes from the same logits and seeds, and plays the same
 * samples.
 */
#include <arch/rad_arch.h>
#include <arch/rad_block_attn_gated_fp8.h>
#include <arch/rad_block_gdn_fp8.h>
#include <arch/rad_block_moe_fp8.h>

#include <algorithm>
#include <cmath>
#include <cstdio>
#include <cstring>
#include <string>
#include <vector>

namespace fishomni {

using namespace rad::arch;

/* ================================================================== the model's constants */
constexpr int64_t kMaxLanes = 4;
/* The longest prompt and speech. fish-speech's default request is 2048 frames (95 s); a plain
 * prompt is a few dozen rows a sentence. */
constexpr int64_t kMaxPrompt = 2048, kMaxFrames = 2048;
/* A frame: ten codes, code 0 of 4096 (the semantic band), codes 1..9 drawn from heads of 4096 and
 * read by the codec through 1024-entry codebooks. */
constexpr int64_t kCodes = 10, kVocab = 4096, kResVocab = 1024;
/* Token ids: the end of speech (<|im_end|>) and the semantic band <|semantic:0..4095|>. The main
 * token is drawn over those 4097, in id order, so candidate 0 is the end and candidate c + 1 is
 * semantic code c. */
constexpr int64_t kEos = 248046, kSemBegin = 248099, kSemEnd = 252194, kCand = kVocab + 1;
/* The tower: four shared layers, then one a codebook after the first. */
constexpr int kShared = 4, kTower = kShared + (int)kCodes - 1;
/* fish-speech's server and SDK defaults (sampling.py), the technical report's evaluation
 * settings: temperature 0.7, top-p 0.7, top-k 30, for the main token and every head alike. */
constexpr int64_t kTopK = 30;
static const double kTemp = 0.7, kTopP = 0.7;
/* The repetition-aware redraw, fixed by the training recipe (tower.py): when the first draw is
 * semantic and among the last 16 main tokens, a second draw at temperature 1, top-p 0.95,
 * top-k 30 is taken instead. */
constexpr int64_t kRasWin = 16, kRasTopK = 30;
static const double kRasTemp = 1.0, kRasTopP = 0.95;

/* The codec: 2048 samples a frame at 44.1 kHz. A chunk is at most kVocChunk frames; its outputs
 * reach back about nine frames through the convolutions after the transformer (kConvCtx, rounded
 * up), whose rows reach back kAttnWin - 1 frames. The dequantiser is per frame. */
constexpr int64_t kSamplesPerFrame = 2048, kSampleRate = 44100;
constexpr int64_t kVocChunk = 16, kConvCtx = 12, kAttnWin = 128;
constexpr int64_t kVocContext = (kAttnWin - 1) + kConvCtx;
constexpr int64_t kConvFrames = kConvCtx + kVocChunk;
constexpr int64_t kCbDim = 8, kLat = 1024, kDec = 1536;
/* The codec transformer: 8 layers of 1024, 16 heads of 64, a SwiGLU of 3072. */
constexpr int64_t kCtLayers = 8, kCtHeads = 16, kCtHeadDim = 64, kCtFf = 3072;
static const double kCtTheta = 10000.0, kCtEps = 1e-5;
/* The codec's sequence rates, rows a frame: the transformer's frames, the convolutions' frames,
 * the two upsamplings', and each decoder block's output (8, 8, 4, 2 times). */
constexpr int kRates = 8;
static const int64_t kRate[kRates] = { 1, 1, 2, 4, 32, 256, 1024, 2048 };

/* The prompt (reference-bracket-v1, the plain form: generate.py's build_drama3_prompt with no
 * references). Every literal there is tokenised on its own; at these seams the joined text
 * tokenises the same, since each one falls at a special token or a newline. The input gets its
 * speaker tag in text_prepare. */
static const char* kPlain =
    "<|im_start|>system\nconvert the provided text to speech<|im_end|>\n"
    "<|im_start|>user\n{input}<|im_end|>\n<|im_start|>assistant\n<|voice|>";

/* Weight groups (movement units): the backbone's layers are 0..39 (the blocks' own), the tower's
 * 40..52 like their KV layers, then the frame's tables and the codec. */
enum : int { kGrpTower = 40, kGrpFrame = 53, kGrpCodec = 100 };

/* ================================================================== the networks */
struct Layer {
    int          full = 0;
    AttnGatedFP8 attn;
    GdnFP8       gdn;
    MoeFP8       mlp;
};

/* A tower layer (tower.py's TowerLayer): the code embedding and the two norms into eh_proj, the
 * gated attention block over the paged cache, the SwiGLU, the final norm; a per-codebook layer's
 * head and its draw. q, gate, k and v are four projections of the checkpoint's [Q | G | K | V]
 * rows (paged attention reads a contiguous query, and the gate is not interleaved per head as the
 * backbone's is). */
struct TowerLayer {
    rad_weight w_emb = 0, w_en = 0, w_hn = 0, w_eh = 0, w_an = 0;
    rad_weight w_q = 0, w_g = 0, w_k = 0, w_v = 0, w_qn = 0, w_kn = 0, w_o = 0;
    rad_weight w_fn = 0, w_gu = 0, w_down = 0, w_fin = 0, w_head = 0;
    rad_op op_emb = 0, op_eadd = 0, op_en = 0, op_hn = 0, op_eh = 0, op_an = 0;
    rad_op op_q = 0, op_g = 0, op_k = 0, op_v = 0, op_qn = 0, op_kn = 0, op_rq = 0, op_rk = 0;
    rad_op op_attn = 0, op_kv = 0, op_sig = 0, op_mul = 0, op_o = 0, op_ar1 = 0, op_add1 = 0;
    rad_op op_fn = 0, op_gu = 0, op_act = 0, op_down = 0, op_ar2 = 0, op_add2 = 0, op_fin = 0;
    rad_op op_head = 0, op_samp = 0;
};

/* The codec transformer's layer: fused q|k|v with rotary at the frames' positions, causal
 * attention over a 128-frame window, layer scales on both residual branches. */
struct CodecLayer {
    rad_weight w_n1 = 0, w_n2 = 0, w_qkv = 0, w_o = 0, w_gu = 0, w_down = 0, w_ls1 = 0, w_ls2 = 0;
    rad_op     op_n1 = 0, op_qkv = 0, op_rope = 0, op_attn = 0, op_o = 0, op_ls1 = 0, op_add1 = 0;
    rad_op     op_n2 = 0, op_gu = 0, op_act = 0, op_down = 0, op_ls2 = 0, op_add2 = 0;
};

/* A 2x upsampling and its ConvNeXt block. */
struct Upsample {
    rad_weight w_t = 0, b_t = 0, w_dw = 0, b_dw = 0, w_ln = 0, b_ln = 0, w_p1 = 0, b_p1 = 0;
    rad_weight w_p2 = 0, b_p2 = 0, w_g = 0;
    rad_op     op_t = 0, op_dw = 0, op_ln = 0, op_p1 = 0, op_gelu = 0, op_p2 = 0, op_g = 0;
    rad_op     op_add = 0;
};

/* A causal weight-normalised conv with its bias. */
struct VConv {
    rad_weight w = 0, b = 0;
    rad_op     op = 0;
};
struct VRes {
    rad_weight a1 = 0, a2 = 0;
    rad_op     op_s1 = 0, op_s2 = 0;
    VConv      c1{}, c2{};
};
struct VBlock {
    rad_weight a = 0, wt = 0, bt = 0;
    rad_op     op_s = 0, op_t = 0;
    VRes       res[3];
};

struct Model {
    Names nm{""};
    Geom  g{};                      /* the backbone's */
    Geom  gt{};                     /* the tower's */
    GdnFP8::Config gcfg{};
    MoeFP8::Config moecfg{};
    int64_t n_rot = 0, n_rot_t = 0, n_main = 0, lanes = 0;
    rad_kvgroup kv_full = 0, kv_state = 0, kv_conv = 0;

    /* ---- the backbone: the residual stream, its normed copy, and the blocks' working set */
    rad_buf b_x = 0;
    ActFP8  a_h{};
    rad_buf b_qg = 0, b_k = 0, b_v = 0, b_q = 0, b_rope_cs = 0;
    ActFP8  a_attn{};
    ActFP8  a_in{}, a_go{};
    rad_buf b_ab = 0, b_gq = 0, b_gk = 0, b_gv = 0, b_gdec = 0, b_beta = 0, b_kkt = 0;
    rad_buf b_rlogits = 0, b_eids = 0, b_ew = 0, b_sorted = 0, b_eoff = 0, b_ecnt = 0;
    rad_buf b_egu = 0, b_edn = 0, b_emoe = 0;
    ActFP8  a_eff{};
    rad_buf b_sgu = 0, b_sout = 0, b_sgate = 0;
    ActFP8  a_sff{};
    rad_weight w_tok = 0, w_out_norm = 0;
    rad_op  op_embed = 0, op_embed_ar = 0, op_final_norm = 0, op_rope_cs = 0;
    std::vector<Layer> layers;

    /* ---- a lane's state (PERSIST) */
    rad_buf b_hid = 0;            /* [lanes, 2048] the last row's final-norm hidden state */
    rad_buf b_status = 0;         /* [lanes] i32 */
    rad_buf b_hist = 0;           /* [lanes * 10, kMaxFrames] i32: each lane's codes, codebook rows */
    rad_buf b_ras = 0;            /* [lanes, 16] i32: the last 16 main picks (candidate indices) */
    rad_buf b_u = 0;              /* [lanes, 2048] the last frame's codes 2..9, embedded and summed */

    /* ---- the frame */
    rad_weight w_cand = 0;        /* [4097, 2048] the lm_head's candidate rows */
    rad_weight w_cemb = 0;        /* [4097, 2048] the embedding's candidate rows */
    rad_weight w_cb = 0;          /* [9 * 4096, 2048] codebook table sections 1..9 */
    rad_buf b_plane = 0, b_slog = 0, b_first = 0, b_alt = 0, b_codes = 0, b_ug = 0, b_unew = 0;
    rad_buf b_last = 0, b_hlog = 0;
    rad_op  op_hsel = 0, op_head = 0, op_samp = 0, op_samp_ras = 0, op_ras = 0, op_status = 0;
    rad_op  op_ugather = 0, op_plast = 0, op_pstore = 0, op_uzero = 0, op_rasinit = 0;
    rad_op  op_efill = 0, op_store = 0, op_u = 0, op_uscat = 0, op_fb = 0, op_fstore = 0;

    /* ---- the tower */
    TowerLayer tw[kTower];
    rad_buf b_te = 0, b_tcat = 0, b_tm = 0, b_th = 0, b_tq = 0, b_tg = 0, b_tk = 0, b_tv = 0;
    rad_buf b_tattn = 0, b_to = 0, b_tgu = 0, b_tff = 0, b_tho = 0;

    /* ---- the codec (VOCODE) */
    rad_weight w_cbk[kCodes] = {};
    rad_op  op_rq[kCodes] = {};
    VConv   qo[kCodes];
    std::vector<CodecLayer> ct;
    rad_weight w_cn = 0;
    rad_op  op_cn = 0, op_cnst = 0, op_ccu[kRates] = {}, op_fcast = 0;
    Upsample up[2];
    VConv   dec0{};
    VBlock  vb[4];
    int64_t v_ups[4] = { 8, 8, 4, 2 };
    rad_weight w_fa = 0;
    rad_op  op_fs = 0;
    VConv   fin{};
    rad_buf b_rq = 0, b_cx = 0, b_ch = 0, b_cqkv = 0, b_cattn = 0, b_co = 0, b_cgu = 0, b_cff = 0;
    rad_buf b_cconst = 0, b_ccu[kRates] = {};
    rad_buf b_ux[3] = {}, b_ua = 0, b_ub = 0, b_uh = 0, b_ug2 = 0;
    rad_buf b_vs[5] = {}, b_vt[5] = {}, b_va[5] = {}, b_vb[5] = {};
    rad_buf b_vout = 0, b_audio = 0;
};

static Model g_model[MAX_RANKS];

/* ================================================================== declare helpers */
static rad_op norm_op(RadBuilder* b, int64_t rows, int64_t n, double eps, double wadd,
                      rad_weight w, std::initializer_list<rad_buf> x, rad_buf y) {
    return rw(b, RAD_OP(b, "rmsnorm",
                        RAD_PARAMS(RAD_RANGE("M", 1, rows), RAD_INT("n", n), RAD_F64("eps", eps),
                                   RAD_F64("wadd", wadd), RAD_STR("dtype", "bf16")),
                        RAD_WEIGHTS(w)),
              x, { y });
}

static rad_op add_op(RadBuilder* b, int64_t rows, int64_t n, rad_buf a, rad_buf c, rad_buf y) {
    return rw(b, RAD_OP(b, "add",
                        RAD_PARAMS(RAD_RANGE("M", 1, rows), RAD_INT("n", n),
                                   RAD_STR("dtype", "bf16")),
                        RAD_NOWEIGHTS),
              { a, c }, { y });
}

static rad_op gemm_op(RadBuilder* b, int64_t rows, int64_t N, int64_t K, rad_weight w, rad_buf x,
                      rad_buf y) {
    return rw(b, RAD_OP(b, "gemm_nt",
                        RAD_PARAMS(RAD_RANGE("M", 1, rows), RAD_INT("N", N), RAD_INT("K", K),
                                   RAD_STR("dtype", "bf16")),
                        RAD_WEIGHTS(w)),
              { x }, { y });
}

static rad_op gemm_bias_op(RadBuilder* b, int64_t rows, int64_t N, int64_t K, rad_weight w,
                           rad_weight bias, rad_buf x, rad_buf y) {
    return rw(b, RAD_OP(b, "gemm_nt_bias",
                        RAD_PARAMS(RAD_RANGE("M", 1, rows), RAD_INT("N", N), RAD_INT("K", K),
                                   RAD_STR("dtype", "bf16")),
                        RAD_WEIGHTS(w, bias)),
              { x }, { y });
}

static rad_op rows_op(RadBuilder* b, const char* op, int64_t rows, int64_t n,
                      std::initializer_list<rad_buf> in, std::initializer_list<rad_buf> out) {
    return rw(b, RAD_OP(b, op,
                        RAD_PARAMS(RAD_RANGE("M", 1, rows), RAD_INT("n", n),
                                   RAD_STR("dtype", "bf16")),
                        RAD_NOWEIGHTS),
              in, out);
}

static rad_op mulw_op(RadBuilder* b, int64_t rows, int64_t n, rad_weight w, rad_buf x, rad_buf y) {
    return rw(b, RAD_OP(b, "mul_weight",
                        RAD_PARAMS(RAD_RANGE("M", 1, rows), RAD_INT("n", n),
                                   RAD_STR("dtype", "bf16")),
                        RAD_WEIGHTS(w)),
              { x }, { y });
}

static rad_op iota_op(RadBuilder* b, int64_t rows, int64_t start, int64_t step, rad_buf y) {
    return rw(b, RAD_OP(b, "iota",
                        RAD_PARAMS(RAD_RANGE("M", 1, rows), RAD_INT("start", start),
                                   RAD_INT("step", step)),
                        RAD_NOWEIGHTS),
              {}, { y });
}

static rad_op cu_op(RadBuilder* b, int64_t mult, rad_buf len, rad_buf y) {
    return rw(b, RAD_OP(b, "cu_repeat",
                        RAD_PARAMS(RAD_RANGE("M", 1, 2), RAD_INT("mult", mult)),
                        RAD_NOWEIGHTS),
              { len }, { y });
}

static rad_op ar_op(RadBuilder* b, const Geom& g, rad_buf x) {
    if (g.world <= 1) return 0;
    return rw(b, RAD_OP(b, "all_reduce",
                        RAD_PARAMS(RAD_INT("world_size", g.world),
                                   RAD_RANGE("numel", g.n_embd, g.max_tok * g.n_embd),
                                   RAD_STR("dtype", g.dtype), RAD_INT("exact", g.wire_exact),
                                   RAD_INT("min_bytes", g.wire_min_bytes)),
                        RAD_NOWEIGHTS),
              { x }, { x });
}

/* A frame draw: `k` largest, Fish's nucleus over the whole candidate set first (rad OPS.md,
 * cfg_topk_sample's top_p), one row a lane, no guidance. */
static rad_op draw_op(RadBuilder* b, int64_t lanes, int64_t n, int64_t k, double temp,
                      double top_p, int stream, rad_buf logits, rad_buf ids) {
    return rw(b, RAD_OP(b, "cfg_topk_sample",
                        RAD_PARAMS(RAD_RANGE("M", 1, lanes), RAD_INT("n_vocab", n),
                                   RAD_INT("k", k), RAD_INT("rep", 1), RAD_F64("cfg", 1.0),
                                   RAD_F64("temp", temp), RAD_INT("stream", stream),
                                   RAD_STR("dtype", "f32"), RAD_F64("top_p", top_p)),
                        RAD_NOWEIGHTS),
              { logits }, { ids });
}

/* A plain weight copied from the checkpoint, declared at `dtype`, replicated. */
static rad_weight wcopy(RadBuilder* b, const char* dn, const char* src, uint32_t dtype,
                        std::initializer_list<int64_t> shape, int group) {
    if (map_copy(b, dn, src) < 0) return 0;
    return decl_w(b, dn, dtype, shape, RAD_ACCESS_PER_TOKEN, RAD_SHARD_NONE, grp_layer(group));
}

/* ================================================================== check_format */
/* The container's statement of what it is. Every mismatch below would still make sound -- a
 * different template, another codebook layout, an fp8 format read as this one -- so each is a
 * refusal by name rather than a silent default. */
static int check_format(const RadModelMeta* meta) {
    const char* method = rad_meta_gets(meta, "quantization_config.quant_method", nullptr);
    const char* block  = rad_meta_gets(meta, "quantization_config.weight_block_size", nullptr);
    if (!method || std::strcmp(method, "bsgemm-moe") != 0) {
        fprintf(stderr, "radiance: fishomni serves Fish Audio's released drama-3, whose routed "
                        "experts are block-scaled fp8 (quant_method 'bsgemm-moe'); this container "
                        "says '%s'\n", method ? method : "(none)");
        return RAD_E_UNSUPPORTED;
    }
    if (block) {
        long long b0 = 0, b1 = 0;
        if (std::sscanf(block, "%lld %lld", &b0, &b1) != 2) { b0 = 0; b1 = 0; }
        if (b0 != RAD_FP8_BLOCK || b1 != RAD_FP8_BLOCK) {
            fprintf(stderr, "radiance: fishomni refuses weight_block_size [%lld, %lld]: libr4d's "
                            "block-scaled GEMMs are compiled at %d in both dimensions\n",
                    b0, b1, RAD_FP8_BLOCK);
            return RAD_E_UNSUPPORTED;
        }
    }
    const char* tv = rad_meta_gets(meta, "speech_template_version", "");
    if (std::strcmp(tv, "reference-bracket-v1") != 0) {
        fprintf(stderr, "radiance: fishomni builds the reference-bracket-v1 prompt and this "
                        "checkpoint asks for '%s'\n", tv);
        return RAD_E_UNSUPPORTED;
    }
    const char* ad = "audio_decoder_config";
    char k[96];
    auto ai = [&](const char* key, long long dflt) {
        std::snprintf(k, sizeof k, "%s.%s", ad, key);
        return rad_meta_geti(meta, k, dflt);
    };
    auto as = [&](const char* key) {
        std::snprintf(k, sizeof k, "%s.%s", ad, key);
        return rad_meta_gets(meta, k, "");
    };
    if (rad_meta_geti(meta, "semantic_start_token_id", 0) != kSemBegin ||
        rad_meta_geti(meta, "semantic_end_token_id", 0) != kSemEnd ||
        rad_meta_geti(meta, "eos_token_id", 0) != kEos ||
        std::strcmp(as("decoder_type"), "codebook_mtp_shared") != 0 ||
        ai("num_codebooks", 0) != kCodes || ai("vocab_size", 0) != kVocab ||
        ai("vq_backbone_codebooks", 0) != 1 || ai("shared_enrichment_layers", 0) != kShared ||
        std::strcmp(as("vq_feature_placement"), "backbone_partial") != 0 ||
        std::strcmp(as("vq_feature_scope"), "all_vq") != 0) {
        fprintf(stderr, "radiance: fishomni: not the released drama-3 layout (semantic tokens "
                        "%lld..%lld, end %lld, a codebook_mtp_shared tower of %d shared layers "
                        "over %lld codebooks of %lld, one codebook into the backbone)\n",
                (long long)kSemBegin, (long long)kSemEnd, (long long)kEos, kShared,
                (long long)kCodes, (long long)kVocab);
        return RAD_E_UNSUPPORTED;
    }
    return RAD_OK;
}

/* ================================================================== the backbone */
/* qwen35moe_fp8's trunk, written out (arch/qwen35_fp8/qwen35_fp8.cpp, QWEN35_MOE): the same
 * blocks, metadata and names, without its drafters, vision tower and int8 build. Its bf16 linears
 * (attention, delta net, shared expert) are served by LinearFP8's plain branch beside the fp8
 * experts. */
static int declare_trunk(RadBuilder* b, const RadModelMeta* meta, const RadBuildCtx* ctx,
                         Model& m) {
    Geom& g = m.g;
    Names& nm = m.nm;
    if (meta->n_expert <= 0) {
        fprintf(stderr, "radiance: fishomni: the backbone declares no experts; drama-3's is "
                        "routed\n");
        return RAD_E_UNSUPPORTED;
    }
    bool have_interval = false;
    const int64_t interval = meta_int2(meta, "qwen35.full_attention_interval",
                                       "full_attention_interval", 4, &have_interval);
    if (interval <= 0) return RAD_E_INVAL;
    RAD_ARCH_TRY(check_layer_schedule("fishomni", meta_text_gets(meta, "layer_types", nullptr),
                                      g.n_layer, interval, {"full_attention"}));
    m.n_main = g.n_layer;

    /* GemmaRMSNorm everywhere but the delta net's output norm (rad_block_gdn_fp8.h). */
    g.wadd    = 1.0f;
    g.wadd_qk = 1.0f;

    double prf = rad_meta_getf(meta, "partial_rotary_factor", 0.0);
    if (!(prf > 0.0)) prf = rad_meta_getf(meta, "rope_parameters.partial_rotary_factor", 0.0);
    m.n_rot = prf > 0.0 ? (int64_t)(g.head_dim * prf) : 0;
    if (m.n_rot <= 0 || m.n_rot > g.head_dim || (m.n_rot & 1)) {
        fprintf(stderr, "radiance: fishomni: no usable rotary width (head_dim %lld)\n",
                (long long)g.head_dim);
        return RAD_E_INVAL;
    }
    RAD_ARCH_TRY(yarn_from(g, meta, "", m.n_rot));

    GdnFP8::Config& gc = m.gcfg;
    const int64_t n_head_k_all = meta_int2(meta, "qwen35.ssm.group_count",
                                           "linear_num_key_heads", 0);
    const int64_t n_head_v_all = meta_int2(meta, "qwen35.ssm.time_step_rank",
                                           "linear_num_value_heads", 0);
    gc.head_k     = meta_int2(meta, "qwen35.ssm.state_size", "linear_key_head_dim", 0);
    gc.head_v     = meta_int2(meta, "qwen35.ssm.value_head_dim", "linear_value_head_dim", 0);
    gc.conv_width = meta_int2(meta, "qwen35.ssm.conv_kernel", "linear_conv_kernel_dim", 0);
    if (n_head_k_all <= 0 || n_head_v_all <= 0 || gc.head_k <= 0 || gc.head_v <= 0 ||
        gc.conv_width <= 0) {
        fprintf(stderr, "radiance: fishomni: the container does not describe the delta-net "
                        "layers\n");
        return RAD_E_INVAL;
    }
    gc.chunk = 64;
    RAD_ARCH_TRY(divide_or_fail(n_head_k_all, g.world, "linear_num_key_heads", &gc.n_head_k));
    RAD_ARCH_TRY(divide_or_fail(n_head_v_all, g.world, "linear_num_value_heads", &gc.n_head_v));

    const int64_t q_dim = g.q_dim(), kv_dim = g.kv_dim();
    const int64_t v_dim = gc.v_dim(), conv_dim = gc.conv_dim();

    /* ---- the KV groups. The full-attention group also holds the tower's 13 layers, bound below
     * at 40..52 (declare_tower). */
    RadKVGroupDecl fd{};
    fd.kind      = RAD_KV_FULL;
    fd.dtype     = rad_kv_cache_dtype(ctx, RAD_BF16);
    fd.n_head_kv = g.n_head_kv;
    fd.head_dim  = g.head_dim;
    m.kv_full = rad_decl_kv_group(b, nm.f("kv_attn"), &fd);
    g.kv_dtype = rad_dtype_name(fd.dtype);

    RadKVGroupDecl sd{};
    sd.kind         = RAD_KV_LINEAR;
    sd.dtype        = RAD_F32;
    sd.n_head_kv    = gc.n_head_v;
    sd.state_dim[0] = gc.head_v;
    sd.state_dim[1] = gc.head_k;
    m.kv_state = rad_decl_kv_group(b, nm.f("kv_gdn_state"), &sd);

    RadKVGroupDecl cd{};
    cd.kind       = RAD_KV_CONV;
    cd.dtype      = RAD_BF16;
    cd.n_head_kv  = 2 * gc.n_head_k + gc.n_head_v;
    cd.head_dim   = gc.head_k;
    cd.conv_width = gc.conv_width;
    m.kv_conv = rad_decl_kv_group(b, nm.f("kv_gdn_conv"), &cd);
    if (!m.kv_full || !m.kv_state || !m.kv_conv) return RAD_E_INVAL;

    /* ---- activations (qwen35_fp8.cpp says what each is) */
    m.b_x       = decl_b(b, nm.f("x"),        g.act_dtype, {g.max_tok, g.n_embd});
    m.a_h.x     = decl_b(b, nm.f("h"),        g.act_dtype, {g.max_tok, g.n_embd});
    RAD_ARCH_TRY(m.a_h.declare_qs(b, nm, g, "h", g.n_embd));
    m.b_qg      = decl_b(b, nm.f("attn_qg"),  g.act_dtype, {g.max_tok, g.n_head, 2 * g.head_dim});
    m.b_k       = decl_b(b, nm.f("attn_k"),   g.act_dtype, {g.max_tok, kv_dim});
    m.b_v       = decl_b(b, nm.f("attn_v"),   g.act_dtype, {g.max_tok, kv_dim});
    m.b_q       = decl_b(b, nm.f("attn_q"),   g.act_dtype, {g.max_tok, q_dim});
    m.a_attn.x  = decl_b(b, nm.f("attn_out"), g.act_dtype, {g.max_tok, q_dim});
    m.b_rope_cs = decl_b(b, nm.f("rope_cs"), RAD_F32, {rope_table_rows(g), m.n_rot},
                         RAD_BUF_PERSIST);
    RAD_ARCH_TRY(m.a_attn.declare_qs(b, nm, g, "attn_out", q_dim));
    m.a_in.x    = decl_b(b, nm.f("gdn_in"),   g.act_dtype, {g.max_tok, conv_dim + v_dim});
    RAD_ARCH_TRY(m.a_in.declare_qs(b, nm, g, "gdn_in", conv_dim + v_dim));
    m.b_ab      = decl_b(b, nm.f("gdn_ab"),   g.act_dtype, {g.max_tok, gc.ab_dim()});
    m.b_gq      = decl_b(b, nm.f("gdn_q"),    g.act_dtype, {g.max_tok, gc.n_head_k, gc.head_k});
    m.b_gk      = decl_b(b, nm.f("gdn_k"),    g.act_dtype, {g.max_tok, gc.n_head_k, gc.head_k});
    m.b_gv      = decl_b(b, nm.f("gdn_v"),    g.act_dtype, {g.max_tok, gc.n_head_v, gc.head_v});
    m.b_gdec    = decl_b(b, nm.f("gdn_g"),    RAD_F32,     {g.max_tok, gc.n_head_v});
    m.b_beta    = decl_b(b, nm.f("gdn_beta"), RAD_F32,     {g.max_tok, gc.n_head_v});
    m.b_kkt     = decl_b(b, nm.f("gdn_kkt"),  RAD_BF16,    {g.max_tok, gc.n_head_v, gc.chunk});
    m.a_go.x    = decl_b(b, nm.f("gdn_o"),    g.act_dtype, {g.max_tok, gc.n_head_v, gc.head_v});
    RAD_ARCH_TRY(m.a_go.declare_qs(b, nm, g, "gdn_o", v_dim));

    /* ---- the routing geometry; `n_ff` is already the per-rank expert width */
    {
        MoeFP8::Config& mc = m.moecfg;
        mc.n_expert = meta->n_expert;
        mc.top_k    = meta->n_expert_used > 0 ? meta->n_expert_used
                                              : meta_int2(meta, "qwen35.expert_used_count",
                                                          "num_experts_per_tok", 0);
        mc.n_ff_exp = g.n_ff;
        mc.norm_topk = (int)meta_int2(meta, "qwen35.expert_weights_norm", "norm_topk_prob", 1);
        const int64_t sh_all = meta_int2(meta, "qwen35.expert_shared_feed_forward_length",
                                         "shared_expert_intermediate_size", 0);
        if (sh_all > 0)
            RAD_ARCH_TRY(divide_or_fail(sh_all, g.world, "shared_expert_intermediate_size",
                                        &mc.n_ff_shared));
        const int64_t moe_rows = 2048;
        mc.rows = g.max_tok < moe_rows ? g.max_tok : moe_rows;
        if (mc.top_k <= 0 || mc.top_k > mc.n_expert) {
            fprintf(stderr, "radiance: fishomni: top_k %lld is not in [1, %lld]\n",
                    (long long)mc.top_k, (long long)mc.n_expert);
            return RAD_E_INVAL;
        }
        const int64_t R = g.max_tok, K = mc.rows * mc.top_k;
        m.b_rlogits = decl_b(b, nm.f("moe_logits"), g.act_dtype, {R, mc.n_expert});
        m.b_eids    = decl_b(b, nm.f("moe_ids"),    RAD_I32,     {R, mc.top_k});
        m.b_ew      = decl_b(b, nm.f("moe_w"),      g.act_dtype, {R, mc.top_k});
        m.b_sorted  = decl_b(b, nm.f("moe_sorted"), RAD_I32,     {K});
        m.b_eoff    = decl_b(b, nm.f("moe_off"),    RAD_I32,     {mc.n_expert + 1});
        m.b_ecnt    = decl_b(b, nm.f("moe_cnt"),    RAD_I32,     {mc.n_expert}, RAD_BUF_PERSIST);
        m.b_egu     = decl_b(b, nm.f("moe_gate_up"), g.act_dtype, {K, 2 * mc.n_ff_exp});
        m.a_eff.x   = decl_b(b, nm.f("moe_ffn"),    g.act_dtype, {K, mc.n_ff_exp});
        m.a_eff.q   = decl_b(b, nm.f("moe_ffn.q"),  RAD_F8E4M3,  {K, mc.n_ff_exp});
        m.a_eff.s   = decl_b(b, nm.f("moe_ffn.s"),  RAD_F32,     {K, fp8_blocks(mc.n_ff_exp)});
        m.b_edn     = decl_b(b, nm.f("moe_down"),   g.act_dtype, {K, g.n_embd});
        if (mc.n_ff_shared > 0) {
            m.b_emoe  = decl_b(b, nm.f("moe_out"),   g.act_dtype, {R, g.n_embd});
            m.b_sgu   = decl_b(b, nm.f("shexp_gate_up"), g.act_dtype, {R, 2 * mc.n_ff_shared});
            m.a_sff.x = decl_b(b, nm.f("shexp_ffn"),     g.act_dtype, {R, mc.n_ff_shared});
            m.a_sff.q = decl_b(b, nm.f("shexp_ffn.q"),   RAD_F8E4M3,  {R, mc.n_ff_shared});
            m.a_sff.s = decl_b(b, nm.f("shexp_ffn.s"),   RAD_F32, {R, fp8_blocks(mc.n_ff_shared)});
            m.b_sout  = decl_b(b, nm.f("shexp_out"),     g.act_dtype, {R, g.n_embd});
            m.b_sgate = decl_b(b, nm.f("shexp_gate"),    g.act_dtype, {R, 1});
        }
    }

    /* ---- the vocabulary edge. The embedding is row-sharded with the vocabulary and summed by the
     * all-reduce below; there is no lm_head here, only its 4097 candidate rows (declare_frame). */
    RAD_ARCH_TRY(map_copy(b, nm.f("token_embd.weight"),
                          nm.ckpt("model.language_model.embed_tokens.weight")));
    RAD_ARCH_TRY(map_copy(b, nm.f("output_norm.weight"),
                          nm.ckpt("model.language_model.norm.weight")));
    m.w_tok = decl_w(b, nm.f("token_embd.weight"), RAD_BF16, {g.n_vocab, g.n_embd},
                     RAD_ACCESS_VOCAB, RAD_SHARD_ROW, grp_model());
    m.w_out_norm = decl_w(b, nm.f("output_norm.weight"), RAD_F32, {g.n_embd},
                          RAD_ACCESS_PER_TOKEN, RAD_SHARD_NONE, grp_model());
    m.op_embed = rw(b, RAD_OP(b, "embed_lookup",
                        RAD_PARAMS(RAD_RANGE("M", 1, g.max_tok), RAD_INT("n_embd", g.n_embd),
                                   RAD_INT("n_vocab", g.n_vocab), RAD_STR("dtype", g.dtype),
                                   RAD_INT("vocab_offset", g.vocab_off)),
                        RAD_WEIGHTS(m.w_tok)),
                    {}, {m.b_x});
    /* Always issued by PROMPT, never folded into layer 0's norm: a frame's embedding is the same
     * on every rank (replicated tables), and a reduction there would sum it world times. Exact:
     * it sums disjoint rows. */
    if (g.world > 1)
        m.op_embed_ar = rw(b, RAD_OP(b, "all_reduce",
                               RAD_PARAMS(RAD_INT("world_size", g.world),
                                          RAD_RANGE("numel", g.n_embd, g.max_tok * g.n_embd),
                                          RAD_STR("dtype", g.dtype), RAD_INT("exact", 1)),
                               RAD_NOWEIGHTS),
                           {m.b_x}, {m.b_x});
    m.op_rope_cs = rw(b, decl_rotary(b, g, "rope_table",
                         RAD_PARAMS(RAD_RANGE("M", 1, qk_fuse_rows(g)), RAD_INT("rot", m.n_rot),
                                    RAD_F64("theta", g.theta), RAD_F64("scale", g.rope_scale),
                                    RAD_STR("dtype", "f32")),
                         RAD_NOWEIGHTS),
                     {}, {m.b_rope_cs});

    AttnGatedFP8::Wire aw{};
    aw.x = m.b_x; aw.h = m.a_h; aw.qg = m.b_qg; aw.k = m.b_k; aw.v = m.b_v;
    aw.q = m.b_q; aw.attn = m.a_attn;
    aw.cos_sin = m.op_rope_cs ? m.b_rope_cs : 0;

    GdnFP8::Wire gw{};
    gw.x = m.b_x; gw.h = m.a_h; gw.in = m.a_in; gw.ab = m.b_ab;
    gw.q = m.b_gq; gw.k = m.b_gk; gw.v = m.b_gv;
    gw.gdec = m.b_gdec; gw.beta = m.b_beta; gw.kkt = m.b_kkt; gw.o = m.a_go;

    MoeFP8::Wire mw{};
    mw.x = m.b_x; mw.h = m.a_h;
    mw.logits = m.b_rlogits; mw.ids = m.b_eids; mw.ew = m.b_ew;
    mw.sorted = m.b_sorted;  mw.eoff = m.b_eoff; mw.ecnt = m.b_ecnt;
    mw.egu = m.b_egu; mw.eff = m.a_eff; mw.edn = m.b_edn; mw.moe = m.b_emoe;
    mw.sgu = m.b_sgu; mw.sff = m.a_sff; mw.sout = m.b_sout; mw.sgate = m.b_sgate;

    m.layers.resize((size_t)m.n_main);
    for (int64_t l = 0; l < m.n_main; ++l) {
        Layer& lay = m.layers[(size_t)l];
        lay.full = is_full_attention(l, interval) ? 1 : 0;
        /* embed_ar false: layer 0's norm takes no reduction (see op_embed_ar). */
        const LayerFold f = layer_fold(g, l, m.n_main, nullptr, 0, false);
        const char* pre = "model.language_model.layers";
        if (lay.full) {
            AttnGatedFP8::Src as{};
            as.norm   = nm.ckpt("%s.%lld.input_layernorm.weight",  pre, (long long)l);
            as.qg     = nm.ckpt("%s.%lld.self_attn.q_proj.weight", pre, (long long)l);
            as.k      = nm.ckpt("%s.%lld.self_attn.k_proj.weight", pre, (long long)l);
            as.v      = nm.ckpt("%s.%lld.self_attn.v_proj.weight", pre, (long long)l);
            as.q_norm = nm.ckpt("%s.%lld.self_attn.q_norm.weight", pre, (long long)l);
            as.k_norm = nm.ckpt("%s.%lld.self_attn.k_norm.weight", pre, (long long)l);
            as.o      = nm.ckpt("%s.%lld.self_attn.o_proj.weight", pre, (long long)l);
            RAD_ARCH_TRY(rad_bind_layer_kv(b, (int)l, m.kv_full));
            RAD_ARCH_TRY(lay.attn.declare(b, nm, g, (int)l, m.kv_full, m.n_rot, aw, as,
                                          f.mix_fold, false, f.mix_ar_in, f.mix_ar_out));
        } else {
            GdnFP8::Src gs{};
            gs.norm     = nm.ckpt("%s.%lld.input_layernorm.weight",         pre, (long long)l);
            gs.in_qkv   = nm.ckpt("%s.%lld.linear_attn.in_proj_qkv.weight", pre, (long long)l);
            gs.in_a     = nm.ckpt("%s.%lld.linear_attn.in_proj_a.weight",   pre, (long long)l);
            gs.in_b     = nm.ckpt("%s.%lld.linear_attn.in_proj_b.weight",   pre, (long long)l);
            gs.in_z     = nm.ckpt("%s.%lld.linear_attn.in_proj_z.weight",   pre, (long long)l);
            gs.conv1d   = nm.ckpt("%s.%lld.linear_attn.conv1d.weight",      pre, (long long)l);
            gs.a_log    = nm.ckpt("%s.%lld.linear_attn.A_log",              pre, (long long)l);
            gs.dt_bias  = nm.ckpt("%s.%lld.linear_attn.dt_bias",            pre, (long long)l);
            gs.out_norm = nm.ckpt("%s.%lld.linear_attn.norm.weight",        pre, (long long)l);
            gs.out      = nm.ckpt("%s.%lld.linear_attn.out_proj.weight",    pre, (long long)l);
            RAD_ARCH_TRY(rad_bind_layer_kv(b, (int)l, m.kv_state));
            RAD_ARCH_TRY(rad_bind_layer_kv(b, (int)l, m.kv_conv));
            RAD_ARCH_TRY(lay.gdn.declare(b, nm, g, gc, (int)l, m.kv_state, m.kv_conv, gw, gs,
                                         f.mix_fold, false, f.mix_ar_in, f.mix_ar_out));
        }
        MoeFP8::Src ms{};
        ms.cfg     = m.moecfg;
        ms.norm    = nm.ckpt("%s.%lld.post_attention_layernorm.weight", pre, (long long)l);
        ms.router  = nm.ckpt("%s.%lld.mlp.gate.weight",                 pre, (long long)l);
        ms.experts = nm.ckpt("%s.%lld.mlp.experts",                     pre, (long long)l);
        if (m.moecfg.n_ff_shared > 0) {
            ms.shared      = nm.ckpt("%s.%lld.mlp.shared_expert",             pre, (long long)l);
            ms.shared_gate = nm.ckpt("%s.%lld.mlp.shared_expert_gate.weight", pre, (long long)l);
        }
        /* The experts' stored format, read from the layer's first: the release's scale planes are
         * f32 (fp8a8f32), not the bf16 Qwen3.6's are. */
        RAD_ARCH_TRY(MoeFP8::probe(b, nm, (int)l, ms, &ms.cfg));
        RAD_ARCH_TRY(lay.mlp.declare(b, nm, g, (int)l, mw, ms, true, f.mlp_add,
                                     f.mlp_ar_in, f.mlp_ar_out));
    }
    for (int64_t l = 0; l + 1 < m.n_main; ++l)
        m.layers[(size_t)l].mlp.xp_next = &m.layers[(size_t)l + 1].mlp;

    m.op_final_norm = norm_op(b, g.max_tok, g.n_embd, g.eps, 1.0, m.w_out_norm, {m.b_x},
                              m.a_h.x);
    if (!have_interval)
        rad_note(b, "the container did not state full_attention_interval; assuming %lld, which "
                    "makes layers 3,7,... full attention", (long long)interval);
    return m.op_embed && m.op_final_norm ? RAD_OK : RAD_E_INVAL;
}

/* ================================================================== the frame's head */
/* The lane state, the candidate head and the main token's two draws (FRAME, before the tower),
 * and what PROMPT leaves in the lane. Declared in the order a frame issues them: buffer liveness
 * follows declaration order. */
static int declare_frame_head(RadBuilder* b, Model& m) {
    Names& nm = m.nm;
    const int64_t S = m.lanes, D = m.g.n_embd, T = m.g.max_tok;
    m.b_hid    = decl_b(b, nm.f("frame.hid"), RAD_BF16, { S, D }, RAD_BUF_PERSIST);
    m.b_status = decl_b(b, nm.f("frame.status"), RAD_I32, { S }, RAD_BUF_PERSIST);
    m.b_hist   = decl_b(b, nm.f("frame.history"), RAD_I32, { S * kCodes, kMaxFrames },
                        RAD_BUF_PERSIST);
    m.b_ras    = decl_b(b, nm.f("frame.ras"), RAD_I32, { S, kRasWin }, RAD_BUF_PERSIST);
    m.b_u      = decl_b(b, nm.f("frame.unseen"), RAD_BF16, { S, D }, RAD_BUF_PERSIST);
    m.b_plane  = decl_b(b, nm.f("frame.plane"), RAD_BF16, { S, D });
    m.b_slog   = decl_b(b, nm.f("frame.slog"), RAD_F32, { S, kCand });
    m.b_first  = decl_b(b, nm.f("frame.first"), RAD_I32, { S });
    m.b_alt    = decl_b(b, nm.f("frame.alt"), RAD_I32, { S });
    m.b_codes  = decl_b(b, nm.f("frame.codes"), RAD_I32, { kCodes, S });
    m.b_ug     = decl_b(b, nm.f("frame.ug"), RAD_BF16, { S, D });
    m.b_last   = decl_b(b, nm.f("frame.last"), RAD_BF16, { S, D });

    /* The main token's candidates: the lm_head's rows for the end of speech and the semantic band,
     * in id order, replicated (the full head is vocab-sharded and 1 GB). The same rows of the
     * embedding feed a frame back to the backbone, indexed by the same candidate. */
    const char* lm = nm.ckpt("lm_head.weight");
    const char* et = nm.ckpt("model.language_model.embed_tokens.weight");
    RAD_ARCH_TRY(map_rows(b, nm.f("frame.cand.weight"),
                          { { lm, (int)kEos, 1 }, { lm, (int)kSemBegin, kVocab } }));
    m.w_cand = decl_w(b, nm.f("frame.cand.weight"), RAD_BF16, { kCand, D }, RAD_ACCESS_PER_TOKEN,
                      RAD_SHARD_NONE, grp_layer(kGrpFrame));
    RAD_ARCH_TRY(map_rows(b, nm.f("frame.cemb.weight"),
                          { { et, (int)kEos, 1 }, { et, (int)kSemBegin, kVocab } }));
    m.w_cemb = decl_w(b, nm.f("frame.cemb.weight"), RAD_BF16, { kCand, D }, RAD_ACCESS_PER_TOKEN,
                      RAD_SHARD_NONE, grp_layer(kGrpFrame));
    /* The codebook table's sections 1..9; section 0 is never read (tower.py, embedding_sum). */
    RAD_ARCH_TRY(map_rows(b, nm.f("frame.cb.weight"),
                          { { nm.ckpt("audio_decoder.codebook_embeddings.weight"), (int)kVocab,
                              (kCodes - 1) * kVocab } }));
    m.w_cb = decl_w(b, nm.f("frame.cb.weight"), RAD_BF16, { (kCodes - 1) * kVocab, D },
                    RAD_ACCESS_PER_TOKEN, RAD_SHARD_NONE, grp_layer(kGrpFrame));
    if (!m.w_cand || !m.w_cemb || !m.w_cb) return RAD_E_INVAL;

    /* ---- FRAME: the hidden states, the candidates' logits, the two draws and the choice */
    m.op_hsel = rows_op(b, "gather_rows", S, D, { m.b_hid }, { m.b_plane });
    m.op_head = rw(b, RAD_OP(b, "logits_gemm",
                             RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n_vocab", kCand),
                                        RAD_INT("n_embd", D), RAD_STR("dtype", "bf16")),
                             RAD_WEIGHTS(m.w_cand)),
                   { m.b_plane }, { m.b_slog });
    m.op_samp = draw_op(b, S, kCand, kTopK, kTemp, kTopP, 0, m.b_slog, m.b_first);
    m.op_samp_ras = draw_op(b, S, kCand, kRasTopK, kRasTemp, kRasTopP, 1, m.b_slog, m.b_alt);
    /* The redraw: only a semantic first draw (candidates 1..4096), and only one the lane's last
     * 16 picks hold; the prompt's rows are text, so its window starts empty (op_rasinit). */
    m.op_ras = rw(b, RAD_OP(b, "ras_pick",
                            RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("win", kRasWin),
                                       RAD_INT("lo", 1), RAD_INT("hi", kCand), RAD_INT("rep", 1)),
                            RAD_NOWEIGHTS),
                  { m.b_first, m.b_alt, m.b_ras }, { m.b_codes, m.b_ras });
    m.op_status = rw(b, RAD_OP(b, "end_status",
                               RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("end", 0),
                                          RAD_INT("rep", 1)),
                               RAD_NOWEIGHTS),
                     { m.b_codes }, { m.b_status });
    m.op_ugather = rows_op(b, "gather_rows", S, D, { m.b_u }, { m.b_ug });

    /* ---- PROMPT: the last row's hidden state into the lane, an empty window and no unseen codes
     * (the prompt's last row is text), and the tower's code embeddings, all zero for text labels */
    m.op_plast = rows_op(b, "gather_rows", S, D, { m.a_h.x }, { m.b_last });
    m.op_pstore = rw(b, RAD_OP(b, "scatter_rows",
                               RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n", D),
                                          RAD_STR("dtype", "bf16")),
                               RAD_NOWEIGHTS),
                     { m.b_last }, { m.b_hid });
    m.op_uzero = rw(b, RAD_OP(b, "fill",
                              RAD_PARAMS(RAD_RANGE("M", 1, 1), RAD_INT("n", D),
                                         RAD_STR("dtype", "bf16")),
                              RAD_NOWEIGHTS),
                    {}, { m.b_u });
    m.op_rasinit = iota_op(b, kRasWin, -1, 0, m.b_ras);
    m.b_tcat = decl_b(b, nm.f("tower.cat"), RAD_BF16, { T, 2 * D });
    m.op_efill = rw(b, RAD_OP(b, "fill",
                              RAD_PARAMS(RAD_RANGE("M", 1, T), RAD_INT("n", D),
                                         RAD_STR("dtype", "bf16")),
                              RAD_NOWEIGHTS),
                    {}, { m.b_tcat });
    return m.op_hsel && m.op_head && m.op_samp && m.op_samp_ras && m.op_ras && m.op_status &&
                   m.op_ugather && m.op_plast && m.op_pstore && m.op_uzero && m.op_rasinit &&
                   m.op_efill
               ? RAD_OK
               : RAD_E_INVAL;
}

/* ================================================================== the tower */
static int declare_tower(RadBuilder* b, const RadModelMeta* meta, Model& m) {
    Names& nm = m.nm;
    Geom& g = m.gt;
    g = m.g;
    const char* ad = "audio_decoder_config";
    char key[96];
    auto ai = [&](const char* k, long long d) {
        std::snprintf(key, sizeof key, "%s.%s", ad, k);
        return (int64_t)rad_meta_geti(meta, key, d);
    };
    auto af = [&](const char* k, double d) {
        std::snprintf(key, sizeof key, "%s.%s", ad, k);
        return rad_meta_getf(meta, key, d);
    };
    g.n_head_all = ai("n_head", 0);
    g.n_head_kv_all = ai("n_local_heads", 0);
    g.head_dim = ai("head_dim", 0);
    g.n_ff_all = ai("intermediate_size", 0);
    const double rot_frac = af("rotary_percent", 0.0);
    g.eps = (float)af("norm_eps", 1e-6);
    g.theta = (float)af("rope_base", 0.0);
    if (ai("dim", 0) != g.n_embd || g.n_head_all <= 0 || g.n_head_kv_all <= 0 ||
        g.head_dim <= 0 || g.n_ff_all <= 0 || !(g.theta > 0.0f) || !(rot_frac > 0.0)) {
        fprintf(stderr, "radiance: fishomni: the audio decoder config does not describe the "
                        "tower (dim %lld, %lld heads over %lld of %lld, ffn %lld)\n",
                (long long)ai("dim", 0), (long long)g.n_head_all, (long long)g.n_head_kv_all,
                (long long)g.head_dim, (long long)g.n_ff_all);
        return RAD_E_UNSUPPORTED;
    }
    RAD_ARCH_TRY(divide_or_fail(g.n_head_all, g.world, "the tower's heads", &g.n_head));
    RAD_ARCH_TRY(divide_or_fail(g.n_head_kv_all, g.world, "the tower's KV heads", &g.n_head_kv));
    RAD_ARCH_TRY(divide_or_fail(g.n_ff_all, g.world, "the tower's feed-forward", &g.n_ff));
    g.rope_scale = 1.0f;
    g.yarn = RadYarn{};
    g.rope_mc = false;
    m.n_rot_t = (int64_t)(g.head_dim * rot_frac);
    /* One KV group for the backbone's ten attention layers and these: the cache rows must match. */
    if (g.n_head_kv != m.g.n_head_kv || g.head_dim != m.g.head_dim) {
        fprintf(stderr, "radiance: fishomni: the tower's KV heads (%lld of %lld) differ from the "
                        "backbone's (%lld of %lld), and they share one cache group\n",
                (long long)g.n_head_kv, (long long)g.head_dim, (long long)m.g.n_head_kv,
                (long long)m.g.head_dim);
        return RAD_E_UNSUPPORTED;
    }

    const int64_t T = g.max_tok, S = m.lanes, D = g.n_embd, hd = g.head_dim;
    const int64_t qd = g.n_head * hd, kd = g.n_head_kv * hd, ff = g.n_ff;
    const int64_t qd_all = g.n_head_all * hd, kd_all = g.n_head_kv_all * hd;
    m.b_te    = decl_b(b, nm.f("tower.e"), RAD_BF16, { S, D });
    m.b_tm    = decl_b(b, nm.f("tower.m"), RAD_BF16, { T, D });
    m.b_th    = decl_b(b, nm.f("tower.h"), RAD_BF16, { T, D });
    m.b_tq    = decl_b(b, nm.f("tower.q"), RAD_BF16, { T, qd });
    m.b_tg    = decl_b(b, nm.f("tower.g"), RAD_BF16, { T, qd });
    m.b_tk    = decl_b(b, nm.f("tower.k"), RAD_BF16, { T, kd });
    m.b_tv    = decl_b(b, nm.f("tower.v"), RAD_BF16, { T, kd });
    m.b_tattn = decl_b(b, nm.f("tower.attn"), RAD_BF16, { T, qd });
    m.b_to    = decl_b(b, nm.f("tower.o"), RAD_BF16, { T, D });
    m.b_tgu   = decl_b(b, nm.f("tower.gu"), RAD_BF16, { T, 2 * ff });
    m.b_tff   = decl_b(b, nm.f("tower.ff"), RAD_BF16, { T, ff });
    m.b_tho   = decl_b(b, nm.f("tower.out"), RAD_BF16, { T, D });
    m.b_hlog  = decl_b(b, nm.f("tower.hlog"), RAD_F32, { S, kVocab });

    for (int i = 0; i < kTower; ++i) {
        TowerLayer& L = m.tw[i];
        const bool shared = i < kShared;
        const int k = i - kShared;                 /* the per-codebook index, -1.. for shared */
        const int grp = kGrpTower + i, kvl = (int)m.n_main + i;
        const char* pre = shared ? nm.ckpt("audio_decoder_mtp_shared.layers.%d", i)
                                 : nm.ckpt("audio_decoder_mtp.layers.%d", k);
        auto src = [&](const char* s) { return nm.ckpt("%s.%s", pre, s); };
        auto dn = [&](const char* s) { return nm.f("tower.%d.%s", i, s); };
        auto gain = [&](const char* d, const char* s, int64_t n) {
            return wcopy(b, dn(d), src(s), RAD_F32, { n }, grp);
        };

        /* The code embedding. A layer that injects code 0 reads it by candidate (row 0 the end of
         * speech, row c + 1 code c), so its table is the checkpoint's with row 0 again in front:
         * fish-speech clamps the end's c0 to 0. The others read the code a head drew. */
        const char* tsrc = src(shared ? "semantic_embedding.weight" : "codebook_embedding.weight");
        const bool by_cand = shared || k == 0;
        if (by_cand) RAD_ARCH_TRY(map_rows(b, dn("emb.weight"), { { tsrc, 0, 1 },
                                                                  { tsrc, 0, kVocab } }));
        else RAD_ARCH_TRY(map_copy(b, dn("emb.weight"), tsrc));
        L.w_emb = decl_w(b, dn("emb.weight"), RAD_BF16, { by_cand ? kCand : kVocab, D },
                         RAD_ACCESS_PER_TOKEN, RAD_SHARD_NONE, grp_layer(grp));
        L.w_en  = gain("enorm.weight", "enorm.weight", D);
        L.w_hn  = gain("hnorm.weight", "hnorm.weight", D);
        L.w_an  = gain("attn_norm.weight", "transformer_layer.attention_norm.weight", D);
        L.w_fn  = gain("ffn_norm.weight", "transformer_layer.ffn_norm.weight", D);
        L.w_fin = gain("final_norm.weight", "final_layernorm.weight", D);
        L.w_qn  = gain("q_norm.weight", "transformer_layer.attention.q_norm.weight", hd);
        L.w_kn  = gain("k_norm.weight", "transformer_layer.attention.k_norm.weight", hd);
        L.w_eh  = wcopy(b, dn("eh.weight"), src("eh_proj.weight"), RAD_BF16, { D, 2 * D }, grp);

        /* wqkv rows [Q | G | K | V], each a projection of its own, split by heads. */
        const char* wqkv = src("transformer_layer.attention.wqkv.weight");
        auto proj = [&](const char* d, int64_t first, int64_t rows, int64_t local) -> rad_weight {
            if (map_rows(b, dn(d), { { wqkv, (int)first, rows } }) < 0) return 0;
            return decl_w(b, dn(d), RAD_BF16, { local, D }, RAD_ACCESS_PER_TOKEN, RAD_SHARD_ROW,
                          grp_layer(grp));
        };
        L.w_q = proj("q.weight", 0, qd_all, qd);
        L.w_g = proj("g.weight", qd_all, qd_all, qd);
        L.w_k = proj("k.weight", 2 * qd_all, kd_all, kd);
        L.w_v = proj("v.weight", 2 * qd_all + kd_all, kd_all, kd);
        RAD_ARCH_TRY(map_copy(b, dn("o.weight"), src("transformer_layer.attention.wo.weight")));
        L.w_o = decl_w(b, dn("o.weight"), RAD_BF16, { D, qd }, RAD_ACCESS_PER_TOKEN,
                       RAD_SHARD_COL, grp_layer(grp));
        RAD_ARCH_TRY(map_concat(b, dn("gate_up.weight"),
                                { src("transformer_layer.feed_forward.w1.weight"),
                                  src("transformer_layer.feed_forward.w3.weight") }));
        L.w_gu = decl_w(b, dn("gate_up.weight"), RAD_BF16, { 2 * ff, D }, RAD_ACCESS_PER_TOKEN,
                        RAD_SHARD_ROW, grp_layer(grp), 0, { ff, ff });
        RAD_ARCH_TRY(map_copy(b, dn("down.weight"), src("transformer_layer.feed_forward.w2.weight")));
        L.w_down = decl_w(b, dn("down.weight"), RAD_BF16, { D, ff }, RAD_ACCESS_PER_TOKEN,
                          RAD_SHARD_COL, grp_layer(grp));
        if (!L.w_emb || !L.w_en || !L.w_hn || !L.w_an || !L.w_fn || !L.w_fin || !L.w_qn ||
            !L.w_kn || !L.w_eh || !L.w_q || !L.w_g || !L.w_k || !L.w_v || !L.w_o || !L.w_gu ||
            !L.w_down)
            return RAD_E_INVAL;

        /* ---- the ops, in the order a pass issues them. The embedding and its norm run in FRAME
         * only; PROMPT's labels are text, whose embedding is zero, and so is its norm (op_efill
         * zeroes that half of the concatenation once a prompt). */
        L.op_emb = rw(b, RAD_OP(b, "rvq_embed",
                                RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n_embd", D),
                                           RAD_INT("n_codes", 1), RAD_INT("vocab", kVocab),
                                           RAD_INT("off0", 0), RAD_F64("scale", 1.0),
                                           RAD_STR("dtype", "bf16")),
                                RAD_WEIGHTS(L.w_emb, L.w_emb)),
                      { m.b_codes }, { m.b_te });
        if (i == 0) L.op_eadd = add_op(b, S, D, m.b_te, m.b_ug, m.b_te);
        L.op_en = norm_op(b, S, D, g.eps, 1.0, L.w_en, { m.b_te }, m.b_tcat);
        /* Layer 0's hidden state is the backbone's: the prompt's rows (PROMPT) or the frame's
         * plane (FRAME); both stay live to here. */
        L.op_hn = i == 0 ? norm_op(b, T, D, g.eps, 1.0, L.w_hn, { m.a_h.x, m.b_plane }, m.b_tcat)
                         : norm_op(b, T, D, g.eps, 1.0, L.w_hn, { m.b_tho }, m.b_tcat);
        L.op_eh = gemm_op(b, T, D, 2 * D, L.w_eh, m.b_tcat, m.b_tm);
        L.op_an = norm_op(b, T, D, g.eps, 1.0, L.w_an, { m.b_tm }, m.b_th);
        L.op_q = gemm_op(b, T, qd, D, L.w_q, m.b_th, m.b_tq);
        L.op_g = gemm_op(b, T, qd, D, L.w_g, m.b_th, m.b_tg);
        L.op_k = gemm_op(b, T, kd, D, L.w_k, m.b_th, m.b_tk);
        L.op_v = gemm_op(b, T, kd, D, L.w_v, m.b_th, m.b_tv);
        /* (1 + w) per head, always: the exporter never wrote attention_qk_norm (tower.py). */
        L.op_qn = norm_op(b, T * g.n_head, hd, g.eps, 1.0, L.w_qn, { m.b_tq }, m.b_tq);
        L.op_kn = norm_op(b, T * g.n_head_kv, hd, g.eps, 1.0, L.w_kn, { m.b_tk }, m.b_tk);
        /* Adjacent pairs (GPT-J), unlike the backbone's halves, over the first 64 dims. */
        L.op_rq = rw(b, decl_rope(b, g, T, hd, g.n_head, 0, m.n_rot_t, "gptj"), { m.b_tq },
                     { m.b_tq });
        L.op_rk = rw(b, decl_rope(b, g, T, hd, g.n_head_kv, 0, m.n_rot_t, "gptj"), { m.b_tk },
                     { m.b_tk });
        RAD_ARCH_TRY(rad_bind_layer_kv(b, kvl, m.kv_full));
        /* Declared before kv_store, which reads back the resolved block size. */
        L.op_attn = rw(b, RAD_OP(b, "attn_paged",
                           RAD_PARAMS(RAD_RANGE("q_len", 1, T), RAD_INT("head_dim", hd),
                                      RAD_INT("gqa", g.gqa()), RAD_INT("causal", 1),
                                      RAD_INT("window", 0), RAD_INT("n_head", g.n_head),
                                      RAD_INT("block_size", RAD_KV_BLOCK),
                                      RAD_INT("max_seqs", g.max_seqs),
                                      RAD_INT("max_ctx", g.max_ctx),
                                      RAD_STR("q_dtype", g.dtype),
                                      RAD_STR("kv_dtype", m.g.kv_dtype)),
                           RAD_NOWEIGHTS),
                       { m.b_tq }, { m.b_tattn });
        L.op_kv = rw(b, RAD_OP(b, "kv_store",
                         RAD_PARAMS(RAD_RANGE("M", 1, T), RAD_INT("head_dim", hd),
                                    RAD_INT("n_head_kv", g.n_head_kv),
                                    RAD_INT("block_size", rad_kv_block_size(b, m.kv_full)),
                                    RAD_STR("kv_dtype", m.g.kv_dtype)),
                         RAD_NOWEIGHTS),
                     { m.b_tk, m.b_tv }, {});
        L.op_sig = rows_op(b, "sigmoid", T, qd, { m.b_tg }, { m.b_tg });
        L.op_mul = rows_op(b, "mul", T, qd, { m.b_tattn, m.b_tg }, { m.b_tattn });
        L.op_o = gemm_op(b, T, D, qd, L.w_o, m.b_tattn, m.b_to);
        L.op_ar1 = ar_op(b, g, m.b_to);
        L.op_add1 = add_op(b, T, D, m.b_tm, m.b_to, m.b_tm);
        L.op_fn = norm_op(b, T, D, g.eps, 1.0, L.w_fn, { m.b_tm }, m.b_th);
        L.op_gu = gemm_op(b, T, 2 * ff, D, L.w_gu, m.b_th, m.b_tgu);
        L.op_act = rows_op(b, "silu_mul", T, ff, { m.b_tgu }, { m.b_tff });
        L.op_down = gemm_op(b, T, D, ff, L.w_down, m.b_tff, m.b_to);
        L.op_ar2 = ar_op(b, g, m.b_to);
        L.op_add2 = add_op(b, T, D, m.b_tm, m.b_to, m.b_tm);
        L.op_fin = norm_op(b, T, D, g.eps, 1.0, L.w_fin, { m.b_tm }, m.b_tho);
        if (!L.op_emb || !L.op_en || !L.op_hn || !L.op_eh || !L.op_an || !L.op_q || !L.op_g ||
            !L.op_k || !L.op_v || !L.op_qn || !L.op_kn || !L.op_rq || !L.op_rk || !L.op_attn ||
            !L.op_kv || !L.op_sig || !L.op_mul || !L.op_o || !L.op_add1 || !L.op_fn ||
            !L.op_gu || !L.op_act || !L.op_down || !L.op_add2 || !L.op_fin ||
            (i == 0 && !L.op_eadd) || (g.world > 1 && (!L.op_ar1 || !L.op_ar2)))
            return RAD_E_INVAL;

        /* A per-codebook layer's head draws code k + 1 (FRAME only). */
        if (!shared) {
            L.w_head = wcopy(b, nm.f("tower.head.%d.weight", k),
                             nm.ckpt("audio_decoder_mtp.heads.%d.weight", k), RAD_BF16,
                             { kVocab, D }, grp);
            L.op_head = rw(b, RAD_OP(b, "logits_gemm",
                                     RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n_vocab", kVocab),
                                                RAD_INT("n_embd", D), RAD_STR("dtype", "bf16")),
                                     RAD_WEIGHTS(L.w_head)),
                           { m.b_tho }, { m.b_hlog });
            L.op_samp = draw_op(b, S, kVocab, kTopK, kTemp, kTopP, 2 + k, m.b_hlog, m.b_codes);
            if (!L.w_head || !L.op_head || !L.op_samp) return RAD_E_INVAL;
        }
    }
    /* The codes stay live through the last layer: every layer's embedding reads them. */
    RAD_ARCH_TRY(rad_op_reads(b, m.tw[kTower - 1].op_samp, &m.b_codes, 1));
    return RAD_OK;
}

/* ================================================================== the frame's tail */
/* The frame into the lane's history, its unseen codes into the lane, and its embedding into the
 * backbone's stream; after the backbone, the frame row's hidden state into the lane. */
static int declare_frame_tail(RadBuilder* b, Model& m) {
    Names& nm = m.nm;
    const int64_t S = m.lanes, D = m.g.n_embd;
    m.b_unew = decl_b(b, nm.f("frame.unew"), RAD_BF16, { S, D });
    m.op_store = rw(b, RAD_OP(b, "frame_store",
                              RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n_codes", kCodes),
                                         RAD_INT("stride", kMaxFrames), RAD_INT("rep", 1),
                                         RAD_INT("skip", 0)),
                              RAD_NOWEIGHTS),
                    { m.b_codes, m.b_status }, { m.b_hist });
    /* Codes 2..9 summed in f32 and rounded once, as embedding_bag does: sections 2..9. */
    m.op_u = rw(b, RAD_OP(b, "rvq_embed",
                          RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n_embd", D),
                                     RAD_INT("n_codes", kCodes - 2), RAD_INT("vocab", kVocab),
                                     RAD_INT("off0", 0), RAD_F64("scale", 1.0),
                                     RAD_STR("dtype", "bf16"), RAD_INT("round", 1)),
                          RAD_WEIGHTS(m.w_cb, m.w_cb)),
                { m.b_codes }, { m.b_unew });
    m.op_uscat = rw(b, RAD_OP(b, "scatter_rows",
                              RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n", D),
                                         RAD_STR("dtype", "bf16")),
                              RAD_NOWEIGHTS),
                    { m.b_unew }, { m.b_u });
    /* (E_lm[candidate] + E_cb[4096 + c1]) / sqrt 2, each sum rounded to bf16 as the reference's
     * tensors are (tower.py, embed_backbone). */
    m.op_fb = rw(b, RAD_OP(b, "rvq_embed",
                           RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n_embd", D),
                                      RAD_INT("n_codes", 2), RAD_INT("vocab", kVocab),
                                      RAD_INT("off0", 0), RAD_F64("scale", 1.0 / std::sqrt(2.0)),
                                      RAD_STR("dtype", "bf16")),
                           RAD_WEIGHTS(m.w_cemb, m.w_cb)),
                 { m.b_codes }, { m.b_x });
    m.op_fstore = rw(b, RAD_OP(b, "scatter_rows",
                               RAD_PARAMS(RAD_RANGE("M", 1, S), RAD_INT("n", D),
                                          RAD_STR("dtype", "bf16")),
                               RAD_NOWEIGHTS),
                     { m.a_h.x }, { m.b_hid });
    return m.op_store && m.op_u && m.op_uscat && m.op_fb && m.op_fstore ? RAD_OK : RAD_E_INVAL;
}

/* ================================================================== the codec */
/* A causal conv whose weight the checkpoint keeps weight-normalised (folded at convert). */
static int vconv(RadBuilder* b, Names& nm, VConv& v, const char* dn, const char* src, int64_t cin,
                 int64_t cout, int64_t k, int64_t dil, int64_t rows, rad_buf x, rad_buf res,
                 rad_buf y, rad_buf cu, const char* act = "none") {
    const char* wn = nm.f("%s.weight", dn);
    RAD_ARCH_TRY(map_wnorm(b, wn, nm.ckpt("%s.parametrizations.weight.original0", src),
                           nm.ckpt("%s.parametrizations.weight.original1", src)));
    v.w = decl_w(b, wn, RAD_BF16, { cout, cin, k }, RAD_ACCESS_PER_TOKEN, RAD_SHARD_NONE,
                 grp_layer(kGrpCodec));
    v.b = wcopy(b, nm.f("%s.bias", dn), nm.ckpt("%s.bias", src), RAD_BF16, { cout }, kGrpCodec);
    if (!v.w || !v.b) return RAD_E_INVAL;
    const RadParam ps[] = { RAD_RANGE("M", 1, rows), RAD_INT("cin", cin), RAD_INT("cout", cout),
                            RAD_INT("k", k), RAD_INT("dil", dil), RAD_STR("act", act),
                            RAD_STR("dtype", "bf16"), RAD_INT("causal", 1) };
    const rad_weight ws[] = { v.w, v.b };
    v.op = res ? rw(b, rad_decl_op(b, "conv1d", ps, 8, ws, 2), { x, cu, res }, { y })
               : rw(b, rad_decl_op(b, "conv1d", ps, 8, ws, 2), { x, cu }, { y });
    return v.op ? RAD_OK : RAD_E_INVAL;
}

static rad_weight valpha(RadBuilder* b, Names& nm, const char* dn, const char* src, int64_t n) {
    return wcopy(b, nm.f("%s.alpha", dn), nm.ckpt("%s.alpha", src), RAD_F32, { 1, n, 1 },
                 kGrpCodec);
}

static rad_op snake_op(RadBuilder* b, int64_t rows, int64_t n, rad_weight a, rad_buf x, rad_buf y) {
    return rw(b, RAD_OP(b, "snake",
                        RAD_PARAMS(RAD_RANGE("M", 1, rows), RAD_INT("n", n),
                                   RAD_STR("dtype", "bf16")),
                        RAD_WEIGHTS(a)),
              { x }, { y });
}

static int declare_codec(RadBuilder* b, Model& m) {
    Names& nm = m.nm;
    const int64_t NL = kVocContext + kVocChunk;       /* frames through the transformer */
    const int64_t NC = kConvFrames;                    /* frames through the convolutions */
    const int64_t qd = kCtHeads * kCtHeadDim;
    const char* q = "codec.quantizer";

    /* ---- the dequantiser: each codebook's raw row (dimension 8) through its own 1x1 projection
     * to 1024, summed into the transformer's stream. Code 0 is a candidate index (c0 + 1); codes
     * 1..9 come from heads of 4096 and read 1024-entry codebooks clamped at 1023 (rvq.py). */
    m.b_rq = decl_b(b, nm.f("codec.rq"), RAD_BF16, { NL, kCbDim });
    m.b_cx = decl_b(b, nm.f("codec.x"), RAD_BF16, { NL, kLat });
    m.b_cconst = decl_b(b, nm.f("codec.nconv"), RAD_I32, { 1 });
    m.op_cnst = iota_op(b, 1, NC, 0, m.b_cconst);
    for (int s = 0; s < kRates; ++s) {
        m.b_ccu[s] = decl_b(b, nm.f("codec.cu%d", s), RAD_I32, { 2 });
        m.op_ccu[s] = s == 0 ? cu_op(b, 1, 0, m.b_ccu[0]) : cu_op(b, kRate[s], m.b_cconst, m.b_ccu[s]);
        if (!m.op_ccu[s]) return RAD_E_INVAL;
    }
    for (int k = 0; k < kCodes; ++k) {
        const char* qs = k == 0 ? nm.ckpt("%s.semantic_quantizer.quantizers.0", q)
                                : nm.ckpt("%s.quantizer.quantizers.%d", q, k - 1);
        const int64_t bins = k == 0 ? kVocab : kResVocab;
        m.w_cbk[k] = wcopy(b, nm.f("codec.cb%d.weight", k), nm.ckpt("%s.codebook.weight", qs),
                           RAD_BF16, { bins, kCbDim }, kGrpCodec);
        m.op_rq[k] = rw(b, RAD_OP(b, "rvq_embed",
                                  RAD_PARAMS(RAD_RANGE("M", 1, NL), RAD_INT("n_embd", kCbDim),
                                             RAD_INT("n_codes", 1), RAD_INT("vocab", bins),
                                             RAD_INT("off0", k == 0 ? -1 : 0),
                                             RAD_F64("scale", 1.0), RAD_STR("dtype", "bf16"),
                                             RAD_INT("clamp", k == 0 ? 0 : kResVocab)),
                                  RAD_WEIGHTS(m.w_cbk[k], m.w_cbk[k])),
                        { m.b_hist }, { m.b_rq });
        /* The out-projection is the old-style weight norm (weight_g, weight_v). */
        VConv& v = m.qo[k];
        const char* wn = nm.f("codec.q%d.weight", k);
        RAD_ARCH_TRY(map_wnorm(b, wn, nm.ckpt("%s.out_proj.weight_g", qs),
                               nm.ckpt("%s.out_proj.weight_v", qs)));
        v.w = decl_w(b, wn, RAD_BF16, { kLat, kCbDim, 1 }, RAD_ACCESS_PER_TOKEN, RAD_SHARD_NONE,
                     grp_layer(kGrpCodec));
        v.b = wcopy(b, nm.f("codec.q%d.bias", k), nm.ckpt("%s.out_proj.bias", qs), RAD_BF16,
                    { kLat }, kGrpCodec);
        if (!m.w_cbk[k] || !m.op_rq[k] || !v.w || !v.b) return RAD_E_INVAL;
        const RadParam ps[] = { RAD_RANGE("M", 1, NL), RAD_INT("cin", kCbDim),
                                RAD_INT("cout", kLat), RAD_INT("k", 1), RAD_INT("dil", 1),
                                RAD_STR("act", "none"), RAD_STR("dtype", "bf16"),
                                RAD_INT("causal", 1) };
        const rad_weight ws[] = { v.w, v.b };
        v.op = k == 0 ? rw(b, rad_decl_op(b, "conv1d", ps, 8, ws, 2), { m.b_rq, m.b_ccu[0] },
                           { m.b_cx })
                      : rw(b, rad_decl_op(b, "conv1d", ps, 8, ws, 2),
                           { m.b_rq, m.b_ccu[0], m.b_cx }, { m.b_cx });
        if (!v.op) return RAD_E_INVAL;
    }

    /* ---- the post-quantiser transformer (modded_dac.py, WindowLimitedTransformer) */
    const char* pt = "codec.quantizer.post_module";
    m.b_ch    = decl_b(b, nm.f("codec.h"), RAD_BF16, { NL, kLat });
    m.b_cqkv  = decl_b(b, nm.f("codec.qkv"), RAD_BF16, { NL, 3 * qd });
    m.b_cattn = decl_b(b, nm.f("codec.attn"), RAD_BF16, { NL, qd });
    m.b_co    = decl_b(b, nm.f("codec.o"), RAD_BF16, { NL, kLat });
    m.b_cgu   = decl_b(b, nm.f("codec.gu"), RAD_BF16, { NL, 2 * kCtFf });
    m.b_cff   = decl_b(b, nm.f("codec.ff"), RAD_BF16, { NL, kCtFf });
    m.ct.resize((size_t)kCtLayers);
    for (int l = 0; l < kCtLayers; ++l) {
        CodecLayer& L = m.ct[(size_t)l];
        auto src = [&](const char* s) { return nm.ckpt("%s.layers.%d.%s", pt, l, s); };
        auto dn = [&](const char* s) { return nm.f("codec.%d.%s", l, s); };
        L.w_n1 = wcopy(b, dn("n1.weight"), src("attention_norm.weight"), RAD_F32, { kLat },
                       kGrpCodec);
        L.w_n2 = wcopy(b, dn("n2.weight"), src("ffn_norm.weight"), RAD_F32, { kLat }, kGrpCodec);
        L.w_ls1 = wcopy(b, dn("ls1.weight"), src("attention_layer_scale.gamma"), RAD_F32,
                        { kLat }, kGrpCodec);
        L.w_ls2 = wcopy(b, dn("ls2.weight"), src("ffn_layer_scale.gamma"), RAD_F32, { kLat },
                        kGrpCodec);
        L.w_qkv = wcopy(b, dn("qkv.weight"), src("attention.wqkv.weight"), RAD_BF16,
                        { 3 * qd, kLat }, kGrpCodec);
        L.w_o = wcopy(b, dn("o.weight"), src("attention.wo.weight"), RAD_BF16, { kLat, qd },
                      kGrpCodec);
        if (map_concat(b, dn("gate_up.weight"),
                       { src("feed_forward.w1.weight"), src("feed_forward.w3.weight") }) < 0)
            return RAD_E_INVAL;
        L.w_gu = decl_w(b, dn("gate_up.weight"), RAD_BF16, { 2 * kCtFf, kLat },
                        RAD_ACCESS_PER_TOKEN, RAD_SHARD_NONE, grp_layer(kGrpCodec));
        L.w_down = wcopy(b, dn("down.weight"), src("feed_forward.w2.weight"), RAD_BF16,
                         { kLat, kCtFf }, kGrpCodec);
        /* Plain-gain RMS norms at eps 1e-5 (the codec's own RMSNorm, not the backbone's). */
        L.op_n1 = norm_op(b, NL, kLat, kCtEps, 0.0, L.w_n1, { m.b_cx }, m.b_ch);
        L.op_qkv = gemm_op(b, NL, 3 * qd, kLat, L.w_qkv, m.b_ch, m.b_cqkv);
        /* Adjacent pairs over all 64 dims, positions the frames' own in the piece, as a whole
         * decode restarting at 0 would see them. */
        L.op_rope = rw(b, RAD_OP(b, "rope",
                                 RAD_PARAMS(RAD_RANGE("M", 1, NL), RAD_INT("head_dim", kCtHeadDim),
                                            RAD_INT("n_head", kCtHeads),
                                            RAD_INT("n_head_kv", kCtHeads),
                                            RAD_F64("theta", kCtTheta), RAD_F64("scale", 1.0),
                                            RAD_STR("mode", "gptj")),
                                 RAD_NOWEIGHTS),
                       { m.b_cqkv }, { m.b_cqkv });
        L.op_attn = rw(b, RAD_OP(b, "attn_dense",
                                 RAD_PARAMS(RAD_RANGE("M", 1, NL), RAD_INT("head_dim", kCtHeadDim),
                                            RAD_INT("gqa", 1), RAD_INT("causal", 1),
                                            RAD_STR("dtype", "bf16"),
                                            RAD_F64("scale", 1.0 / std::sqrt((double)kCtHeadDim)),
                                            RAD_INT("max_seqlen", NL), RAD_INT("window", kAttnWin)),
                                 RAD_NOWEIGHTS),
                       { m.b_cqkv }, { m.b_cattn });
        L.op_o = gemm_op(b, NL, kLat, qd, L.w_o, m.b_cattn, m.b_co);
        L.op_ls1 = mulw_op(b, NL, kLat, L.w_ls1, m.b_co, m.b_co);
        L.op_add1 = add_op(b, NL, kLat, m.b_cx, m.b_co, m.b_cx);
        L.op_n2 = norm_op(b, NL, kLat, kCtEps, 0.0, L.w_n2, { m.b_cx }, m.b_ch);
        L.op_gu = gemm_op(b, NL, 2 * kCtFf, kLat, L.w_gu, m.b_ch, m.b_cgu);
        L.op_act = rows_op(b, "silu_mul", NL, kCtFf, { m.b_cgu }, { m.b_cff });
        L.op_down = gemm_op(b, NL, kLat, kCtFf, L.w_down, m.b_cff, m.b_co);
        L.op_ls2 = mulw_op(b, NL, kLat, L.w_ls2, m.b_co, m.b_co);
        L.op_add2 = add_op(b, NL, kLat, m.b_cx, m.b_co, m.b_cx);
        if (!L.w_n1 || !L.w_n2 || !L.w_ls1 || !L.w_ls2 || !L.w_qkv || !L.w_o || !L.w_gu ||
            !L.w_down || !L.op_rope || !L.op_attn || !L.op_ls1 || !L.op_ls2 || !L.op_act)
            return RAD_E_INVAL;
        RAD_ARCH_TRY(rad_op_reads(b, L.op_attn, &m.b_ccu[0], 1));
    }
    /* The final norm over only the frames the convolutions read: the last nc. */
    m.w_cn = wcopy(b, nm.f("codec.norm.weight"), nm.ckpt("%s.norm.weight", pt), RAD_F32, { kLat },
                   kGrpCodec);
    m.b_ux[0] = decl_b(b, nm.f("codec.ux0"), RAD_BF16, { NC, kLat });
    m.op_cn = norm_op(b, NC, kLat, kCtEps, 0.0, m.w_cn, { m.b_cx }, m.b_ux[0]);

    /* ---- two 2x upsamplings, each a transposed conv of kernel 2 and a ConvNeXt block */
    m.b_ua  = decl_b(b, nm.f("codec.ua"), RAD_BF16, { 4 * NC, kLat });
    m.b_ub  = decl_b(b, nm.f("codec.ub"), RAD_BF16, { 4 * NC, kLat });
    m.b_uh  = decl_b(b, nm.f("codec.uh"), RAD_BF16, { 4 * NC, 4 * kLat });
    m.b_ug2 = decl_b(b, nm.f("codec.ug"), RAD_BF16, { 4 * NC, 4 * kLat });
    for (int i = 0; i < 2; ++i) {
        Upsample& U = m.up[i];
        const int64_t rin = NC << i, rout = NC << (i + 1);
        const char* us = nm.ckpt("%s.upsample.%d", q, i);
        auto w = [&](const char* dn, const char* s, uint32_t dt,
                     std::initializer_list<int64_t> sh) {
            return wcopy(b, nm.f("codec.up%d.%s", i, dn), nm.ckpt("%s.%s", us, s), dt, sh,
                         kGrpCodec);
        };
        U.w_t  = w("t.weight", "0.conv.weight", RAD_BF16, { kLat, kLat, 2 });
        U.b_t  = w("t.bias", "0.conv.bias", RAD_BF16, { kLat });
        U.w_dw = w("dw.weight", "1.dwconv.conv.weight", RAD_BF16, { kLat, 1, 7 });
        U.b_dw = w("dw.bias", "1.dwconv.conv.bias", RAD_BF16, { kLat });
        U.w_ln = w("ln.weight", "1.norm.weight", RAD_F32, { kLat });
        U.b_ln = w("ln.bias", "1.norm.bias", RAD_F32, { kLat });
        U.w_p1 = w("p1.weight", "1.pwconv1.weight", RAD_BF16, { 4 * kLat, kLat });
        U.b_p1 = w("p1.bias", "1.pwconv1.bias", RAD_BF16, { 4 * kLat });
        U.w_p2 = w("p2.weight", "1.pwconv2.weight", RAD_BF16, { kLat, 4 * kLat });
        U.b_p2 = w("p2.bias", "1.pwconv2.bias", RAD_BF16, { kLat });
        U.w_g  = w("gamma", "1.gamma", RAD_F32, { kLat });
        m.b_ux[i + 1] = decl_b(b, nm.f("codec.ux%d", i + 1), RAD_BF16, { rout, kLat });
        U.op_t = rw(b, RAD_OP(b, "conv_t1d",
                              RAD_PARAMS(RAD_RANGE("M", 1, rin), RAD_INT("cin", kLat),
                                         RAD_INT("cout", kLat), RAD_INT("stride", 2),
                                         RAD_STR("dtype", "bf16"), RAD_INT("pad", 0),
                                         RAD_INT("k", 2)),
                              RAD_WEIGHTS(U.w_t, U.b_t)),
                    { m.b_ux[i], m.b_ccu[1 + i] }, { m.b_ux[i + 1] });
        U.op_dw = rw(b, RAD_OP(b, "conv1d_dw",
                               RAD_PARAMS(RAD_RANGE("M", 1, rout), RAD_INT("n", kLat),
                                          RAD_INT("k", 7), RAD_STR("dtype", "bf16")),
                               RAD_WEIGHTS(U.w_dw, U.b_dw)),
                     { m.b_ux[i + 1], m.b_ccu[2 + i] }, { m.b_ua });
        U.op_ln = rw(b, RAD_OP(b, "layernorm",
                               RAD_PARAMS(RAD_RANGE("M", 1, rout), RAD_INT("n", kLat),
                                          RAD_F64("eps", 1e-6), RAD_STR("dtype", "bf16")),
                               RAD_WEIGHTS(U.w_ln, U.b_ln)),
                     { m.b_ua }, { m.b_ub });
        U.op_p1 = gemm_bias_op(b, rout, 4 * kLat, kLat, U.w_p1, U.b_p1, m.b_ub, m.b_uh);
        U.op_gelu = rows_op(b, "gelu", rout, 4 * kLat, { m.b_uh }, { m.b_ug2 });
        U.op_p2 = gemm_bias_op(b, rout, kLat, 4 * kLat, U.w_p2, U.b_p2, m.b_ug2, m.b_ua);
        U.op_g = mulw_op(b, rout, kLat, U.w_g, m.b_ua, m.b_ua);
        U.op_add = add_op(b, rout, kLat, m.b_ux[i + 1], m.b_ua, m.b_ux[i + 1]);
        if (!U.w_t || !U.b_t || !U.w_dw || !U.b_dw || !U.w_ln || !U.b_ln || !U.w_p1 || !U.b_p1 ||
            !U.w_p2 || !U.b_p2 || !U.w_g || !U.op_t || !U.op_dw || !U.op_ln || !U.op_p1 ||
            !U.op_gelu || !U.op_p2 || !U.op_g || !U.op_add)
            return RAD_E_INVAL;
    }

    /* ---- the decoder: a conv into 1536 channels, four upsampling blocks, the output conv */
    const int64_t R0 = 4 * NC;   /* rows at 4 a frame */
    int64_t rows[5], ch[5];
    rows[0] = R0;
    ch[0] = kDec;
    for (int i = 0; i < 4; ++i) {
        rows[i + 1] = rows[i] * m.v_ups[i];
        ch[i + 1] = kDec >> (i + 1);
    }
    for (int s = 0; s < 5; ++s) {
        m.b_vs[s] = decl_b(b, nm.f("codec.s%d", s), RAD_BF16, { rows[s], ch[s] });
        m.b_vt[s] = decl_b(b, nm.f("codec.t%d", s), RAD_BF16, { rows[s], ch[s] });
        if (s > 0) {
            m.b_va[s] = decl_b(b, nm.f("codec.a%d", s), RAD_BF16, { rows[s], ch[s] });
            m.b_vb[s] = decl_b(b, nm.f("codec.b%d", s), RAD_BF16, { rows[s], ch[s] });
        }
    }
    const char* dd = "codec.decoder.model";
    RAD_ARCH_TRY(vconv(b, nm, m.dec0, "codec.dec0", nm.ckpt("%s.0.conv", dd), kLat, kDec, 7, 1,
                       R0, m.b_ux[2], 0, m.b_vs[0], m.b_ccu[3]));
    static const int64_t kDil[3] = { 1, 3, 9 };
    for (int i = 0; i < 4; ++i) {
        VBlock& B = m.vb[i];
        const int64_t ci = ch[i], co = ch[i + 1], s = m.v_ups[i];
        const char* bn = nm.f("codec.b%d", i);
        const char* bs = nm.ckpt("%s.%d.block", dd, i + 1);
        B.a = valpha(b, nm, nm.f("%s.snake", bn), nm.ckpt("%s.0", bs), ci);
        B.op_s = snake_op(b, rows[i], ci, B.a, m.b_vs[i], m.b_vt[i]);
        /* The transposed conv's weight norm is per input channel: its weight is [in, out, k]. */
        const char* wn = nm.f("%s.t.weight", bn);
        RAD_ARCH_TRY(map_wnorm(b, wn, nm.ckpt("%s.1.conv.parametrizations.weight.original0", bs),
                               nm.ckpt("%s.1.conv.parametrizations.weight.original1", bs)));
        B.wt = decl_w(b, wn, RAD_BF16, { ci, co, 2 * s }, RAD_ACCESS_PER_TOKEN, RAD_SHARD_NONE,
                      grp_layer(kGrpCodec));
        B.bt = wcopy(b, nm.f("%s.t.bias", bn), nm.ckpt("%s.1.conv.bias", bs), RAD_BF16, { co },
                     kGrpCodec);
        B.op_t = rw(b, RAD_OP(b, "conv_t1d",
                              RAD_PARAMS(RAD_RANGE("M", 1, rows[i]), RAD_INT("cin", ci),
                                         RAD_INT("cout", co), RAD_INT("stride", s),
                                         RAD_STR("dtype", "bf16"), RAD_INT("pad", 0),
                                         RAD_INT("k", 2 * s)),
                              RAD_WEIGHTS(B.wt, B.bt)),
                    { m.b_vt[i], m.b_ccu[3 + i] }, { m.b_vs[i + 1] });
        if (!B.a || !B.wt || !B.bt || !B.op_t || !B.op_s) return RAD_E_INVAL;
        /* Three residual units (dilations 1, 3, 9): x + conv2(snake2(conv1(snake1(x)))), x the
         * stage buffer, written back in place by conv2's residual. */
        for (int r = 0; r < 3; ++r) {
            VRes& U = B.res[r];
            const char* un = nm.f("%s.res%d", bn, r);
            const char* ub = nm.ckpt("%s.%d.block", bs, r + 2);
            const int64_t R = rows[i + 1];
            U.a1 = valpha(b, nm, nm.f("%s.act1", un), nm.ckpt("%s.0", ub), co);
            U.a2 = valpha(b, nm, nm.f("%s.act2", un), nm.ckpt("%s.2", ub), co);
            U.op_s1 = snake_op(b, R, co, U.a1, m.b_vs[i + 1], m.b_vt[i + 1]);
            RAD_ARCH_TRY(vconv(b, nm, U.c1, nm.f("%s.conv1", un), nm.ckpt("%s.1.conv", ub), co, co,
                               7, kDil[r], R, m.b_vt[i + 1], 0, m.b_va[i + 1], m.b_ccu[4 + i]));
            U.op_s2 = snake_op(b, R, co, U.a2, m.b_va[i + 1], m.b_vb[i + 1]);
            RAD_ARCH_TRY(vconv(b, nm, U.c2, nm.f("%s.conv2", un), nm.ckpt("%s.3.conv", ub), co, co,
                               1, 1, R, m.b_vb[i + 1], m.b_vs[i + 1], m.b_vs[i + 1],
                               m.b_ccu[4 + i]));
            if (!U.a1 || !U.a2 || !U.op_s1 || !U.op_s2) return RAD_E_INVAL;
        }
    }
    m.w_fa = valpha(b, nm, "codec.snake_out", nm.ckpt("%s.5", dd), ch[4]);
    m.op_fs = snake_op(b, rows[4], ch[4], m.w_fa, m.b_vs[4], m.b_vt[4]);
    m.b_vout = decl_b(b, nm.f("codec.out"), RAD_BF16, { rows[4], 1 });
    RAD_ARCH_TRY(vconv(b, nm, m.fin, "codec.conv_out", nm.ckpt("%s.6.conv", dd), ch[4], 1, 7, 1,
                       rows[4], m.b_vt[4], 0, m.b_vout, m.b_ccu[7], "tanh"));
    m.b_audio = decl_b(b, nm.f("codec.audio"), RAD_F32, { kVocChunk * kSamplesPerFrame, 1 },
                       RAD_BUF_PERSIST);
    m.op_fcast = rw(b, RAD_OP(b, "cast",
                              RAD_PARAMS(RAD_RANGE("M", 1, kVocChunk * kSamplesPerFrame),
                                         RAD_INT("n", 1), RAD_STR("from", "bf16"),
                                         RAD_STR("to", "f32")),
                              RAD_NOWEIGHTS),
                    { m.b_vout }, { m.b_audio });
    return m.w_cn && m.op_cn && m.w_fa && m.op_fs && m.op_fcast && m.op_cnst ? RAD_OK
                                                                             : RAD_E_INVAL;
}

/* ================================================================== declare */
static int declare(RadBuilder* b, const RadModelMeta* meta, const RadBuildCtx* ctx) {
    if (!b || !meta || !ctx) return RAD_E_INVAL;
    if (ctx->rank < 0 || ctx->rank >= MAX_RANKS) return RAD_E_INVAL;
    Model& m = g_model[ctx->rank];
    m = Model{};
    m.nm = Names(ctx->scope);
    RAD_ARCH_TRY(check_format(meta));
    if (ctx->world_size > 2) {
        fprintf(stderr, "radiance: fishomni: drama-3 is served on one or two cards (--tp 1 or 2): "
                        "its two KV heads and the tower's split stop at two ranks\n");
        return RAD_E_UNSUPPORTED;
    }
    RAD_ARCH_TRY(geom_from(m.g, meta, ctx, "bf16", RAD_BF16));
    m.lanes = std::min<int64_t>(kMaxLanes, std::max<int64_t>(1, ctx->max_seqs));
    if (m.g.max_tok < kVocContext + kVocChunk) {
        fprintf(stderr, "radiance: fishomni: a pass carries %lld rows; a codec chunk needs %lld\n",
                (long long)m.g.max_tok, (long long)(kVocContext + kVocChunk));
        return RAD_E_INVAL;
    }

    /* Declared in the order the passes issue them where it matters for liveness: the backbone
     * first (PROMPT runs it before everything else), then the frame head, the tower, the frame's
     * tail, and the codec. FRAME runs the head and the tower before the backbone; the buffers
     * that cross that seam (`x`, `h`, the codes, the plane) are named by the ops on both sides,
     * so their live ranges span it. */
    RAD_ARCH_TRY(declare_trunk(b, meta, ctx, m));
    RAD_ARCH_TRY(declare_frame_head(b, m));
    RAD_ARCH_TRY(declare_tower(b, meta, m));
    RAD_ARCH_TRY(declare_frame_tail(b, m));
    RAD_ARCH_TRY(declare_codec(b, m));

    if (!ctx->shape_probe) {
        RadAudioGenDecl d{};
        d.name = "drama-3";
        d.tmpl = nullptr;
        d.tmpl_plain = kPlain;
        d.prompt_whole = 1;
        d.first_frame = 0;
        d.max_prompt = kMaxPrompt;
        d.max_frames = kMaxFrames;
        d.frame_rate_num = kSampleRate;
        d.frame_rate_den = kSamplesPerFrame;
        d.lat_num = 1;
        d.lat_den = 1;
        d.samples_per_latent = kSamplesPerFrame;
        d.sample_rate = kSampleRate;
        d.channels = 1;
        d.default_cfg = 1.0;
        d.max_lanes = m.lanes;
        d.status = m.b_status;
        d.audio_out = m.b_audio;
        d.voc_chunk = kVocChunk;
        d.voc_context = kVocContext;
        d.branches = 1;
        d.input_special = 1;
        RAD_ARCH_TRY(rad_declare_audio_generator(b, &d));
    }
    rad_note(b, "rank %d/%d: drama-3 -- backbone %lld layers (%lld heads, %lld KV a rank; %lld "
                "experts of %lld a rank, %lld a token), tower %d layers at KV layers %lld..%lld "
                "(%lld heads a rank, ffn %lld), codec transformer %d layers, %lld lanes",
             m.g.rank, m.g.world, (long long)m.n_main, (long long)m.g.n_head,
             (long long)m.g.n_head_kv, (long long)m.moecfg.n_expert, (long long)m.moecfg.n_ff_exp,
             (long long)m.moecfg.top_k, kTower, (long long)m.n_main,
             (long long)(m.n_main + kTower - 1), (long long)m.gt.n_head, (long long)m.gt.n_ff,
             (int)kCtLayers, (long long)m.lanes);
    rad_note(b, "sampling: temperature %.2f, top-p %.2f, top-k %lld for the main token and every "
                "head; a semantic first draw among the lane's last %lld picks is redrawn at "
                "temperature %.2f, top-p %.2f, top-k %lld",
             kTemp, kTopP, (long long)kTopK, (long long)kRasWin, kRasTemp, kRasTopP,
             (long long)kRasTopK);
    return RAD_OK;
}

/* ================================================================== step */
static void step_trunk(RadCtx* c, const RadBatch* batch, const Model& m) {
    const int64_t T = batch->n_tok;
    if (m.op_rope_cs && T <= qk_fuse_rows(m.g) && !rope_mixed(batch))
        RAD_ISSUE_N(c, m.op_rope_cs, T, rope_pos1(batch, T), RAD_B(m.b_rope_cs));
    for (const Layer& l : m.layers) {
        if (l.full) l.attn.step(c, batch);
        else        l.gdn.step(c, batch);
        l.mlp.step(c, batch);
    }
    RAD_ISSUE_N(c, m.op_final_norm, T, brows(m.b_x, T), RAD_W(m.w_out_norm), brows(m.a_h.x, T));
}

/* Where the tower runs: its rows' positions and cache slots, the sequences' block tables,
 * context lengths and bounds, and its first layer's hidden state. FRAME also embeds codes. */
struct TowerAt {
    int64_t    R = 0;
    int64_t    max_q = 0;
    RadOperand pos{}, slot{}, bt{}, used{}, cu{};
    rad_buf    h0 = 0;
    bool       frame = false;
    RadOperand seed{}, fidx{};
};

static void step_tower(RadCtx* c, const Model& m, const TowerAt& at) {
    const Geom& g = m.gt;
    const int64_t R = at.R, D = g.n_embd, hd = g.head_dim, Sx = m.lanes;
    const int64_t qd = g.n_head * hd;
    /* Row k of the code-major [10, lanes] plane, narrowed to this pass's lanes. */
    auto code = [&](int k) {
        RadOperand o = brow_slice(m.b_codes, k, 1, Sx);
        o.cols = R;
        return o;
    };
    for (int i = 0; i < kTower; ++i) {
        const TowerLayer& L = m.tw[i];
        const int k = i - kShared;
        if (at.frame) {
            RAD_ISSUE_N(c, L.op_emb, R, code(k < 0 ? 0 : k), RAD_W(L.w_emb), RAD_W(L.w_emb),
                        brows(m.b_te, R));
            if (L.op_eadd)
                RAD_ISSUE_N(c, L.op_eadd, R, brows(m.b_te, R), brows(m.b_ug, R), brows(m.b_te, R));
            RAD_ISSUE_N(c, L.op_en, R, brows(m.b_te, R), RAD_W(L.w_en), bcol(m.b_tcat, 0, D, R));
        }
        RAD_ISSUE_N(c, L.op_hn, R, brows(i == 0 ? at.h0 : m.b_tho, R), RAD_W(L.w_hn),
                    bcol(m.b_tcat, D, D, R));
        RAD_ISSUE_N(c, L.op_eh, R, brows(m.b_tcat, R), RAD_W(L.w_eh), brows(m.b_tm, R));
        RAD_ISSUE_N(c, L.op_an, R, brows(m.b_tm, R), RAD_W(L.w_an), brows(m.b_th, R));
        RAD_ISSUE_N(c, L.op_q, R, brows(m.b_th, R), RAD_W(L.w_q), brows(m.b_tq, R));
        RAD_ISSUE_N(c, L.op_g, R, brows(m.b_th, R), RAD_W(L.w_g), brows(m.b_tg, R));
        RAD_ISSUE_N(c, L.op_k, R, brows(m.b_th, R), RAD_W(L.w_k), brows(m.b_tk, R));
        RAD_ISSUE_N(c, L.op_v, R, brows(m.b_th, R), RAD_W(L.w_v), brows(m.b_tv, R));
        RAD_ISSUE_N(c, L.op_qn, R * g.n_head, brows(m.b_tq, R), RAD_W(L.w_qn), brows(m.b_tq, R));
        RAD_ISSUE_N(c, L.op_kn, R * g.n_head_kv, brows(m.b_tk, R), RAD_W(L.w_kn),
                    brows(m.b_tk, R));
        RAD_ISSUE_N(c, L.op_rq, R, brows(m.b_tq, R), at.pos);
        RAD_ISSUE_N(c, L.op_rk, R, brows(m.b_tk, R), at.pos);
        RAD_ISSUE_N(c, L.op_kv, R, brows(m.b_tk, R), brows(m.b_tv, R), at.slot,
                    kv_cache(m.kv_full, (int)m.n_main + i));
        RAD_ISSUE_N(c, L.op_attn, at.max_q, brows(m.b_tq, R),
                    kv_cache(m.kv_full, (int)m.n_main + i), at.bt, at.used, RAD_NONE, RAD_NONE,
                    at.cu, brows(m.b_tattn, R));
        RAD_ISSUE_N(c, L.op_sig, R, brows(m.b_tg, R), brows(m.b_tg, R));
        RAD_ISSUE_N(c, L.op_mul, R, brows(m.b_tattn, R), brows(m.b_tg, R), brows(m.b_tattn, R));
        RAD_ISSUE_N(c, L.op_o, R, brows(m.b_tattn, R), RAD_W(L.w_o), brows(m.b_to, R));
        if (L.op_ar1) RAD_ISSUE_N(c, L.op_ar1, R * D, brows(m.b_to, R), RAD_NONE);
        RAD_ISSUE_N(c, L.op_add1, R, brows(m.b_tm, R), brows(m.b_to, R), brows(m.b_tm, R));
        RAD_ISSUE_N(c, L.op_fn, R, brows(m.b_tm, R), RAD_W(L.w_fn), brows(m.b_th, R));
        RAD_ISSUE_N(c, L.op_gu, R, brows(m.b_th, R), RAD_W(L.w_gu), brows(m.b_tgu, R));
        RAD_ISSUE_N(c, L.op_act, R, brows(m.b_tgu, R), brows(m.b_tff, R));
        RAD_ISSUE_N(c, L.op_down, R, brows(m.b_tff, R), RAD_W(L.w_down), brows(m.b_to, R));
        if (L.op_ar2) RAD_ISSUE_N(c, L.op_ar2, R * D, brows(m.b_to, R), RAD_NONE);
        RAD_ISSUE_N(c, L.op_add2, R, brows(m.b_tm, R), brows(m.b_to, R), brows(m.b_tm, R));
        RAD_ISSUE_N(c, L.op_fin, R, brows(m.b_tm, R), RAD_W(L.w_fin), brows(m.b_tho, R));
        if (at.frame && L.op_head) {
            RAD_ISSUE_N(c, L.op_head, R, brows(m.b_tho, R), RAD_W(L.w_head), brows(m.b_hlog, R));
            RAD_ISSUE_N(c, L.op_samp, R, brows(m.b_hlog, R), at.seed, at.fidx, code(k + 1),
                        RAD_NONE, RAD_NONE, RAD_NONE);
        }
    }
    (void)qd;
}

static void step_prompt(RadCtx* c, const RadBatch* batch, const Model& m) {
    const RadAudioGenBatch* A = batch->agen_b;
    const int64_t T = batch->n_tok, D = m.g.n_embd;
    RAD_ISSUE_N(c, m.op_embed, T, praw(batch->token_ids, RAD_I32, T), RAD_W(m.w_tok),
                brows(m.b_x, T));
    if (m.op_embed_ar) RAD_ISSUE_N(c, m.op_embed_ar, T * D, brows(m.b_x, T), RAD_NONE);
    step_trunk(c, batch, m);

    /* The lane: the prompt's last hidden state, an empty window, no unseen codes. */
    const int64_t S = batch->n_seq, lane = A->lane_h[0];
    RAD_ISSUE_N(c, m.op_plast, S, brows(m.a_h.x, T), praw(A->last_row, RAD_I32, S),
                brows(m.b_last, S));
    RAD_ISSUE_N(c, m.op_pstore, S, brows(m.b_last, S), praw(A->slot, RAD_I32, S),
                brows(m.b_hid, m.lanes));
    RAD_ISSUE_N(c, m.op_uzero, 1, brow_slice(m.b_u, lane, 1, D));
    {
        RadOperand w = brow_slice(m.b_ras, lane, 1, kRasWin);
        RAD_ISSUE_N(c, m.op_rasinit, kRasWin, w);
    }

    /* The tower over every prompt row: the label of each is text, so every code embedding is 0.
     * The last row's pass is FRAME 0's, which writes its cache rows again. */
    const RadKVGroupBatch* kvb = kv_batch(batch, m.kv_full);
    RAD_ISSUE_N(c, m.op_efill, T, bcol(m.b_tcat, 0, D, T));
    TowerAt at{};
    at.R = T;
    at.max_q = batch->max_q_len;
    at.pos = praw(batch->positions, RAD_I32, T);
    at.slot = praw(kvb->slot_mapping, RAD_I32, T);
    at.bt = praw2(kvb->block_table, RAD_I32, batch->n_seq, kvb->block_table_pitch);
    at.used = praw(kvb->seqused, RAD_I32, batch->n_seq);
    at.cu = praw(batch->cu_seqlens, RAD_I32, batch->n_seq + 1);
    at.h0 = m.a_h.x;
    step_tower(c, m, at);
}

static void step_frame(RadCtx* c, const RadBatch* batch, const Model& m) {
    const RadAudioGenBatch* A = batch->agen_b;
    const int64_t S = A->n_lane, Sx = m.lanes;
    const RadOperand seed = praw(A->seed, RAD_U32, 2 * S), frame = praw(A->frame, RAD_I32, S);
    const RadOperand lanes = praw(A->lane, RAD_I32, S), slot = praw(A->slot, RAD_I32, S);
    auto code = [&](int k) {
        RadOperand o = brow_slice(m.b_codes, k, 1, Sx);
        o.cols = S;
        return o;
    };

    /* 1. the main token, from the hidden state of the row before the frame's */
    RAD_ISSUE_N(c, m.op_hsel, S, brows(m.b_hid, m.lanes), slot, brows(m.b_plane, S));
    RAD_ISSUE_N(c, m.op_head, S, brows(m.b_plane, S), RAD_W(m.w_cand), brows(m.b_slog, S));
    RAD_ISSUE_N(c, m.op_samp, S, brows(m.b_slog, S), seed, frame, brows(m.b_first, S), RAD_NONE,
                RAD_NONE, RAD_NONE);
    RAD_ISSUE_N(c, m.op_samp_ras, S, brows(m.b_slog, S), seed, frame, brows(m.b_alt, S),
                RAD_NONE, RAD_NONE, RAD_NONE);
    RAD_ISSUE_N(c, m.op_ras, S, brows(m.b_first, S), brows(m.b_alt, S), lanes,
                brows(m.b_ras, m.lanes), code(0));
    RAD_ISSUE_N(c, m.op_status, S, code(0), lanes, brows(m.b_status, m.lanes));
    RAD_ISSUE_N(c, m.op_ugather, S, brows(m.b_u, m.lanes), slot, brows(m.b_ug, S));

    /* 2. the tower at that row: its position, slot and context, the frame's own sequences */
    const RadKVGroupBatch* kvb = kv_batch(batch, m.kv_full);
    TowerAt at{};
    at.R = S;
    at.max_q = 1;
    at.pos = praw(A->prev_pos, RAD_I32, S);
    at.slot = praw(A->prev_slot, RAD_I32, S);
    at.bt = praw2(kvb->block_table, RAD_I32, batch->n_seq, kvb->block_table_pitch);
    at.used = praw(A->prev_used, RAD_I32, S);
    at.cu = praw(batch->cu_seqlens, RAD_I32, batch->n_seq + 1);
    at.h0 = m.b_plane;
    at.frame = true;
    at.seed = seed;
    at.fidx = frame;
    step_tower(c, m, at);

    /* 3. the frame into the lane's history and the lane's unseen codes; the backbone over its
     * embedding at the frame's own row */
    RAD_ISSUE_N(c, m.op_store, S, bcol_at(m.b_codes, 0, Sx, 0, S, kCodes), lanes, frame,
                brows(m.b_status, m.lanes), brows(m.b_hist, m.lanes * kCodes));
    RadOperand sec2 = RAD_W(m.w_cb), sec3 = RAD_W(m.w_cb), sec1 = RAD_W(m.w_cb);
    const int64_t D = m.g.n_embd;
    sec1.rows = kVocab;
    sec2.offset = kVocab * D;
    sec2.rows = kVocab;
    sec3.offset = 2 * kVocab * D;
    sec3.rows = (kCodes - 3) * kVocab;
    RAD_ISSUE_N(c, m.op_u, S, bcol_at(m.b_codes, 2, Sx, 0, S, kCodes - 2), sec2, sec3,
                brows(m.b_unew, S));
    RAD_ISSUE_N(c, m.op_uscat, S, brows(m.b_unew, S), slot, brows(m.b_u, m.lanes));
    RAD_ISSUE_N(c, m.op_fb, S, bcol_at(m.b_codes, 0, Sx, 0, S, 2), RAD_W(m.w_cemb), sec1,
                brows(m.b_x, S));
    step_trunk(c, batch, m);
    RAD_ISSUE_N(c, m.op_fstore, S, brows(m.a_h.x, S), slot, brows(m.b_hid, m.lanes));
}

static void step_vocode(RadCtx* c, const RadBatch* batch, const Model& m) {
    const RadAudioGenBatch* A = batch->agen_b;
    const int64_t nl = A->voc_latents, n = nl - A->voc_left, L = A->voc_lane;
    const int64_t qd = kCtHeads * kCtHeadDim;
    /* The convolutions run over the last kConvFrames frames, or all of them when fewer. */
    const int64_t nc = std::min<int64_t>(nl, kConvFrames), c0 = nl - nc;
    const RadOperand nlen = praw(batch->cu_seqlens + 1, RAD_I32, 1);
    const RadOperand clen = nc == nl ? nlen : brows(m.b_cconst, 1);

    /* 1. the bounds at each rate: the transformer's frames, then the convolutions' */
    if (nc != nl) RAD_ISSUE_N(c, m.op_cnst, 1, brows(m.b_cconst, 1));
    RAD_ISSUE_N(c, m.op_ccu[0], 2, nlen, brows(m.b_ccu[0], 2));
    for (int s = 1; s < kRates; ++s) RAD_ISSUE_N(c, m.op_ccu[s], 2, clen, brows(m.b_ccu[s], 2));

    /* 2. the codes, dequantised: the lane's frames [voc_frame0, + nl) of each codebook */
    for (int k = 0; k < kCodes; ++k) {
        RadOperand codes = bcol_at(m.b_hist, L * kCodes + k, kMaxFrames, A->voc_frame0, nl, 1);
        RAD_ISSUE_N(c, m.op_rq[k], nl, codes, RAD_W(m.w_cbk[k]), RAD_W(m.w_cbk[k]),
                    brows(m.b_rq, nl));
        RAD_ISSUE_N(c, m.qo[k].op, nl, brows(m.b_rq, nl), RAD_W(m.qo[k].w), brows(m.b_ccu[0], 2),
                    k == 0 ? RAD_NONE : brows(m.b_cx, nl), brows(m.b_cx, nl), RAD_W(m.qo[k].b));
    }

    /* 3. the transformer over every frame of the pass */
    const RadOperand pos = praw(batch->positions, RAD_I32, nl);
    const RadOperand cu = brows(m.b_ccu[0], 2);
    for (const CodecLayer& Ly : m.ct) {
        RAD_ISSUE_N(c, Ly.op_n1, nl, brows(m.b_cx, nl), RAD_W(Ly.w_n1), brows(m.b_ch, nl));
        RAD_ISSUE_N(c, Ly.op_qkv, nl, brows(m.b_ch, nl), RAD_W(Ly.w_qkv), brows(m.b_cqkv, nl));
        RAD_ISSUE_N(c, Ly.op_rope, nl, brows(m.b_cqkv, nl), pos);
        RAD_ISSUE_N(c, Ly.op_attn, nl, bcol(m.b_cqkv, 0, qd, nl), bcol(m.b_cqkv, qd, qd, nl),
                    bcol(m.b_cqkv, 2 * qd, qd, nl), cu, brows(m.b_cattn, nl));
        RAD_ISSUE_N(c, Ly.op_o, nl, brows(m.b_cattn, nl), RAD_W(Ly.w_o), brows(m.b_co, nl));
        RAD_ISSUE_N(c, Ly.op_ls1, nl, brows(m.b_co, nl), RAD_W(Ly.w_ls1), brows(m.b_co, nl));
        RAD_ISSUE_N(c, Ly.op_add1, nl, brows(m.b_cx, nl), brows(m.b_co, nl), brows(m.b_cx, nl));
        RAD_ISSUE_N(c, Ly.op_n2, nl, brows(m.b_cx, nl), RAD_W(Ly.w_n2), brows(m.b_ch, nl));
        RAD_ISSUE_N(c, Ly.op_gu, nl, brows(m.b_ch, nl), RAD_W(Ly.w_gu), brows(m.b_cgu, nl));
        RAD_ISSUE_N(c, Ly.op_act, nl, brows(m.b_cgu, nl), brows(m.b_cff, nl));
        RAD_ISSUE_N(c, Ly.op_down, nl, brows(m.b_cff, nl), RAD_W(Ly.w_down), brows(m.b_co, nl));
        RAD_ISSUE_N(c, Ly.op_ls2, nl, brows(m.b_co, nl), RAD_W(Ly.w_ls2), brows(m.b_co, nl));
        RAD_ISSUE_N(c, Ly.op_add2, nl, brows(m.b_cx, nl), brows(m.b_co, nl), brows(m.b_cx, nl));
    }
    RAD_ISSUE_N(c, m.op_cn, nc, brow_slice(m.b_cx, c0, nc, kLat), RAD_W(m.w_cn),
                brows(m.b_ux[0], nc));

    /* 4. the upsamplings, at 2 and 4 rows a frame */
    for (int i = 0; i < 2; ++i) {
        const Upsample& U = m.up[i];
        const int64_t rin = nc << i, rout = nc << (i + 1);
        RAD_ISSUE_N(c, U.op_t, rin, brows(m.b_ux[i], rin), RAD_W(U.w_t), RAD_W(U.b_t),
                    brows(m.b_ccu[1 + i], 2), brows(m.b_ux[i + 1], rout));
        RAD_ISSUE_N(c, U.op_dw, rout, brows(m.b_ux[i + 1], rout), RAD_W(U.w_dw),
                    brows(m.b_ccu[2 + i], 2), brows(m.b_ua, rout), RAD_W(U.b_dw));
        RAD_ISSUE_N(c, U.op_ln, rout, brows(m.b_ua, rout), RAD_W(U.w_ln), RAD_W(U.b_ln),
                    brows(m.b_ub, rout));
        RAD_ISSUE_N(c, U.op_p1, rout, brows(m.b_ub, rout), RAD_W(U.w_p1), RAD_W(U.b_p1), RAD_NONE,
                    brows(m.b_uh, rout));
        RAD_ISSUE_N(c, U.op_gelu, rout, brows(m.b_uh, rout), brows(m.b_ug2, rout));
        RAD_ISSUE_N(c, U.op_p2, rout, brows(m.b_ug2, rout), RAD_W(U.w_p2), RAD_W(U.b_p2),
                    RAD_NONE, brows(m.b_ua, rout));
        RAD_ISSUE_N(c, U.op_g, rout, brows(m.b_ua, rout), RAD_W(U.w_g), brows(m.b_ua, rout));
        RAD_ISSUE_N(c, U.op_add, rout, brows(m.b_ux[i + 1], rout), brows(m.b_ua, rout),
                    brows(m.b_ux[i + 1], rout));
    }

    /* 5. the decoder */
    int64_t rows[5];
    rows[0] = 4 * nc;
    for (int i = 0; i < 4; ++i) rows[i + 1] = rows[i] * m.v_ups[i];
    auto conv = [&](const VConv& v, rad_buf x, rad_buf res, rad_buf y, int64_t R, rad_buf cub) {
        RAD_ISSUE_N(c, v.op, R, brows(x, R), RAD_W(v.w), brows(cub, 2),
                    res ? brows(res, R) : RAD_NONE, brows(y, R), RAD_W(v.b));
    };
    conv(m.dec0, m.b_ux[2], 0, m.b_vs[0], rows[0], m.b_ccu[3]);
    for (int i = 0; i < 4; ++i) {
        const VBlock& B = m.vb[i];
        const int64_t r0 = rows[i], r1 = rows[i + 1];
        RAD_ISSUE_N(c, B.op_s, r0, brows(m.b_vs[i], r0), RAD_W(B.a), brows(m.b_vt[i], r0),
                    RAD_NONE);
        RAD_ISSUE_N(c, B.op_t, r0, brows(m.b_vt[i], r0), RAD_W(B.wt), RAD_W(B.bt),
                    brows(m.b_ccu[3 + i], 2), brows(m.b_vs[i + 1], r1));
        for (int r = 0; r < 3; ++r) {
            const VRes& U = B.res[r];
            RAD_ISSUE_N(c, U.op_s1, r1, brows(m.b_vs[i + 1], r1), RAD_W(U.a1),
                        brows(m.b_vt[i + 1], r1), RAD_NONE);
            conv(U.c1, m.b_vt[i + 1], 0, m.b_va[i + 1], r1, m.b_ccu[4 + i]);
            RAD_ISSUE_N(c, U.op_s2, r1, brows(m.b_va[i + 1], r1), RAD_W(U.a2),
                        brows(m.b_vb[i + 1], r1), RAD_NONE);
            conv(U.c2, m.b_vb[i + 1], m.b_vs[i + 1], m.b_vs[i + 1], r1, m.b_ccu[4 + i]);
        }
    }
    RAD_ISSUE_N(c, m.op_fs, rows[4], brows(m.b_vs[4], rows[4]), RAD_W(m.w_fa),
                brows(m.b_vt[4], rows[4]), RAD_NONE);
    conv(m.fin, m.b_vt[4], 0, m.b_vout, rows[4], m.b_ccu[7]);
    /* 6. the chunk's own samples: its last n frames */
    const int64_t ns = n * kSamplesPerFrame;
    RAD_ISSUE_N(c, m.op_fcast, ns, brow_slice(m.b_vout, rows[4] - ns, ns, 1), brows(m.b_audio, ns));
}

static void step(RadCtx* c, const RadBatch* batch) {
    const Model& m = g_model[rad_rank(c)];
    if (!batch->gen || !batch->agen_b) {
        rad_step_fail(c, "fishomni is an audio generator and runs generator passes only");
        return;
    }
    switch (batch->gen) {
    case RAD_GEN_PASS_PROMPT: step_prompt(c, batch, m); return;
    case RAD_GEN_PASS_FRAME:  step_frame(c, batch, m); return;
    case RAD_GEN_PASS_VOCODE: step_vocode(c, batch, m); return;
    default:
        rad_step_fail(c, "fishomni: a generator pass of a kind this plugin does not know");
    }
}

/* ================================================================== the probe */
static int probe(const RadModelMeta* meta, RadArchProbe* out) {
    if (!meta || !out) return RAD_E_INVAL;
    out->gen_rows = kMaxPrompt;
    out->gen_audio = 1;
    out->gen_ctx = kMaxPrompt + kMaxFrames + 1;
    return RAD_OK;
}

/* ================================================================== the request's text */
/* A Unicode White_Space code point's length at `s`, else 0. Python's str.strip() without
 * arguments also strips U+001C..U+001F, which fish-speech avoids (generate.py,
 * UNICODE_WHITE_SPACE); so does this. */
static size_t white_space_at(const unsigned char* s, size_t n) {
    if (n >= 1 && ((s[0] >= 0x09 && s[0] <= 0x0D) || s[0] == 0x20)) return 1;
    if (n >= 2 && s[0] == 0xC2 && (s[1] == 0x85 || s[1] == 0xA0)) return 2;
    if (n >= 3 && s[0] == 0xE1 && s[1] == 0x9A && s[2] == 0x80) return 3;           /* U+1680 */
    if (n >= 3 && s[0] == 0xE2 && s[1] == 0x80 &&
        ((s[2] >= 0x80 && s[2] <= 0x8A) || s[2] == 0xA8 || s[2] == 0xA9 || s[2] == 0xAF))
        return 3;                                          /* U+2000..200A, 2028, 2029, 202F */
    if (n >= 3 && s[0] == 0xE2 && s[1] == 0x81 && s[2] == 0x9F) return 3;           /* U+205F */
    if (n >= 3 && s[0] == 0xE3 && s[1] == 0x80 && s[2] == 0x80) return 3;           /* U+3000 */
    return 0;
}

/* The length of a canonical speaker tag at `s` (`<|speaker:N|>`, N 0..15 without a leading
 * zero), else 0. */
static size_t speaker_tag_at(const char* s, size_t n) {
    static const char kHead[] = "<|speaker:";
    const size_t h = sizeof kHead - 1;
    if (n < h || std::strncmp(s, kHead, h) != 0) return 0;
    size_t i = h;
    while (i < n && s[i] >= '0' && s[i] <= '9') ++i;
    const size_t digits = i - h;
    if (digits == 0 || digits > 2 || i + 1 >= n || s[i] != '|' || s[i + 1] != '>') return 0;
    if (digits == 2 && s[h] == '0') return 0;
    const int v = digits == 1 ? s[h] - '0' : (s[h] - '0') * 10 + (s[h + 1] - '0');
    return v <= 15 ? i + 2 : 0;
}

static int64_t refuse(char* out, int64_t cap, const char* why) {
    if (out && cap > 0) std::snprintf(out, (size_t)cap, "%s", why);
    return RAD_E_INVAL;
}

/* `s` without the Unicode White_Space at either end. */
static std::string strip_white(const std::string& s) {
    const unsigned char* u = (const unsigned char*)s.data();
    size_t a = 0, z = s.size();
    for (size_t w; a < z && (w = white_space_at(u + a, z - a)) > 0;) a += w;
    /* From the back: a White_Space code point is one to three bytes, so try each ending. */
    for (bool more = true; more && z > a;) {
        more = false;
        for (size_t w = 1; w <= 3 && w <= z - a; ++w)
            if (white_space_at(u + z - w, w) == w) {
                z -= w;
                more = true;
                break;
            }
    }
    return s.substr(a, z - a);
}

/* What fish-speech's server hands the model (chunking.py, split_drama3_text): each speaker's turn
 * as "<|speaker:N|> " and its text stripped of white space at both ends, turns joined by a newline,
 * text before the first tag speaker 0's; untagged text stripped and given speaker 0
 * (generate.py, with_speaker_tag). Its model was trained on that form: the same two turns joined
 * by a space instead are spoken through less often. `r` is validated already. */
static std::string speaker_turns(const std::string& r) {
    if (r.find("<|speaker") == std::string::npos) return "<|speaker:0|> " + strip_white(r);
    std::string outs, id = "0";
    size_t at = 0;
    auto turn = [&](const std::string& who, size_t a, size_t z) {
        const std::string body = strip_white(r.substr(a, z - a));
        if (body.empty()) return;
        if (!outs.empty()) outs += "\n";
        outs += "<|speaker:" + who + "|> " + body;
    };
    for (size_t t = r.find("<|speaker"); t != std::string::npos;) {
        turn(id, at, t);
        const size_t len = speaker_tag_at(r.data() + t, r.size() - t);
        id = r.substr(t + 10, len - 12);      /* the digits between "<|speaker:" and "|>" */
        at = t + len;
        t = r.find("<|speaker", at);
    }
    turn(id, at, r.size());
    return outs;
}

/* generate.py's validate_drama3_text: the input is not empty, holds none of the tokens only the
 * prompt builder writes, and names speakers only as <|speaker:0|> to <|speaker:15|>; then its
 * speaker turns are written as the reference's server writes them (speaker_turns). */
static int64_t text_prepare(int field, const char* in, char* out, int64_t cap) {
    if (!in) return RAD_E_INVAL;
    std::string r = in;
    if (field == RAD_TEXT_INPUT) {
        const unsigned char* u = (const unsigned char*)r.data();
        const size_t n = r.size();
        size_t lead = 0;
        for (size_t w; lead < n && (w = white_space_at(u + lead, n - lead)) > 0;) lead += w;
        bool blank = true;
        for (size_t i = lead; i < n && blank;) {
            const size_t w = white_space_at(u + i, n - i);
            if (w == 0) blank = false;
            else i += w;
        }
        if (blank) return refuse(out, cap, "the input is empty: there is nothing to speak");
        static const char* kStructural[] = { "<|im_start|>", "<|im_end|>", "<|voice|>",
                                             "<|text|>", "<|interleave|>", "<|semantic:" };
        for (const char* t : kStructural)
            if (r.find(t) != std::string::npos) {
                char why[128];
                std::snprintf(why, sizeof why, "%s is written by the prompt builder, not the input",
                              t);
                return refuse(out, cap, why);
            }
        for (size_t at = r.find("<|speaker"); at != std::string::npos;
             at = r.find("<|speaker", at + 1))
            if (!speaker_tag_at(r.data() + at, n - at))
                return refuse(out, cap, "speaker tags are <|speaker:0|> to <|speaker:15|>");
        r = speaker_turns(r);
        if (r.empty()) return refuse(out, cap, "the input is empty: there is nothing to speak");
    }
    if ((int64_t)r.size() < cap) {
        std::memcpy(out, r.data(), r.size());
        out[r.size()] = 0;
    }
    return (int64_t)r.size();
}

}  /* namespace fishomni */

#ifndef RAD_ARCH_NO_EXPORTS
RAD_ARCH_PROBE(fishomni)
extern "C" int64_t rad_arch_text_prepare(int field, const char* in, char* out, int64_t cap) {
    return fishomni::text_prepare(field, in, out, cap);
}
RAD_ARCH_PLUGIN(fishomni, "fishomni", "bsgemm-moe", "0.1.0",
                "Fish Audio drama-3: the Qwen3.5-35B-A3B backbone (block-scaled fp8 experts), a "
                "13-layer codebook tower over its full-attention cache, and Fish S2's modified "
                "DAC; 44.1 kHz mono speech")
#endif
