/* kv.cpp -- see kv.h. */
#include "mem/kv.h"

#include "kvstream/carve.h"
#include "kvstream/plan.h"

#include <algorithm>
#include <cassert>
#include <cstring>

namespace rad {

const std::vector<int32_t> KVManager::kNoBlocks;

/* ------------------------------------------------------------------ group sizing */

static int64_t ceil_div(int64_t a, int64_t b) { return b > 0 ? (a + b - 1) / b : 0; }

BundleComparison compare_bundling(const std::vector<int64_t>& bundles) {
    BundleComparison c;
    c.bundles = bundles;
    if (bundles.empty()) return c;

    auto groups = [&](int64_t g) {
        int64_t n = 0; for (int64_t b : bundles) n += ceil_div(b, g); return n;
    };
    auto slots = [&](int64_t g) {
        int64_t n = 0; for (int64_t b : bundles) n += ceil_div(b, g) * g; return n;
    };

    const int64_t lo = *std::min_element(bundles.begin(), bundles.end());
    const int64_t hi = *std::max_element(bundles.begin(), bundles.end());

    /* vLLM's rule: the smallest bundle, or the largest when they are within 1.5x
     * (gpt-oss-20b + eagle is 12 sw + 13 full, and padding to (13,13) beats (12,24)). */
    c.stock_group_size = (hi * 2 < lo * 3) ? hi : lo;
    c.stock_groups = groups(c.stock_group_size);
    c.stock_slots  = slots(c.stock_group_size);

    /* Least waste under the same scheme: fewest slots, then fewest groups, capped at the stock
     * group count (without the cap size 1 always wins and multiplies per-group bookkeeping). */
    const int64_t cap = c.stock_groups;
    int64_t best = c.stock_group_size;
    for (int64_t g = 1; g <= hi; ++g) {
        if (groups(g) > cap) continue;
        if (std::pair<int64_t,int64_t>{slots(g), groups(g)} <
            std::pair<int64_t,int64_t>{slots(best), groups(best)}) best = g;
    }
    c.patched_group_size = best;
    c.patched_groups = groups(best);
    c.patched_slots  = slots(best);

    /* Ours: one group per state kind, each with its own pool, so no padding. */
    c.our_groups = (int64_t)bundles.size();
    c.our_slots  = 0; for (int64_t b : bundles) c.our_slots += b;
    return c;
}

std::string BundleComparison::report() const {
    std::string b;
    for (size_t i = 0; i < bundles.size(); ++i)
        b += fmt("%s%lld", i ? "/" : "", (long long)bundles[i]);
    return fmt("KV layer bundles %s (%lld real layers)\n"
               "    vLLM stock    size %2lld -> %2lld groups, %3lld slots (%lld padding)\n"
               "    least-waste   size %2lld -> %2lld groups, %3lld slots (%lld padding)\n"
               "    radiance      per state kind, own pool -> %2lld groups, %3lld slots (0 padding)\n",
               b.c_str(), (long long)our_slots,
               (long long)stock_group_size, (long long)stock_groups, (long long)stock_slots,
               (long long)(stock_slots - our_slots),
               (long long)patched_group_size, (long long)patched_groups, (long long)patched_slots,
               (long long)(patched_slots - our_slots),
               (long long)our_groups, (long long)our_slots);
}

/* ------------------------------------------------------------------ configure */

const char* kv_kind_name(int k) {
    switch (k) {
        case RAD_KV_FULL:   return "full";
        case RAD_KV_WINDOW: return "window";
        case RAD_KV_LINEAR: return "linear";
        case RAD_KV_CONV:   return "conv";
        case RAD_KV_RING:   return "ring";
        default:            return "?";
    }
}

/* plan_groups() fills plans_ and fixed_ without a pool; carve() spends a pool against them. See
 * kv.h for why they are separate. */
int KVManager::configure(const std::vector<KVGroupInfo>& groups, const Config& cfg,
                         Pool& kv_pool) {
    RAD_TRY(plan_groups(groups, cfg));
    return carve(kv_pool);
}

int KVManager::plan_groups(const std::vector<KVGroupInfo>& groups, const Config& cfg) {
    /* Kept only to warn that the flag is ignored on a model with no recurrent state (the engine
     * opens the host slots, see set_checkpoint_store). Only an explicitly passed flag counts, so
     * the default does not warn. */
    const int64_t budget_ckpts = cfg.given.count("--checkpoint-slots") && cfg.checkpoint_slots > 0
                                     ? cfg.checkpoint_slots : 0;

    forget();
    max_seqs_ = cfg.max_seqs > 0 ? cfg.max_seqs : 1;
    max_ctx_  = cfg.max_ctx > 0 ? cfg.max_ctx : 0;
    max_tok_  = cfg.max_tok > 0 ? cfg.max_tok : 0;

    if (groups.empty()) {
        RAD_ERR("KV manager: no KV groups were declared; the architecture plugin declares at "
                "least one (spec §7.2)");
        return RAD_E_INVAL;
    }

    std::vector<int64_t> bundles;
    for (size_t i = 0; i < groups.size(); ++i) {
        /* Handle 0 is the null group: the builder reserves slot 0 of every handle table so a zero
         * handle means "none" (rad_builder.cpp). A placeholder is pushed rather than skipped,
         * because plan() indexes plans_ by handle; with 0 blocks and 0 states it is inert. */
        if (i == 0) {
            KVGroupPlan null_plan;
            null_plan.index = 0;
            null_plan.name  = "(none)";
            /* Not the default RAD_KV_FULL: -1 makes paged() and stateful() both false, so no loop
             * takes the paged branch and divides by a zero block size. */
            null_plan.kind  = -1;
            plans_.push_back(std::move(null_plan));
            /* Not in `bundles`, which would report it as the smallest real bundle. */
            continue;
        }
        const KVGroupInfo& g = groups[i];
        KVGroupPlan p;
        p.index    = (int32_t)i;
        p.name     = g.name.empty() ? fmt("kv%zu", i) : g.name;
        /* R-SWA: RAD_KV_RING is a window group whose floor is per sequence (declare_runtime_window
         * / SeqWindow), so it plans as a RAD_KV_WINDOW group with `runtime_win` set below. No
         * other plan-path code has to know the kind. */
        p.kind     = g.decl.kind == RAD_KV_RING ? RAD_KV_WINDOW : g.decl.kind;
        p.n_layers = (int64_t)g.layers.size();
        p.dense_read = g.dense_read;

        if (p.n_layers <= 0) {
            RAD_ERR("KV group '%s': no layers are bound to it, so its page size is unknown "
                    "(rad_bind_layer_kv)", p.name.c_str());
            return RAD_E_INVAL;
        }
        const int64_t elt = rad_dtype_bytes(g.decl.dtype, 1);
        if (elt <= 0) {
            RAD_ERR("KV group '%s': dtype %u has no core-known size", p.name.c_str(), g.decl.dtype);
            return RAD_E_DTYPE;
        }
        bundles.push_back(p.n_layers);

        if (p.kind == RAD_KV_FULL || p.kind == RAD_KV_WINDOW) {
            p.block_size = g.block_size;
            if (p.block_size <= 0) {
                RAD_ERR("KV group '%s': block size is 0. It comes off the resolved attention "
                        "kernel's constraints at declare, never from a core constant (spec §7.2) "
                        "-- so a 0 here means the attention op for this group did not resolve.",
                        p.name.c_str());
                return RAD_E_NOKERNEL;
            }
            /* One page covers every layer bound to the group. */
            p.bytes_per_block = g.bytes_per_block > 0
                ? g.bytes_per_block
                : p.block_size * g.decl.n_head_kv * g.decl.head_dim * elt * 2 * p.n_layers;
            if (p.bytes_per_block <= 0) {
                RAD_ERR("KV group '%s': page size computes to 0 (n_head_kv=%lld head_dim=%lld)",
                        p.name.c_str(), (long long)g.decl.n_head_kv, (long long)g.decl.head_dim);
                return RAD_E_INVAL;
            }
            if (p.kind == RAD_KV_WINDOW) {
                if (g.decl.window <= 0) {
                    RAD_ERR("KV group '%s': %s with window 0", p.name.c_str(),
                            g.decl.kind == RAD_KV_RING ? "RAD_KV_RING (the ring's W)"
                                                       : "RAD_KV_WINDOW");
                    return RAD_E_INVAL;
                }
                /* +1 because a window that is not block-aligned straddles one extra block. */
                p.window_blocks = ceil_div(g.decl.window, p.block_size) + 1;
            }
        } else if (p.kind == RAD_KV_LINEAR || p.kind == RAD_KV_CONV) {
            if (p.kind == RAD_KV_CONV) {
                /* A rolling window of conv_width-1 + n_spec entries, so a speculative rejection is
                 * a read-offset change rather than a recompute (spec §10). */
                p.conv_slots = conv_window_entries(g.decl, cfg.n_spec);
                if (p.conv_slots <= 0) {
                    RAD_ERR("KV group '%s': conv_width %lld with n_spec %d gives 0 slots",
                            p.name.c_str(), (long long)g.decl.conv_width, cfg.n_spec);
                    return RAD_E_INVAL;
                }
                p.bytes_per_state = g.bytes_per_state > 0
                    ? g.bytes_per_state
                    : p.conv_slots * g.decl.n_head_kv * g.decl.head_dim * elt * p.n_layers;
            } else {
                p.bytes_per_state = g.bytes_per_state > 0
                    ? g.bytes_per_state
                    : g.decl.n_head_kv * g.decl.state_dim[0] * g.decl.state_dim[1] * elt
                      * p.n_layers;
                /* Speculation: a verify folds 1 + n_spec tokens into the state before acceptance
                 * is known (see KVGroupPlan::state_copies). One state per candidate would cost
                 * gigabytes a sequence. libr4d instead keeps one committed state plus each token's
                 * rank-1 update factors (normalised k, v, decay, beta): RU_TMAX *
                 * (4*head_k + head_v + 8) floats a head against head_v * head_k for the state, so
                 * they fit in a second slot, and the next step replays the accepted prefix from
                 * them. The engine zeroes both slots when handed out (a zero factor replays as the
                 * identity) and makes state_index wide enough to name them. */
                p.state_copies = cfg.n_spec > 0 ? 2 : 1;
            }
            if (p.bytes_per_state <= 0) {
                RAD_ERR("KV group '%s': per-sequence state computes to 0", p.name.c_str());
                return RAD_E_INVAL;
            }
            /* The kernels lay slots out from the state tensor ([n_states, channels, conv_slots]
             * or [n_states, n_head_kv, state_dim]); this manager clears, saves and restores them
             * by bytes_per_state. The two sizes must match or those touch a neighbour's state. */
            const int64_t indexed =
                (p.kind == RAD_KV_CONV
                     ? p.conv_slots * g.decl.n_head_kv * g.decl.head_dim
                     : g.decl.n_head_kv * g.decl.state_dim[0] * g.decl.state_dim[1])
                * elt * p.n_layers;
            if (p.bytes_per_state != indexed) {
                RAD_ERR("KV group '%s': %lld bytes a sequence are allocated, and the state the "
                        "kernels index is %lld bytes over its %lld layers -- the slot this manager "
                        "clears, checkpoints and restores would not be the slot the kernels read",
                        p.name.c_str(), (long long)p.bytes_per_state, (long long)indexed,
                        (long long)p.n_layers);
                return RAD_E_SHAPE;
            }
            /* One logical state per concurrent sequence, times the copies the kernel needs. */
            p.n_states = max_seqs_ * p.state_copies;
        } else {
            RAD_ERR("KV group '%s': unknown kind %d", p.name.c_str(), p.kind);
            return RAD_E_INVAL;
        }
        /* A zero group costs this rank nothing. Validation above ran on the real sizes, which
         * other ranks still use. */
        if (g.zero) {
            p.zero = true;
            p.bytes_per_block = 0;
            p.bytes_per_state = 0;
        }
        p.replicated = g.replicated && p.paged() && !g.zero;
        plans_.push_back(std::move(p));
    }
    bundling_ = compare_bundling(bundles);

    /* R-SWA: a declared runtime window turns the group's plan over to per-sequence windows (see
     * declare_runtime_window). Applied after every declaration above, so a fixed-window group's
     * plan is exactly what it was. */
    for (auto& p : plans_) apply_runtime_window(p);
    /* A RAD_KV_RING group carries a runtime window by its kind, whether or not the caller had a
     * manager to declare it on first (the engine's sizing probes declare it, but plan_groups must
     * not depend on that). `window` is the ring's W. */
    for (size_t i = 1; i < plans_.size(); ++i) {
        KVGroupPlan& p = plans_[i];
        if (groups[i].decl.kind != RAD_KV_RING || p.runtime_win) continue;
        p.runtime_win    = true;
        p.runtime_tokens = groups[i].decl.window;
        p.win_snap       = false;
    }
    for (const auto& [g, w] : runtime_decl_) {
        if (g < 0 || g >= (int32_t)plans_.size() || !plans_[(size_t)g].runtime_win) {
            RAD_ERR("declare_runtime_window(%d): the group is not a RAD_KV_WINDOW or RAD_KV_RING "
                    "group in this program (a runtime window needs a windowed group)", (int)g);
            return RAD_E_INVAL;
        }
    }

    /* ---- fixed costs first: they are not per-token ---- */
    checkpoint_bytes_ = 0;
    window_ck_bytes_ = 0;
    for (const auto& p : plans_) if (p.stateful()) checkpoint_bytes_ += p.bytes_per_state;
    /* Then the window behind a checkpoint, after the linear state (see has_window_snapshot). A
     * trunk's window rides in the slot whether or not linear state is beside it: a hit resumes at
     * a snapshot either way, and without the window there it could not resume at all. */
    for (size_t i = 1; i < plans_.size(); ++i) {
        KVGroupPlan& p = plans_[i];
        p.win_snap = p.kind == RAD_KV_WINDOW && p.window_blocks > 0 &&
                     !p.runtime_win && !groups[i].drafter;
        if (p.win_snap && !p.zero && p.n_layers > 0)
            window_ck_bytes_ += p.window_blocks * p.bytes_per_block;
    }
    checkpoint_bytes_ += window_ck_bytes_;

    /* The pool pads every reserve() call to RAD_ALIGN_UNIT, so the fixed costs are padded per
     * reservation too. Raw bytes would let the paged split spend the padding and the last
     * reservation would not fit. */
    int64_t fixed = 0;
    for (const auto& p : plans_)
        if (p.stateful()) fixed += align_up(p.bytes_per_state * p.n_states, RAD_ALIGN_UNIT);
    /* And one unit per paged group, whose size need not be a multiple of the alignment. */
    for (const auto& p : plans_) if (p.paged()) fixed += RAD_ALIGN_UNIT;
    /* A runtime window's ring is per sequence and on top of the context the split sizes: one
     * ring a sequence, carved as a fixed cost. Its reference is the context itself, which the
     * split already covers (the group is not capped at window_blocks). */
    for (const auto& p : plans_)
        if (p.runtime_win && !p.zero)
            fixed += align_up(max_seqs_ * p.ring_blocks_max() * p.bytes_per_block, RAD_ALIGN_UNIT);

    fixed_ = fixed;
    ckpts_ = budget_ckpts;
    return RAD_OK;
}

/* Windowed groups are capped at window_pool_cap, as in carve(). A runtime-window group is not:
 * its blocks are the reference (one context a sequence, as a FULL group) plus the ring its fixed
 * costs already carry. */
int64_t KVManager::ceiling(int64_t ctx) const {
    if (ctx <= 0) return 0;
    int64_t need = fixed_;
    for (const auto& p : plans_) {
        if (!p.paged() || p.block_size <= 0) continue;
        int64_t blocks = max_seqs_ * ((ctx + p.block_size - 1) / p.block_size);
        if (p.kind == RAD_KV_WINDOW && !p.runtime_win && p.window_blocks > 0)
            blocks = std::min(blocks, window_pool_cap(p));
        need += kv_ceiling_bytes(p, blocks, stream_.resident_blocks(p));
    }
    /* The streamed groups' maps come out of this pool too (kvstream/carve.h). */
    need += kvstream_maps_charged(plans_, stream_, ctx, max_seqs_);
    return need;
}

/* Moves a WINDOW group's plan to per-sequence runtime windows (declare_runtime_window). Returns
 * false for any other group, so plan_groups() can apply it to every plan unconditionally. */
bool KVManager::apply_runtime_window(KVGroupPlan& p) const {
    auto it = runtime_decl_.find(p.index);
    if (it == runtime_decl_.end() || p.kind != RAD_KV_WINDOW || p.runtime_win) return false;
    p.runtime_win = true;
    p.runtime_tokens = it->second;
    /* The window a sequence may inherit (a fixed-window cap) is no longer the bound, and the
     * declare-time window is not the sequence's own, so nothing here is snapshot-able. */
    p.win_snap = false;
    return true;
}

int KVManager::declare_runtime_window(int32_t g, int64_t window_tokens) {
    if (g <= 0 || window_tokens <= 0) {
        RAD_ERR("declare_runtime_window: group %d with a window of %lld (a runtime window needs a "
                "real group and a positive W)", (int)g, (long long)window_tokens);
        return RAD_E_INVAL;
    }
    const KVGroupPlan* p = plan(g);
    if (p && p->kind != RAD_KV_WINDOW) {
        RAD_ERR("group '%s' is not RAD_KV_WINDOW or RAD_KV_RING, so it cannot carry a runtime "
                "window", p->name.c_str());
        return RAD_E_INVAL;
    }
    if (p && p->runtime_win && p->runtime_tokens != window_tokens) {
        /* A RAD_KV_RING group's W is its declaration's `window`, and one already planned for
         * another W has its ring in the fixed costs. */
        RAD_ERR("declare_runtime_window(%d): group '%s' already carries a runtime window of %lld "
                "tokens, and its ring is sized for that", (int)g, p->name.c_str(),
                (long long)p->runtime_tokens);
        return RAD_E_INVAL;
    }
    if (configured_) {
        RAD_ERR("declare_runtime_window(%d) after the carve: the group's blocks and fixed costs "
                "are already sized for a different window", (int)g);
        return RAD_E_STATE;
    }
    runtime_decl_[g] = window_tokens;
    /* A plan built before the declaration (the engine's probes, or plan_groups() then declare)
     * is updated in place; the next plan_groups() picks the declaration up on its own.
     *
     * A plan set shorter than `g` returns RAD_E_INVAL below with this store kept: deliberate.
     * The declaration is the caller's standing intent (it survives forget(), whose vectors are
     * emptied together and are not this map), and the short plan set is the probe ordering the
     * declaration exists for -- the next plan_groups() applies it to a plan that has the group. */
    if (!plans_.empty()) {
        if (g >= (int32_t)plans_.size()) return RAD_E_INVAL;
        KVGroupPlan& q = plans_[(size_t)g];
        /* Whether the plan counted this group's window snapshot section (plan_groups' rule). */
        const bool counted = q.win_snap && !q.zero && q.n_layers > 0;
        if (!apply_runtime_window(q)) return RAD_OK;   /* already applied */
        /* The cost this declaration adds, against the plan as published: the ring is one a
         * sequence, and the group gives up its window snapshot section. */
        fixed_ += align_up(max_seqs_ * q.ring_blocks_max() * q.bytes_per_block, RAD_ALIGN_UNIT);
        if (counted) {
            const int64_t was = q.window_blocks * q.bytes_per_block;
            /* The plan counted this group's snapshot section, so both totals carry `was`.
             * Saturating hides an accounting bug; surface it in debug builds. */
            assert(window_ck_bytes_ >= was && checkpoint_bytes_ >= was &&
                   "runtime window: snapshot byte totals below the section being removed");
            window_ck_bytes_ = window_ck_bytes_ > was ? window_ck_bytes_ - was : 0;
            checkpoint_bytes_ = checkpoint_bytes_ > was ? checkpoint_bytes_ - was : 0;
        }
    }
    return RAD_OK;
}

int64_t KVManager::runtime_window_tokens(int32_t g) const {
    const KVGroupPlan* p = plan(g);
    return p && p->runtime_win ? p->runtime_tokens : 0;
}

/* The vectors parallel to plans_ are filled at different points of the carve, so a partial carve
 * would leave plans_ passing bounds checks (reserve_block checks plans_, then reads free_usable_)
 * over empty block state. On failure forget() empties both, so every entry point refuses
 * instead of reading out of bounds. */
int KVManager::carve(Pool& kv_pool) {
    const int rc = carve_into(kv_pool);
    if (rc < 0) forget();
    return rc;
}

void KVManager::forget() {
    plans_.clear(); free_blocks_.clear(); refcount_.clear(); free_states_.clear();
    live_.clear(); free_usable_.clear(); bucket_blocks_.clear(); held_hist_.clear();
    chunk_blocks_.clear(); short_peak_.clear();
    pool_ = nullptr;
    clears_.clear();
    seqs_.clear(); pending_.clear();
    configured_ = false;
    report_.clear();
}

int64_t KVManager::paged_split(int64_t budget_bytes, std::vector<int64_t>* blocks) const {
    /* Size the groups to run out at the same total token count (see configure). */
    std::vector<int64_t> out(plans_.size(), 0);
    int64_t remaining = budget_bytes - fixed_;
    /* Zero groups take no part in the split; they get the shared table's block count, which is
     * what the costed groups settle on here or, under the cap, on the ranks holding the cache. */
    std::vector<int32_t> open, zeros;
    bool dense = false;
    for (const auto& p : plans_) {
        if (!p.paged()) continue;
        if (p.zero) zeros.push_back(p.index);
        else if (kvstream_dense(p, plans_, stream_)) dense = true;   /* its carve is a floor */
        else if (!stream_.windowed(p.index)) open.push_back(p.index);
    }
    kvstream_split_windows(plans_, stream_, max_ctx_, max_seqs_, &remaining, &out);
    /* Every paged group is zero: this rank limits nothing, so take the cap, or report unbounded. */
    if (open.empty() && !zeros.empty()) {
        const int64_t tokens = tokens_cap_ > 0 ? tokens_cap_ : kUnboundedTokens;
        if (blocks) {
            for (int32_t i : zeros) out[i] = zero_blocks(plans_[i], tokens);
            *blocks = std::move(out);
        }
        return tokens;
    }

    int64_t tokens = 0;
    while (!open.empty() && remaining > 0) {
        double cost = 0;
        for (int32_t i : open)
            cost += (double)plans_[i].bytes_per_block / (double)plans_[i].block_size;
        if (cost <= 0) break;
        tokens = (int64_t)((double)remaining / cost);
        /* One block table serves every rank (Engine::serve checks it), so no rank carves more
         * than the least of them. */
        if (tokens_cap_ > 0 && tokens > tokens_cap_) tokens = tokens_cap_;

        /* A windowed group cannot address past its pool cap; cap it and give the bytes back to
         * the others. A runtime-window group's cap is the context plus its ring (a fixed cost). */
        int32_t capped = -1;
        for (int32_t i : open) {
            const auto& p = plans_[i];
            if (p.kind != RAD_KV_WINDOW || p.runtime_win) continue;
            if (tokens / p.block_size > window_pool_cap(p)) { capped = i; break; }
        }
        if (capped < 0) break;
        out[capped] = window_pool_cap(plans_[capped]);
        remaining -= out[capped] * plans_[capped].bytes_per_block;
        open.erase(std::find(open.begin(), open.end(), capped));
    }
    for (int32_t i : open) out[i] = remaining > 0 ? tokens / plans_[i].block_size : 0;
    for (int32_t i : zeros) out[i] = remaining > 0 ? zero_blocks(plans_[i], tokens) : 0;
    /* A dense-read group's floor is already charged; with no other open group the pool still pages
     * one full-length sequence, which is what the report and the admission cap see. */
    if (dense && open.empty() && remaining > 0) tokens = max_ctx_;
    if (blocks) *blocks = std::move(out);
    return tokens;
}

int64_t KVManager::pool_mib_for_tokens(int64_t tokens, int64_t max_mib) const {
    const int64_t MiB = (int64_t)1 << 20;
    if (max_mib <= 0) return -1;
    const auto reaches = [&](int64_t mib) {
        /* The fixed costs come first on every rank, even one whose paged groups are all zero. */
        if (mib * MiB < fixed_) return false;
        const int64_t t = paged_split(mib * MiB, nullptr);
        return t == kUnboundedTokens || t >= tokens;
    };
    if (!reaches(max_mib)) return -1;
    /* Invariant: reaches(hi) holds and reaches(lo) does not. */
    int64_t lo = 0, hi = max_mib;
    if (reaches(lo)) return 0;
    while (hi - lo > 1) {
        const int64_t mid = lo + (hi - lo) / 2;
        if (reaches(mid)) hi = mid; else lo = mid;
    }
    return hi;
}

int64_t KVManager::zero_blocks(const KVGroupPlan& p, int64_t tokens) const {
    if (tokens == kUnboundedTokens) return 0;
    const int64_t b = tokens / p.block_size;
    if (p.kind == RAD_KV_WINDOW && !p.runtime_win && b > window_pool_cap(p))
        return window_pool_cap(p);
    return b;
}

int KVManager::carve_into(Pool& kv_pool) {
    /* The pool size is the resolver's; this only splits it between the groups. The streamed
     * groups' maps were reserved from it before the carve and paged_split() charges them, so they
     * are added back here rather than charged twice. */
    const int64_t budget_bytes = kv_pool.avail() +
                                 kvstream_maps_charged(plans_, stream_, max_ctx_, max_seqs_);
    const int64_t fixed        = fixed_;
    pool_base_ = kv_pool.base();
    pool_ = &kv_pool;

    if (fixed >= budget_bytes) {
        RAD_ERR("vram_kv does not fit its fixed costs:\n"
                "  linear/conv state  %10s  (%lld sequences)\n"
                "  vram_kv            %10s\n"
                "  short by           %10s\n"
                "Lower --max-num-seqs, or give the cache more of the card: a smaller "
                "--gpu-headroom-mib or a larger --host-pool-mib. The engine will not shrink one of "
                "them for you (spec §6).",
                humanb(fixed).c_str(), (long long)max_seqs_, humanb(budget_bytes).c_str(),
                humanb(fixed - budget_bytes + 1).c_str());
        return RAD_E_NOMEM;
    }

    /* ---- the resident windows, before anything is split (kvstream/carve.h) ---- */
    RAD_TRY(kvstream_window_fit(plans_, stream_, fixed, budget_bytes, max_ctx_, max_seqs_));

    /* ---- the paged split; under a cap, the least rank's ---- */
    std::vector<int64_t> blocks;
    (void)paged_split(budget_bytes, &blocks);
    for (auto& p : plans_) if (p.paged()) p.n_blocks = blocks[p.index];

    /* How much of that the pool backs, and the refusal of an unbacked streamed plan. */
    RAD_TRY(kvstream_apply(plans_, stream_, max_ctx_, max_seqs_));

    /* A streamed group's `n_blocks` is its context, so this asks whether it can address anything,
     * not whether its window is large enough. */
    for (auto& p : plans_) {
        if (!p.paged()) continue;
        if (p.n_blocks <= 0 && p.zero) {
            RAD_ERR("KV group '%s' is zero on this rank and nothing set its block count: a zero "
                    "group holds what the ranks keeping the cache carve, and no cap from them was "
                    "given (cap_paged_tokens)", p.name.c_str());
            return RAD_E_STATE;
        }
        if (p.n_blocks <= 0) {
            RAD_ERR("KV group '%s': a %s KV pool leaves 0 blocks (%s a page) after the fixed "
                    "linear/conv costs of %s. Raise --host-pool-mib or lower --gpu-headroom-mib, or "
                    "lower --max-num-seqs.",
                    p.name.c_str(), humanb(budget_bytes).c_str(),
                    humanb(p.bytes_per_block).c_str(), humanb(fixed).c_str());
            return RAD_E_NOMEM;
        }
    }

    /* ---- carve. Every reservation comes from the KV pool only; the mover works inside the
     * weight slab and cannot reach it (spec §6). ---- */
    for (auto& p : plans_) {
        int64_t bytes = p.paged() ? kv_pool_bytes(p)
                                  : p.n_states * p.bytes_per_state;
        if (p.zero) {
            p.base = nullptr;
            p.pool_offset = 0;
            p.pool_bytes = 0;
            RAD_INFO("KV group '%s': this rank keeps no cache for it (rad_kv_group_zero) -- %lld "
                     "blocks of the shared table, nothing carved", p.name.c_str(),
                     (long long)p.n_blocks);
            continue;
        }
        int64_t off = 0;
        void* ptr = kv_pool.reserve(p.name, bytes, RAD_ALIGN_UNIT, &off);
        if (!ptr) {
            RAD_ERR("KV group '%s': %s did not fit the KV pool", p.name.c_str(),
                    humanb(bytes).c_str());
            return RAD_E_NOMEM;
        }
        p.base = ptr;
        p.pool_offset = off;
        p.pool_bytes = bytes;
    }
    /* --checkpoint-slots does nothing on a model with no recurrent state; say so. */
    if (ckpts_ > 0 && checkpoint_bytes_ <= 0)
        RAD_WARN("--checkpoint-slots %lld ignored: this model declares no linear-attention state, "
                 "so there is nothing to snapshot", (long long)ckpts_);

    /* ---- free lists ---- */
    free_blocks_.resize(plans_.size());
    refcount_.resize(plans_.size());
    cached_.resize(plans_.size());
    cache_only_.assign(plans_.size(), 0);
    free_states_.resize(plans_.size());
    for (size_t i = 0; i < plans_.size(); ++i) {
        const auto& p = plans_[i];
        if (p.paged()) {
            refcount_[i].assign((size_t)p.n_blocks, 0);
            cached_[i].assign((size_t)p.n_blocks, 0);
            /* Ascending order is already a valid min-heap (see the loan block in kv.h). */
            free_blocks_[i].resize((size_t)p.n_blocks);
            for (int64_t b = 0; b < p.n_blocks; ++b) free_blocks_[i][(size_t)b] = (int32_t)b;
        } else {
            /* Only logical slots are allocatable; copy k of slot s (s + k * n_seq_states) belongs
             * to whoever holds s. */
            const int64_t n_alloc = p.n_seq_states();
            free_states_[i].resize((size_t)n_alloc);
            for (int64_t s = 0; s < n_alloc; ++s)
                free_states_[i][(size_t)s] = (int32_t)(n_alloc - 1 - s);
        }
    }

    /* ---- backing ----
     *
     * Everything carved is backed before anything runs and stays backed for the life of the
     * process, so an elastic pool behaves exactly like a fixed one. The loan never changes what
     * is mapped, so every id the free list names has memory behind it. The fixed part (state and
     * conv slots) is sized per sequence and has no idle fraction to release. */
    if (pool_ && pool_->elastic()) {
        const int64_t used = pool_->used();
        const int rc = pool_->commit(0, used);
        if (rc < 0) {
            RAD_ERR("KV pool: the carve reserved %s of address space and the card would not back "
                    "it", humanb(used).c_str());
            return rc;
        }
    }
    live_.assign(plans_.size(), 0);
    free_usable_.assign(plans_.size(), 0);
    bucket_blocks_.assign(plans_.size(), 1);
    chunk_blocks_.assign(plans_.size(), 0);
    short_peak_.assign(plans_.size(), 0);
    held_hist_.assign(plans_.size(), {});
    for (size_t i = 0; i < plans_.size(); ++i) {
        const auto& p = plans_[i];
        if (!p.paged()) continue;
        live_[i]        = p.n_blocks;
        free_usable_[i] = p.n_blocks;
        /* Buffer floor: one step (max_tok tokens) of this group, so a prefill recalls at most
         * once a chunk and a decode step almost never. Clamped to the carve. */
        const int64_t chunk = blocks_for(p.index, max_tok_);
        chunk_blocks_[i] = std::min(chunk > 0 ? chunk : 1, p.n_blocks);
        /* At most 4096 buckets: the loan stops within 1/4096 of the carve above the highest held
         * block, and finding it walks at most 4096 counters. */
        bucket_blocks_[i] = std::max<int64_t>(1, ceil_div(p.n_blocks, 4096));
        held_hist_[i].assign((size_t)ceil_div(p.n_blocks, bucket_blocks_[i]), 0);
    }

    configured_ = true;
    report_ = bundling_.report();
    /* A runtime-window group reads as "ring": its window is the sequence's own, not the plan's. */
    auto kind_of = [](const KVGroupPlan& p) {
        return p.runtime_win ? "ring" : kv_kind_name(p.kind);
    };
    for (const auto& p : plans_) {
        if (p.paged()) {
            report_ += fmt("    %-14s %-6s %3lld layers  block %4lld tok  page %8s  "
                           "%7lld blocks = %9s  (%lld tokens)\n",
                           p.name.c_str(), kind_of(p), (long long)p.n_layers,
                           (long long)p.block_size, humanb(p.bytes_per_block).c_str(),
                           (long long)p.n_blocks, humanb(p.pool_bytes).c_str(),
                           (long long)(p.n_blocks * p.block_size));
            if (p.streamed())
                report_ += kvstream_report_line(p);
        } else
            report_ += fmt("    %-14s %-6s %3lld layers  state %8s  %7lld slots = %9s\n",
                           p.name.c_str(), kind_of(p), (long long)p.n_layers,
                           humanb(p.bytes_per_state).c_str(),
                           (long long)p.n_states, humanb(p.pool_bytes).c_str());
    }
    for (const auto& p : plans_) {
        if (!p.runtime_win) continue;
        report_ += fmt("    %-14s runtime window W=%lld: a sequence keeps its reference and a ring "
                       "of at most %lld block(s), rewritten in place\n",
                       p.name.c_str(), (long long)p.runtime_tokens,
                       (long long)p.ring_blocks_max());
    }
    /* The pool's address range, so a GPU fault address can be placed in the carve. */
    report_ += fmt("    pool at %p, %s; groups at +%lld..+%lld\n",
                   pool_base_, humanb(pool_ ? pool_->bytes() : 0).c_str(),
                   (long long)(plans_.size() > 1 ? plans_[1].pool_offset : 0),
                   (long long)(plans_.empty() ? 0 : plans_.back().pool_offset +
                                                    plans_.back().pool_bytes));
    return RAD_OK;
}

std::string KVManager::report() const { return report_; }

const KVGroupPlan* KVManager::plan(int32_t g) const {
    return (g >= 0 && g < (int32_t)plans_.size()) ? &plans_[(size_t)g] : nullptr;
}

/* ------------------------------------------------------------------ free lists */

/* Pops the lowest free block (min-heap; see the loan block in kv.h). Entries whose block is no
 * longer free are skipped: reserve_specific_block leaves its heap entry behind, since erasing
 * from a heap needs a rebuild. */
int KVManager::grab_block(int32_t g, int32_t* out) {
    auto& fl = free_blocks_[(size_t)g];
    /* No usable block: recall the loan here. ensure() recalls once for a whole request; this
     * covers callers that take one block at a time, and grow_for takes back a buffer's worth so
     * they do not recall per block. */
    if (free_usable_[(size_t)g] <= 0) (void)grow_for(g, 1);
    if (free_usable_[(size_t)g] <= 0) return RAD_E_FULL;
    while (!fl.empty()) {
        std::pop_heap(fl.begin(), fl.end(), std::greater<int32_t>());
        const int32_t b = fl.back();
        fl.pop_back();
        if (refcount_[(size_t)g][(size_t)b] != 0) continue;    /* stale: taken out of the middle */
        /* Never past the live mark: blocks above it are lent to the expert slab. A hit here
         * means free_usable_ and the heap disagree. */
        if (b >= live_[(size_t)g]) {
            RAD_ERR("KV group '%s': the free list offered block %d with the live mark at %lld and "
                    "%lld usable -- the count and the heap have gone out of step",
                    plans_[(size_t)g].name.c_str(), (int)b, (long long)live_[(size_t)g],
                    (long long)free_usable_[(size_t)g]);
            return RAD_E_STATE;
        }
        refcount_[(size_t)g][(size_t)b] = 1;
        --free_usable_[(size_t)g];
        note_held(g, b, +1);
        *out = b;
        return RAD_OK;
    }
    return RAD_E_FULL;
}

void KVManager::drop_block(int32_t g, int32_t b) {
    auto& rc = refcount_[(size_t)g][(size_t)b];
    if (rc <= 0) { RAD_ERR("KV group %d: double free of block %d", g, b); return; }
    if (cached_[(size_t)g][(size_t)b]) {
        if (rc == 2) ++cache_only_[(size_t)g];
        else if (rc == 1) { --cache_only_[(size_t)g]; cached_[(size_t)g][(size_t)b] = 0; }
    }
    if (--rc != 0) return;
    auto& fl = free_blocks_[(size_t)g];
    fl.push_back(b);
    std::push_heap(fl.begin(), fl.end(), std::greater<int32_t>());
    ++free_usable_[(size_t)g];
    note_held(g, b, -1);
}

void KVManager::add_ref(size_t g, int32_t b) {
    auto& rc = refcount_[g][(size_t)b];
    if (rc == 1 && cached_[g][(size_t)b]) --cache_only_[g];
    ++rc;
}

/* Maintains held_hist_ (see kv.h). */
void KVManager::note_held(int32_t g, int32_t b, int delta) {
    auto& h = held_hist_[(size_t)g];
    if (h.empty()) return;
    const int64_t bucket = (int64_t)b / bucket_blocks_[(size_t)g];
    if (bucket >= 0 && bucket < (int64_t)h.size()) h[(size_t)bucket] += delta;
}

int KVManager::grab_state(int32_t g, int32_t* out) {
    auto& fl = free_states_[(size_t)g];
    if (fl.empty()) return RAD_E_FULL;
    *out = fl.back(); fl.pop_back();
    /* The slot arrives dirty (see StateClear). Recorded rather than zeroed, because this runs on
     * the scheduler thread and the pool is device memory. Every copy is cleared: a zero replay
     * factor makes the first step after a prefill replay nothing (KVGroupPlan::state_copies). */
    const KVGroupPlan* p = plan(g);
    const int64_t copies = p ? p->state_copies : 1, span = p ? p->n_seq_states() : 0;
    for (int64_t k = 0; k < (copies > 0 ? copies : 1); ++k)
        clears_.push_back(StateClear{ g, (int32_t)(*out + k * span) });
    return RAD_OK;
}

void KVManager::drop_state(int32_t g, int32_t s) {
    if (s >= 0) free_states_[(size_t)g].push_back(s);
}

/* Blocks that can be handed out now. Not the free list's length, which also holds lent ids and
 * stale entries left by reserve_specific_block. */
int64_t KVManager::free_blocks(int32_t g) const {
    return (g >= 0 && g < (int32_t)free_usable_.size()) ? free_usable_[(size_t)g] : 0;
}
int64_t KVManager::held_blocks(int32_t g) const {
    if (g < 0 || g >= (int32_t)live_.size()) return 0;
    const int64_t held = live_[(size_t)g] - free_usable_[(size_t)g];
    return held > 0 ? held : 0;
}
int64_t KVManager::total_blocks(int32_t g) const {
    const KVGroupPlan* p = plan(g); return p ? p->n_blocks : 0;
}
int64_t KVManager::live_blocks(int32_t g) const {
    return (g >= 0 && g < (int32_t)live_.size()) ? live_[(size_t)g] : 0;
}
int64_t KVManager::held_top_blocks(int32_t g) const {
    return (g >= 0 && g < (int32_t)plans_.size()) ? held_top((size_t)g) : 0;
}

/* The larger of one prefill chunk and the recent shortfall peak (see buffer_bytes in kv.h). */
int64_t KVManager::buf_blocks(size_t i) const {
    if (i >= plans_.size()) return 0;
    const int64_t floor_b = i < chunk_blocks_.size() ? chunk_blocks_[i] : 0;
    const int64_t peak    = i < short_peak_.size()   ? short_peak_[i]   : 0;
    return peak > floor_b ? peak : floor_b;
}

int64_t KVManager::buffer_bytes() const {
    int64_t b = 0;
    for (size_t i = 0; i < plans_.size(); ++i)
        if (plans_[i].paged()) b += buf_blocks(i) * plans_[i].bytes_per_block;
    return b;
}

/* Free blocks plus lent ones, which are one recall away. Admission decides against this, not the
 * live mark, so a lending cache admits what a non-lending one would. Deciding on the mark would
 * livelock: a large request refused for lack of lent blocks is the demand that recalls them. */
int64_t KVManager::available_blocks(int32_t g) const {
    const KVGroupPlan* p = plan(g);
    if (!p || !p->paged()) return 0;
    const int64_t lent = p->n_blocks - live_blocks(g);
    return free_blocks(g) + (lent > 0 ? lent : 0);
}

bool KVManager::lendable(int32_t g) const {
    const KVGroupPlan* p = plan(g);
    /* A streamed group never lends: its pool is the ring, and a lent block would leave fewer
     * slots than one launch's selection needs. */
    return p && p->kind == RAD_KV_FULL && p->n_blocks > 0 && p->block_size > 0 &&
           p->bytes_per_block > 0 && !p->streamed();
}

int64_t KVManager::lent_blocks(size_t i, int64_t tokens) const {
    const KVGroupPlan& p = plans_[i];
    if (!lendable(p.index) || tokens <= 0) return 0;
    const int64_t b = tokens / p.block_size;
    return b < p.n_blocks ? b : p.n_blocks;
}

int64_t KVManager::held_top(size_t i) const {
    const auto& h = held_hist_[i];
    for (size_t b = h.size(); b-- > 0;)
        if (h[b] > 0) return std::min<int64_t>(((int64_t)b + 1) * bucket_blocks_[i], plans_[i].n_blocks);
    return 0;
}

/* Takes back enough of the loan that `blocks` more can be handed out, without limit: the request
 * is already admitted and the budget says it fits. Recalls the shortfall plus the buffer, so a
 * sequence growing a block at a time does not recall per block. */
int KVManager::grow_for(int32_t g, int64_t blocks) {
    if (g < 0 || g >= (int32_t)plans_.size()) return RAD_E_INVAL;
    const KVGroupPlan& p = plans_[(size_t)g];
    if (!p.paged()) return RAD_OK;
    const int64_t short_by = blocks - free_usable_[(size_t)g];
    if (short_by <= 0) return RAD_OK;

    /* Record the shortfall, not the recall (see short_peak_ in kv.h). */
    if ((size_t)g < short_peak_.size() && short_by > short_peak_[(size_t)g])
        short_peak_[(size_t)g] = short_by;

    if (!lendable(g) || loan_ <= 0 || live_[(size_t)g] >= p.n_blocks) return RAD_E_FULL;
    int64_t live = live_[(size_t)g] + short_by + buf_blocks((size_t)g);
    if (live > p.n_blocks) live = p.n_blocks;
    /* The loan, in tokens, that leaves this group `live` blocks. It only shrinks: a shortfall in
     * one group never lends more of another. */
    int64_t keep = (p.n_blocks - live) * p.block_size;
    if (keep > loan_) keep = loan_;
    if (reclaim_) {
        const int rc = reclaim_(keep);
        if (rc < 0) {
            RAD_ERR("KV group '%s': a request needs %lld more blocks and the expert slab could not "
                    "give back the loan past %lld tokens: %s", p.name.c_str(),
                    (long long)short_by, (long long)keep, rad_strerror(rc));
            return rc;
        }
    }
    RAD_TRY(set_loan(keep));
    return free_usable_[(size_t)g] >= blocks ? RAD_OK : RAD_E_FULL;
}

int64_t KVManager::spare_tokens() {
    int64_t spare = -1;
    for (size_t i = 0; i < plans_.size(); ++i) {
        /* Decay the shortfall peak by 1/8 a tick (a half-life of about half a second), so one
         * large admission does not pin its size of buffer for the life of the process. */
        if (i < short_peak_.size()) short_peak_[i] -= short_peak_[i] / 8;
        if (!lendable(plans_[i].index)) continue;
        const KVGroupPlan& p = plans_[i];
        int64_t keep = held_top(i) + buf_blocks(i);
        if (keep > p.n_blocks) keep = p.n_blocks;
        const int64_t t = (p.n_blocks - keep) * p.block_size;
        if (spare < 0 || t < spare) spare = t;
    }
    return spare > 0 ? spare : 0;
}

int KVManager::set_loan(int64_t tokens) {
    if (tokens < 0) tokens = 0;
    /* Check every group before moving any, so a refused loan changes nothing. */
    for (size_t i = 0; i < plans_.size(); ++i) {
        if (!lendable(plans_[i].index)) continue;
        const int64_t live = plans_[i].n_blocks - lent_blocks(i, tokens);
        if (live < live_[i] && held_top(i) > live) {
            RAD_ERR("KV group '%s': asked to lend down to block %lld with a block held at or above "
                    "%lld", plans_[i].name.c_str(), (long long)live,
                    (long long)(held_top(i) - bucket_blocks_[i]));
            return RAD_E_STATE;
        }
    }
    apply_loan(tokens);
    return RAD_OK;
}

void KVManager::apply_loan(int64_t tokens) {
    for (size_t i = 0; i < plans_.size(); ++i) {
        if (!lendable(plans_[i].index)) continue;
        const int64_t live = plans_[i].n_blocks - lent_blocks(i, tokens);
        /* The free count moves with the mark; the heap is unchanged. Every id between the old
         * and new mark is free, so the count moves by exactly the distance. */
        free_usable_[i] += live - live_[i];
        live_[i] = live;
    }
    loan_ = tokens;
}

int KVManager::follow(const KVManager& leader) {
    if (leader.loan_ != loan_) apply_loan(leader.loan_);
    return RAD_OK;
}
int64_t KVManager::free_states(int32_t g) const {
    return (g >= 0 && g < (int32_t)free_states_.size()) ? (int64_t)free_states_[(size_t)g].size() : 0;
}

/* Counted by the objects a group hands out, not KVGroupPlan::pool_bytes, which may include
 * alignment rounding that nothing can be allocated from. */
int64_t KVManager::pool_bytes(int32_t g) const {
    const KVGroupPlan* p = plan(g);
    if (!p) return 0;
    /* Live blocks only: lent ones are reported by the slab (Mover::flex_used_bytes). */
    if (p->paged())    return live_blocks(g) * p->bytes_per_block;
    if (p->stateful()) return p->n_states * p->bytes_per_state;
    return 0;
}

int64_t KVManager::pool_bytes_carved(int32_t g) const {
    const KVGroupPlan* p = plan(g);
    if (!p) return 0;
    if (p->paged())    return kv_pool_bytes(*p);
    if (p->stateful()) return p->n_states * p->bytes_per_state;
    return 0;
}

int64_t KVManager::pool_bytes_used(int32_t g) const {
    const KVGroupPlan* p = plan(g);
    if (!p) return 0;
    if (p->paged())    return held_blocks(g) * p->bytes_per_block;
    /* Counted in logical slots, then scaled by copies: the free list holds logical slots only,
     * while n_states counts every copy. */
    if (p->stateful()) {
        const int64_t copies = p->state_copies > 0 ? p->state_copies : 1;
        return (p->n_seq_states() - free_states(g)) * copies * p->bytes_per_state;
    }
    return 0;
}

int64_t KVManager::blocks_for(int32_t g, int64_t n_tokens) const {
    const KVGroupPlan* p = plan(g);
    if (!p || !p->paged() || n_tokens <= 0) return 0;
    int64_t n = ceil_div(n_tokens, p->block_size);
    if (p->kind == RAD_KV_WINDOW) {
        if (p->runtime_win) {
            /* The reference's blocks up to n, plus one ring. Without a sequence the floor is
             * unknown, so the whole context is the bound on the reference. */
            const int64_t ring = p->ring_blocks_max();
            const int64_t ctx  = max_ctx_ > 0 ? max_ctx_ : n_tokens;
            n = std::min(n, ceil_div(ctx, p->block_size)) + ring;
        } else {
            n = std::min(n, window_seq_cap(*p));
        }
    }
    return n;
}

bool KVManager::can_ever_fit(int64_t n_tokens) const {
    for (const auto& p : plans_) {
        /* Both kinds are tested explicitly: the null group at handle 0 is neither and holds no
         * states, so a bare `else` would refuse every sequence. */
        if (p.paged())         { if (blocks_for(p.index, n_tokens) > p.n_blocks) return false; }
        else if (p.stateful()) { if (p.n_states < 1) return false; }
    }
    return true;
}

/* ------------------------------------------------------------------ sequences */

KVManager::Seq* KVManager::find(uint64_t s) {
    auto it = seqs_.find(s); return it == seqs_.end() ? nullptr : &it->second;
}
const KVManager::Seq* KVManager::find(uint64_t s) const {
    auto it = seqs_.find(s); return it == seqs_.end() ? nullptr : &it->second;
}
bool KVManager::has_sequence(uint64_t s) const { return find(s) != nullptr; }

int KVManager::add_sequence(uint64_t id) {
    if (!configured_) return RAD_E_STATE;
    if (seqs_.count(id)) return RAD_E_DUPLICATE;
    Seq s;
    s.id = id;
    s.blocks.resize(plans_.size());
    s.first_block_pos.assign(plans_.size(), 0);
    s.win.resize(plans_.size());
    s.state.assign(plans_.size(), -1);
    s.dirty_from.assign(plans_.size(), 0);
    seqs_.emplace(id, std::move(s));
    return RAD_OK;
}

void KVManager::free_sequence(uint64_t id) {
    if (preempt(id) == RAD_OK) seqs_.erase(id);
}

int KVManager::preempt(uint64_t id) {
    Seq* s = find(id);
    if (!s) return RAD_E_NOTFOUND;
    for (size_t g = 0; g < plans_.size(); ++g) {
        for (int32_t b : s->blocks[g]) drop_block((int32_t)g, b);
        s->blocks[g].clear();
        s->first_block_pos[g] = 0;
        /* The runtime window goes with the blocks: re-admission re-arms it at the prompt end
         * (the scheduler's admission path calls set_window again before the KV grows). */
        s->win[g] = SeqWindow{};
        s->dirty_from[g] = 0;
        /* The recurrent state goes too (see preempt in kv.h, spec §7.1). */
        if (s->state[g] >= 0) { drop_state((int32_t)g, s->state[g]); s->state[g] = -1; }
    }
    s->n_tokens = 0;
    ++seq_frees_;
    return RAD_OK;
}

/* ------------------------------------------------------------------ rollback (spec §10) */
/* Paged groups only; see kv.h. */
int KVManager::rollback(uint64_t id, int64_t n_tokens) {
    Seq* s = find(id);
    if (!s) return RAD_E_NOTFOUND;
    if (n_tokens < 0) return RAD_E_INVAL;
    /* Nothing to free; RAD_OK so "every draft accepted" needs no special path in the caller. */
    if (n_tokens >= s->n_tokens) return RAD_OK;
    /* A runtime-windowed sequence unwinds nothing: the ring's slots are reused once it is full,
     * so the slots a rejected verify wrote may already hold newer keys. The scheduler gates
     * drafting on has_runtime_window, so this refuses rather than corrupts, and only a caller
     * that drafts beside a runtime window can reach it. */
    for (const SeqWindow& w : s->win)
        if (w.set) return RAD_E_UNSUPPORTED;

    for (size_t g = 0; g < plans_.size(); ++g) {
        const auto& p = plans_[g];
        if (!p.paged()) continue;
        int64_t first = s->first_block_pos[g] / p.block_size;
        int64_t want  = ceil_div(n_tokens, p.block_size) - first;
        if (want < 0) {
            /* Below what a WINDOW group retains (n_spec larger than the window): that KV is
             * already recycled, so drop everything and rebase. */
            want = 0;
            s->first_block_pos[g] = (n_tokens / p.block_size) * p.block_size;
            s->dirty_from[g] = 0;
        }
        while ((int64_t)s->blocks[g].size() > want) {
            drop_block((int32_t)g, s->blocks[g].back());
            s->blocks[g].pop_back();
        }
        s->dirty_from[g] = std::min<int64_t>(s->dirty_from[g], (int64_t)s->blocks[g].size());
    }
    s->n_tokens = n_tokens;
    return RAD_OK;
}

int64_t KVManager::first_block_pos(uint64_t id, int32_t g) const {
    const Seq* s = find(id);
    if (!s || g < 0 || g >= (int32_t)s->first_block_pos.size()) return 0;
    return s->first_block_pos[(size_t)g];
}

/* ------------------------------------------------------------------ the runtime window */

int KVManager::set_window(uint64_t id, int64_t visible_lo, int64_t window_tokens) {
    if (!configured_) return RAD_E_STATE;
    Seq* s = find(id);
    if (!s) return RAD_E_NOTFOUND;
    if (visible_lo < 0 || window_tokens <= 0) return RAD_E_INVAL;
    /* The reference is written linearly, so the floor cannot be behind KV the sequence already
     * holds: rebasing would have to move blocks the ring has not been shaped for. */
    if (visible_lo < s->n_tokens) {
        RAD_ERR("sequence %llu: runtime window floor %lld is behind its %lld held tokens",
                (unsigned long long)id, (long long)visible_lo, (long long)s->n_tokens);
        return RAD_E_STATE;
    }
    bool any = false;
    /* With a declared runtime window in the program, arm exactly the declared groups: a plain
     * fixed-window group beside them is carved for its fixed window, and arming it silently
     * converts it. With none declared this is the caller-sizes-the-pool path kv.h states, and
     * every windowed group arms as before. */
    bool declared = false;
    for (const KVGroupPlan& p : plans_)
        if (p.kind == RAD_KV_WINDOW && p.runtime_win) declared = true;
    for (size_t g = 0; g < plans_.size(); ++g) {
        const KVGroupPlan& p = plans_[g];
        if (p.kind != RAD_KV_WINDOW) continue;
        if (declared && !p.runtime_win) {
            RAD_ERR("sequence %llu: set_window meets fixed-window group '%s' beside a declared "
                    "runtime window; its pool is carved for its fixed window and the mix is not "
                    "supported", (unsigned long long)id, p.name.c_str());
            return RAD_E_UNSUPPORTED;
        }
        SeqWindow w;
        w.set        = true;
        w.window     = window_tokens;
        w.visible_lo = visible_lo;
        /* Whole blocks: the ring starts at the first boundary at or after the floor, and the
         * tokens in [visible_lo, ring_pos) stay in the reference's last block (SeqWindow). The
         * ring itself must span all of W: the frozen tokens are the oldest of the tail, so a
         * smaller ring would lose the last W - span positions. */
        w.ring_pos    = ceil_div(visible_lo, p.block_size) * p.block_size;
        w.ring_blocks = ceil_div(window_tokens, p.block_size);
        if (w.ring_blocks < 1) w.ring_blocks = 1;   /* the ring always has somewhere to write */
        /* What the sequence can hold: the reference's blocks, then the whole ring. */
        const int64_t need = w.ring_pos / p.block_size + w.ring_blocks;
        if (p.n_blocks > 0 && need > p.n_blocks) return RAD_E_FULL;
        s->win[g] = w;
        any = true;
    }
    if (!any) return RAD_E_UNSUPPORTED;
    return RAD_OK;
}

bool KVManager::runtime_window(uint64_t id, int32_t g, SeqWindow* out) const {
    const Seq* s = find(id);
    if (!s || g < 0 || g >= (int32_t)s->win.size() || !s->win[(size_t)g].set) return false;
    if (out) *out = s->win[(size_t)g];
    return true;
}

bool KVManager::has_runtime_window(uint64_t id) const {
    const Seq* s = find(id);
    if (!s) return false;
    for (const SeqWindow& w : s->win) if (w.set) return true;
    return false;
}

/* What ensure() must have in the table for `n_tokens`: the reference grows linearly until the
 * floor, then the ring fills up to its whole span and never grows again. */
int64_t KVManager::window_table_len(const KVGroupPlan& p, const SeqWindow& w, int64_t n_tokens) {
    const int64_t ref = w.ring_pos / p.block_size;
    if (n_tokens <= w.ring_pos) return ceil_div(n_tokens, p.block_size);
    return ref + std::min(w.ring_blocks, ceil_div(n_tokens - w.ring_pos, p.block_size));
}

int64_t KVManager::seq_tokens(uint64_t id) const { const Seq* s = find(id); return s ? s->n_tokens : 0; }

int64_t KVManager::take_table_changes(uint64_t id, int32_t g) const {
    const Seq* s = find(id);
    if (!s || g < 0 || g >= (int32_t)s->dirty_from.size()) return 0;
    const int64_t d = s->dirty_from[(size_t)g];
    s->dirty_from[(size_t)g] = kNoDirty;
    return d;
}

const std::vector<int32_t>& KVManager::block_table(uint64_t id, int32_t g) const {
    const Seq* s = find(id);
    if (!s || g < 0 || g >= (int32_t)s->blocks.size()) return kNoBlocks;
    return s->blocks[(size_t)g];
}

int32_t KVManager::state_slot(uint64_t id, int32_t g) const {
    const Seq* s = find(id);
    if (!s || g < 0 || g >= (int32_t)s->state.size()) return -1;
    return s->state[(size_t)g];
}

int KVManager::reserve_block(int32_t g, int32_t* out) {
    if (!out) return RAD_E_INVAL;
    *out = -1;
    if (g < 0 || g >= (int32_t)plans_.size()) return RAD_E_INVAL;
    if (!plans_[(size_t)g].paged()) return RAD_E_INVAL;
    if (free_usable_[(size_t)g] <= 0) return RAD_E_FULL;
    return grab_block(g, out) == RAD_OK && *out >= 0 ? RAD_OK : RAD_E_FULL;
}

int64_t KVManager::reserve_blocks(int32_t g, int64_t n, std::vector<int32_t>* out) {
    if (!out || n <= 0) return 0;
    if (g < 0 || g >= (int32_t)plans_.size() || !plans_[(size_t)g].paged()) return 0;
    if (free_usable_[(size_t)g] < n) (void)grow_for(g, n);
    int64_t got = 0;
    while (got < n && free_usable_[(size_t)g] > 0) {
        int32_t b = -1;
        if (grab_block(g, &b) != RAD_OK || b < 0) break;
        out->push_back(b);
        ++got;
    }
    return got;
}

int KVManager::reserve_specific_block(int32_t g, int32_t b) {
    if (g < 0 || g >= (int32_t)plans_.size() || !plans_[(size_t)g].paged()) return RAD_E_INVAL;
    if (b < 0 || b >= plans_[(size_t)g].n_blocks) return RAD_E_INVAL;
    /* A block above live_ is lent; restoring into it would overwrite expert weights in use. Rank
     * 0 picks below its own mark, so a refusal here means this rank's loan is deeper. */
    if (b >= live_[(size_t)g]) return RAD_E_STATE;
    if (refcount_[(size_t)g][(size_t)b] != 0) return RAD_E_STATE;
    /* The heap entry is left behind; grab_block skips it. */
    refcount_[(size_t)g][(size_t)b] = 1;
    --free_usable_[(size_t)g];
    note_held(g, b, +1);
    return RAD_OK;
}

int KVManager::retain_block(int32_t g, int32_t b) {
    if (g < 0 || g >= (int32_t)refcount_.size()) return RAD_E_INVAL;
    if (b < 0 || b >= (int32_t)refcount_[(size_t)g].size()) return RAD_E_INVAL;
    if (refcount_[(size_t)g][(size_t)b] <= 0) {
        RAD_ERR("KV group %d: retain of free block %d -- the cache is naming a block it does not "
                "hold, which would serve one sequence another's context", g, b);
        return RAD_E_STATE;
    }
    add_ref((size_t)g, b);
    cached_[(size_t)g][(size_t)b] = 1;     /* at two or more: shared, so not counted */
    return RAD_OK;
}

void KVManager::cache_reserved_block(int32_t g, int32_t b) {
    if (g < 0 || g >= (int32_t)refcount_.size()) return;
    if (b < 0 || b >= (int32_t)refcount_[(size_t)g].size()) return;
    if (refcount_[(size_t)g][(size_t)b] <= 0) return;
    uint8_t& mark = cached_[(size_t)g][(size_t)b];
    if (!mark) { mark = 1; if (refcount_[(size_t)g][(size_t)b] == 1) ++cache_only_[(size_t)g]; }
}

/* Releasing a marked block releases the cache's reference, so the mark goes with it; other
 * callers (a restore returning a reservation) release unmarked blocks. */
void KVManager::release_block(int32_t g, int32_t b) {
    if (g < 0 || g >= (int32_t)refcount_.size()) return;
    if (b < 0 || b >= (int32_t)refcount_[(size_t)g].size()) return;
    uint8_t& mark = cached_[(size_t)g][(size_t)b];
    if (mark && refcount_[(size_t)g][(size_t)b] > 1) mark = 0;
    drop_block(g, b);
}

int64_t KVManager::cache_only_blocks(int32_t g) const {
    if (g < 0 || g >= (int32_t)cache_only_.size()) return 0;
    return cache_only_[(size_t)g];
}

int32_t KVManager::block_refcount(int32_t g, int32_t b) const {
    if (g < 0 || g >= (int32_t)refcount_.size()) return 0;
    if (b < 0 || b >= (int32_t)refcount_[(size_t)g].size()) return 0;
    return refcount_[(size_t)g][(size_t)b];
}

std::vector<BlockCopy> KVManager::take_pending_copies() {
    std::vector<BlockCopy> out;
    out.swap(pending_);
    return out;
}

/* ------------------------------------------------------------------ ensure */

int64_t KVManager::window_seq_cap(const KVGroupPlan& p) const {
    return p.window_blocks + step_blocks(p) + 1;
}

int64_t KVManager::window_pool_cap(const KVGroupPlan& p) const {
    return max_seqs_ * (p.window_blocks + 1) + step_blocks(p);
}

int64_t KVManager::step_blocks(const KVGroupPlan& p) const {
    return max_tok_ > 0 ? ceil_div(max_tok_, p.block_size) : 0;
}

/* Slides from the step's first query, not its last. The query at keep_from reads keys down to
 * keep_from - window + 1, which lies in block keep_from / block - (window_blocks - 1) or later
 * (window_blocks - 1 >= window / block). A target from the step's end is the same for a decode
 * step but drops keys the earlier rows of a prefill chunk still need.
 *
 * A sequence with a runtime window is left alone. Its visible set is anchored at 0, so nothing in
 * the table is below a sliding floor to recycle; the ring's blocks are rewritten in place and
 * the table never moves (SeqWindow). */
void KVManager::recycle_window(Seq* s, int64_t keep_from) {
    for (size_t g = 0; g < plans_.size(); ++g) {
        const auto& p = plans_[g];
        if (p.kind != RAD_KV_WINDOW || s->win[g].set) continue;
        int64_t first    = s->first_block_pos[g] / p.block_size;
        int64_t target   = std::max<int64_t>(first,
                                             keep_from / p.block_size - (p.window_blocks - 1));
        while (first < target && !s->blocks[g].empty()) {
            drop_block((int32_t)g, s->blocks[g].front());
            s->blocks[g].erase(s->blocks[g].begin());
            s->dirty_from[g] = 0;
            ++first;
        }
        if (s->blocks[g].empty()) first = target;   /* nothing held: rebase to the window */
        s->first_block_pos[g] = first * p.block_size;
    }
}

void KVManager::trim_window(uint64_t id, int64_t keep_from) {
    Seq* s = find(id);
    if (!s || keep_from < 0) return;
    if (keep_from > s->n_tokens) keep_from = s->n_tokens;
    recycle_window(s, keep_from);
}

int KVManager::ensure(uint64_t id, int64_t n_tokens, int64_t keep_from) {
    Seq* s = find(id);
    if (!s) return RAD_E_NOTFOUND;
    if (n_tokens <= s->n_tokens) return RAD_OK;
    if (keep_from < 0 || keep_from > s->n_tokens) keep_from = s->n_tokens;

    /* Pass 0: recycle what the window has slid past. It only frees, so it cannot fail, and the
     * check below sees the freed blocks. */
    recycle_window(s, keep_from);

    /* Pass 1: check every group before touching any, so a failure leaves the sequence as it
     * was. */
    std::vector<int64_t> need(plans_.size(), 0);
    for (size_t g = 0; g < plans_.size(); ++g) {
        const auto& p = plans_[g];
        if (p.paged()) {
            int64_t first = s->first_block_pos[g] / p.block_size;
            int64_t want  = s->win[g].set
                ? window_table_len(p, s->win[g], n_tokens) - first
                : ceil_div(n_tokens, p.block_size) - first;
            need[g] = want - (int64_t)s->blocks[g].size();
            if (need[g] < 0) need[g] = 0;
            /* Copy-on-write: the partial block is the only one a write reaches; if it is shared,
             * it needs one extra block. */
            if (s->n_tokens > 0 && s->n_tokens % p.block_size != 0) {
                int64_t bi = s->n_tokens / p.block_size - first;
                if (bi >= 0 && bi < (int64_t)s->blocks[g].size()
                    && refcount_[g][(size_t)s->blocks[g][(size_t)bi]] > 1) need[g] += 1;
            }
            if (need[g] > available_blocks((int32_t)g)) return RAD_E_FULL;
            RAD_TRY(grow_for((int32_t)g, need[g]));
        } else if (p.stateful() && s->state[g] < 0) {
            if (free_states_[g].empty()) return RAD_E_FULL;
        }
    }

    /* Pass 2: commit. Nothing below can fail. */
    for (size_t g = 0; g < plans_.size(); ++g) {
        const auto& p = plans_[g];
        if (p.paged()) {
            int64_t first = s->first_block_pos[g] / p.block_size;
            if (s->n_tokens > 0 && s->n_tokens % p.block_size != 0) {
                int64_t bi = s->n_tokens / p.block_size - first;
                if (bi >= 0 && bi < (int64_t)s->blocks[g].size()) {
                    int32_t old = s->blocks[g][(size_t)bi];
                    if (refcount_[g][(size_t)old] > 1) {
                        int32_t fresh = -1;
                        grab_block((int32_t)g, &fresh);
                        s->blocks[g][(size_t)bi] = fresh;
                        s->dirty_from[g] = std::min<int64_t>(s->dirty_from[g], bi);
                        drop_block((int32_t)g, old);
                        pending_.push_back({(int32_t)g, old, fresh});
                    }
                }
            }
            int64_t want = s->win[g].set
                ? window_table_len(p, s->win[g], n_tokens) - first
                : ceil_div(n_tokens, p.block_size) - first;
            if ((int64_t)s->blocks[g].size() < want)
                s->dirty_from[g] = std::min<int64_t>(s->dirty_from[g],
                                                     (int64_t)s->blocks[g].size());
            while ((int64_t)s->blocks[g].size() < want) {
                int32_t b = -1;
                grab_block((int32_t)g, &b);
                s->blocks[g].push_back(b);
            }
        } else if (p.stateful() && s->state[g] < 0) {
            grab_state((int32_t)g, &s->state[g]);
        }
    }
    s->n_tokens = n_tokens;
    return RAD_OK;
}

/* ------------------------------------------------------------------ adopt / fork */

int KVManager::adopt(uint64_t id, int32_t g, const std::vector<int32_t>& blocks, int64_t n_tokens) {
    Seq* s = find(id);
    if (!s) return RAD_E_NOTFOUND;
    const KVGroupPlan* p = plan(g);
    if (!p || !p->paged()) return RAD_E_INVAL;
    /* A runtime window's table is its own reference plus ring, laid out against a floor no cache
     * entry knows (set_window), so blocks adopted from a prefix hit would sit at the wrong
     * positions. Prefix publish is skipped for such a sequence; this is the backstop. */
    if (s->win[(size_t)g].set) return RAD_E_STATE;
    /* Whole blocks only (see adopt in kv.h). */
    if (n_tokens % p->block_size != 0) return RAD_E_INVAL;
    if ((int64_t)blocks.size() != n_tokens / p->block_size) return RAD_E_INVAL;
    if (!s->blocks[(size_t)g].empty()) return RAD_E_STATE;
    if (s->n_tokens != 0 && s->n_tokens != n_tokens) return RAD_E_INVAL;

    for (int32_t b : blocks) {
        if (b < 0 || b >= p->n_blocks) return RAD_E_INVAL;
        add_ref((size_t)g, b);
    }
    s->blocks[(size_t)g] = blocks;
    s->dirty_from[(size_t)g] = 0;
    s->n_tokens = n_tokens;
    return RAD_OK;
}

int KVManager::fork(uint64_t parent, uint64_t child) {
    Seq* pa = find(parent);
    if (!pa) return RAD_E_NOTFOUND;
    if (seqs_.count(child)) return RAD_E_DUPLICATE;
    /* The window is runtime data: a child that shared the table without it would read the ring
     * as if it were a reference. A forking model (speculative decoding) does not carry one. */
    for (const SeqWindow& w : pa->win)
        if (w.set) {
            RAD_ERR("sequence %llu: fork refused, it carries a runtime window",
                    (unsigned long long)parent);
            return RAD_E_UNSUPPORTED;
        }

    /* Pass 1: the child needs its own state slot in every stateful group before anything is
     * shared (see fork in kv.h, spec §7.3). */
    for (size_t g = 0; g < plans_.size(); ++g)
        if (plans_[g].stateful() && free_states_[g].empty()) return RAD_E_FULL;

    int st = add_sequence(child);
    if (st < 0) return st;
    Seq* ch = find(child);
    ch->n_tokens = pa->n_tokens;
    for (size_t g = 0; g < plans_.size(); ++g) {
        if (plans_[g].paged()) {
            ch->blocks[g] = pa->blocks[g];
            ch->first_block_pos[g] = pa->first_block_pos[g];
            ch->win[g] = pa->win[g];
            for (int32_t b : ch->blocks[g]) add_ref(g, b);
        } else {
            grab_state((int32_t)g, &ch->state[g]);
        }
    }
    return RAD_OK;
}

/* ------------------------------------------------------------------ make_room */

int KVManager::make_room(uint64_t id, int64_t n_tokens,
                         const std::vector<uint64_t>& victims,
                         std::vector<uint64_t>* preempted) {
    /* Fail before preempting anyone if even an empty pool cannot hold it (spec §17). */
    if (!can_ever_fit(n_tokens)) {
        RAD_WARN("request %llu wants %lld tokens, which exceeds the whole KV pool. Failing it "
                 "rather than preempting the server for a request that still would not fit.",
                 (unsigned long long)id, (long long)n_tokens);
        return RAD_E_FULL;
    }
    Seq* s = find(id);
    if (!s) return RAD_E_NOTFOUND;

    auto fits = [&]() {
        for (size_t g = 0; g < plans_.size(); ++g) {
            const auto& p = plans_[g];
            if (p.paged()) {
                int64_t first = s->first_block_pos[g] / p.block_size;
                int64_t want  = ceil_div(n_tokens, p.block_size) - first;
                if (p.kind == RAD_KV_WINDOW) {
                    if (s->win[g].set) want = window_table_len(p, s->win[g], n_tokens) - first;
                    else               want = std::min(want, window_seq_cap(p));
                }
                int64_t extra = want - (int64_t)s->blocks[g].size() + 1;  /* +1 for a COW copy */
                if (extra > available_blocks((int32_t)g)) return false;
            } else if (p.stateful() && s->state[g] < 0 && free_states_[g].empty()) return false;
        }
        return true;
    };

    if (fits()) return RAD_OK;
    for (uint64_t v : victims) {
        if (v == id) continue;
        if (preempt(v) == RAD_OK && preempted) preempted->push_back(v);
        if (fits()) return RAD_OK;
    }
    return fits() ? RAD_OK : RAD_E_FULL;
}

/* ------------------------------------------------------------------ checkpoints */

/* A disabled store counts as none. A full store makes alloc_checkpoint return RAD_E_FULL, which
 * the caller handles by running its retention policy and retrying. */
void KVManager::set_checkpoint_store(HostArena* store, int64_t rank_off) {
    ck_store_ = store && store->enabled() ? store : nullptr;
    ck_rank_off_ = rank_off;
}

int KVManager::alloc_checkpoint(int32_t* slot_out) {
    if (!ck_store_ || checkpoint_bytes_ <= 0) return RAD_E_FULL;
    const int32_t slot = ck_store_->alloc();
    if (slot < 0) return RAD_E_FULL;
    *slot_out = slot;
    return RAD_OK;
}

void KVManager::free_checkpoint(int32_t slot) {
    if (ck_store_) ck_store_->free(slot);
}

bool KVManager::checkpoint_held(int32_t slot) const {
    return ck_store_ && ck_store_->in_use(slot);
}

void* KVManager::checkpoint_ptr(int32_t slot) const {
    if (!ck_store_) return nullptr;
    char* p = (char*)ck_store_->at(slot);
    return p ? p + ck_rank_off_ : nullptr;
}

/* Save and restore share one traversal because the blob has no header: its layout is defined
 * only by this walk order. */
int KVManager::checkpoint_copy(const int32_t* state_slots, int n_slots, int32_t ck_slot,
                               bool save, RadStream s, const std::vector<int32_t>* win) {
    /* The slot must be held in the shared store (rank 0 hands out ids, so followers check the
     * store). A slot not in use is a lifetime fault in whoever handed out the id. */
    const char* dir = save ? "save into" : "restore from";
    if (!ck_store_) {
        RAD_ERR("checkpoint %s slot %d: this rank has no snapshot store", dir, (int)ck_slot);
        return RAD_E_INVAL;
    }
    if (!ck_store_->in_use(ck_slot)) {
        RAD_ERR("checkpoint %s slot %d: the store does not hold that slot (%lld of %lld in use) -- "
                "it was given back after its id was handed out", dir, (int)ck_slot,
                (long long)ck_store_->used_slots(), (long long)ck_store_->capacity());
        return RAD_E_INVAL;
    }
    char* ck = (char*)checkpoint_ptr(ck_slot);
    if (!ck) {
        RAD_ERR("checkpoint %s slot %d: the store has no address for it", dir, (int)ck_slot);
        return RAD_E_INVAL;
    }
    if (!state_slots || n_slots < (int)plans_.size()) {
        RAD_ERR("checkpoint %s slot %d: %d state slot(s) named for %d group(s)", dir, (int)ck_slot,
                state_slots ? n_slots : 0, (int)plans_.size());
        return RAD_E_INVAL;
    }

    /* One pitched copy per group: a sequence's state is one row per layer, layer_stride apart in
     * the pool and packed in the slot. */
    int64_t off = 0;
    for (size_t g = 0; g < plans_.size(); ++g) {
        const KVGroupPlan& p = plans_[g];
        if (!p.stateful()) continue;
        const int32_t slot = state_slots[g];
        if (slot < 0) {                            /* no state to save, or none to restore into */
            RAD_ERR("checkpoint %s slot %d: the sequence holds no state slot in group %d", dir,
                    (int)ck_slot, (int)g);
            return RAD_E_STATE;
        }
        const int64_t nbytes = p.layer_bytes_per_state();
        void* st = state_ptr((int32_t)g, 0, slot);
        if (!st || p.n_layers <= 0) {
            RAD_ERR("checkpoint %s slot %d: group %d has no address for state slot %d", dir,
                    (int)ck_slot, (int)g, (int)slot);
            return RAD_E_STATE;
        }
        if (off + nbytes * p.n_layers > checkpoint_bytes_) {
            RAD_ERR("checkpoint slot %d: the linear state needs more than the slot's %lld bytes "
                    "a rank", (int)ck_slot, (long long)checkpoint_bytes_);
            return RAD_E_STATE;
        }
        const int cs = save ? rad_memcpy_2d_async(ck + off, nbytes, st, p.layer_stride(), nbytes,
                                                  p.n_layers, s)
                            : rad_memcpy_2d_async(st, p.layer_stride(), ck + off, nbytes, nbytes,
                                                  p.n_layers, s);
        if (cs < 0) {
            RAD_ERR("checkpoint %s slot %d: the device refused the copy of group %d (%lld rows of "
                    "%lld bytes): %s", dir, (int)ck_slot, (int)g, (long long)p.n_layers,
                    (long long)nbytes, rad_strerror(cs));
            return cs;
        }
        off += nbytes * p.n_layers;
    }

    /* Window section: window_blocks pages per snapshot group, page j at slot position j, each
     * n_layers rows of one layer's block, one pitched copy per page. `win` names the pages
     * (window_rows); -1 is a page below position zero and is skipped. */
    if (window_ck_bytes_ > 0) {
        if (!win) {
            RAD_ERR("checkpoint %s slot %d: this model snapshots its window and no window rows "
                    "were named", dir, (int)ck_slot);
            return RAD_E_INVAL;
        }
        size_t wi = 0;
        for (size_t g = 0; g < plans_.size(); ++g) {
            const KVGroupPlan& p = plans_[g];
            if (!p.win_snap) continue;
            const size_t row0 = wi;
            wi += (size_t)p.window_blocks;
            if (p.zero || p.n_layers <= 0) continue;
            if (wi > win->size() || !p.base) {
                RAD_ERR("checkpoint %s slot %d: window group %d has %zu row(s) named for %lld",
                        dir, (int)ck_slot, (int)g, win->size(), (long long)wi);
                return RAD_E_STATE;
            }
            if (off + p.window_blocks * p.bytes_per_block > checkpoint_bytes_) {
                RAD_ERR("checkpoint slot %d: window group %d needs more than the slot's %lld "
                        "bytes a rank", (int)ck_slot, (int)g, (long long)checkpoint_bytes_);
                return RAD_E_STATE;
            }
            const int64_t lb = p.layer_bytes_per_block();
            for (int64_t j = 0; j < p.window_blocks; ++j) {
                const int32_t b = (*win)[row0 + (size_t)j];
                if (b < 0) continue;
                if (b >= p.n_blocks) {
                    RAD_ERR("checkpoint %s slot %d: window group %d names block %d of %lld", dir,
                            (int)ck_slot, (int)g, (int)b, (long long)p.n_blocks);
                    return RAD_E_STATE;
                }
                char* dev = (char*)p.base + (int64_t)b * lb;
                char* host = ck + off + j * p.bytes_per_block;
                const int cs = save ? rad_memcpy_2d_async(host, lb, dev, p.layer_stride(), lb,
                                                          p.n_layers, s)
                                    : rad_memcpy_2d_async(dev, p.layer_stride(), host, lb, lb,
                                                          p.n_layers, s);
                if (cs < 0) {
                    RAD_ERR("checkpoint %s slot %d: the device refused window page %lld of "
                            "group %d: %s", dir, (int)ck_slot, (long long)j, (int)g,
                            rad_strerror(cs));
                    return cs;
                }
            }
            off += p.window_blocks * p.bytes_per_block;
        }
    }
    return RAD_OK;
}

int KVManager::checkpoint_save(const int32_t* slots, int n, int32_t ck, RadStream s,
                               const std::vector<int32_t>* win) {
    return checkpoint_copy(slots, n, ck, /*save=*/true, s, win);
}
int KVManager::checkpoint_restore(const int32_t* slots, int n, int32_t ck, RadStream s,
                                  const std::vector<int32_t>* win) {
    return checkpoint_copy(slots, n, ck, /*save=*/false, s, win);
}

bool KVManager::window_rows(uint64_t id, int64_t pos, std::vector<int32_t>* out) const {
    out->clear();
    const Seq* s = find(id);
    if (!s || pos <= 0) return false;
    /* A runtime window is excluded from window snapshots (set_window): the window length is
     * runtime data and the table is a reference plus a ring, not [lo, pos). */
    for (const SeqWindow& w : s->win) if (w.set) return false;
    for (size_t g = 0; g < plans_.size(); ++g) {
        const KVGroupPlan& p = plans_[g];
        if (!p.win_snap) continue;
        const size_t row0 = out->size();
        out->resize(row0 + (size_t)p.window_blocks, -1);
        if (p.zero || p.block_size <= 0 || pos % p.block_size != 0) {
            if (p.zero) continue;
            return false;
        }
        const int64_t lo = window_lo(p, pos), hi = pos / p.block_size;
        const int64_t first = s->first_block_pos[g] / p.block_size;
        if (lo < first || hi - first > (int64_t)s->blocks[g].size()) return false;
        for (int64_t j = lo; j < hi; ++j)
            (*out)[row0 + (size_t)(j - lo)] = s->blocks[g][(size_t)(j - first)];
    }
    return true;
}

int KVManager::seed_window(uint64_t id, int64_t pos) {
    Seq* s = find(id);
    if (!s) return RAD_E_NOTFOUND;
    /* A sequence with a runtime window is never resumed from a window snapshot (set_window). */
    for (const SeqWindow& w : s->win) if (w.set) return RAD_E_STATE;
    /* Check every group before taking anything, as ensure() does. */
    for (size_t g = 0; g < plans_.size(); ++g) {
        const KVGroupPlan& p = plans_[g];
        if (!p.win_snap) continue;
        if (!s->blocks[g].empty()) return RAD_E_STATE;
        if (pos % p.block_size != 0) return RAD_E_INVAL;
        const int64_t need = pos / p.block_size - window_lo(p, pos);
        if (need > available_blocks((int32_t)g)) return RAD_E_FULL;
        RAD_TRY(grow_for((int32_t)g, need));
    }
    for (size_t g = 0; g < plans_.size(); ++g) {
        const KVGroupPlan& p = plans_[g];
        if (!p.win_snap) continue;
        const int64_t lo = window_lo(p, pos), hi = pos / p.block_size;
        s->first_block_pos[g] = lo * p.block_size;
        for (int64_t j = lo; j < hi; ++j) {
            int32_t b = -1;
            grab_block((int32_t)g, &b);
            s->blocks[g].push_back(b);
        }
        s->dirty_from[g] = 0;
    }
    if (s->n_tokens == 0) s->n_tokens = pos;
    return RAD_OK;
}

/* Columns in a sequence's state_index row: three per copy when speculating. libr4d's anchor
 * scheme targets a paged state cache where a state's page moves by -1, 0 or +1 per step, so it
 * names each copy three times and picks a column at run time. Here a slot is fixed for the
 * sequence's life, so all three name the same slot. Column j names copy j * copies / width. */
int64_t KVManager::state_index_width(int32_t g) const {
    const KVGroupPlan* p = plan(g);
    if (!p || !p->stateful()) return 0;
    return p->state_copies > 1 ? p->state_copies * 3 : 1;
}

int KVManager::state_index_row(uint64_t seq, int32_t g, int32_t* out, int max) const {
    const int64_t w = state_index_width(g);
    if (w <= 0 || !out || max <= 0) return 0;
    const KVGroupPlan* p = plan(g);
    const int32_t base = state_slot(seq, g);
    const int64_t span = p ? p->n_seq_states() : 0, copies = p ? p->state_copies : 1;
    const int n = (int)(w < (int64_t)max ? w : (int64_t)max);
    for (int j = 0; j < n; ++j) {
        /* No slot: -1 across the row, the pad every kernel tests for. */
        out[j] = base < 0 ? -1 : (int32_t)(base + (int64_t)j * copies / w * span);
    }
    return n;
}

void* KVManager::state_ptr(int32_t g, int32_t layer, int32_t s) const {
    const KVGroupPlan* p = plan(g);
    if (!p || !p->base || s < 0 || s >= p->n_states) return nullptr;
    if (layer < 0 || layer >= p->n_layers) return nullptr;
    return (char*)p->base + (int64_t)layer * p->layer_stride()
                          + (int64_t)s * p->layer_bytes_per_state();
}

}  /* namespace rad */
