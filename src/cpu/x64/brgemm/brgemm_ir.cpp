/*******************************************************************************
* Copyright 2026 Intel Corporation
*
* Licensed under the Apache License, Version 2.0 (the "License");
* you may not use this file except in compliance with the License.
* You may obtain a copy of the License at
*
*     http://www.apache.org/licenses/LICENSE-2.0
*
* Unless required by applicable law or agreed to in writing, software
* distributed under the License is distributed on an "AS IS" BASIS,
* WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
* See the License for the specific language governing permissions and
* limitations under the License.
*******************************************************************************/

// The IR-based BRGEMM kernel converts a brgemm descriptor into IR, then runs
// the register allocator and code emitter.
//
// This kernel uses `jit_brgemm_kernel_t` as a reference and is comparable with
// the classic kernel instruction for instruction when it comes to compute
// structure.
//
// `init_conf()` is the only code that reads the descriptor for the builder. It
// converts the descriptor into `conf_t`, and the builder reads only `conf_t`.

#include <algorithm>
#include <cassert>
#include <cstdint>
#include <memory>
#include <vector>

#include "common/c_types_map.hpp"
#include "common/memory_desc_wrapper.hpp"
#include "common/type_helpers.hpp"
#include "common/utils.hpp"
#include "common/verbose.hpp"

#include "cpu/x64/brgemm/brgemm_ir.hpp"
#include "cpu/x64/cpu_isa_traits.hpp"
#include "cpu/x64/injectors/jit_uni_postops_injector.hpp"
#include "cpu/x64/ir/codegen.hpp"
#include "cpu/x64/ir/ir.hpp"
#include "cpu/x64/jit_generator.hpp"

#define GET_OFF(field) offsetof(brgemm_kernel_params_t, field)
#define GET_OFF_BATCH_ELEMENT(field) offsetof(brgemm_batch_element_t, field)

#define VCONDCHECK_BRGEMM_IR(cond, msg, ...) \
    VCONDCHECK(primitive, create, dispatch, brgemm_ir, (cond), \
            status::unimplemented, msg, ##__VA_ARGS__)

namespace dnnl {
namespace impl {
namespace cpu {
namespace x64 {

namespace {

// The shape of an output block: everything the code of the block depends on
// apart from its position.
//
//   bd_block     - rows of the broadcast dimension the block covers
//   ld_block2    - vector registers of the load dimension it covers
//   ld_tail_mask - live elements of the last register, `none` when every
//                  register of the block is full
struct out_block_t {
    int bd_block;
    int ld_block2;
    ir::vreg_t ld_tail_mask;
};

// Position of a block, in elements along M, N, and K, counted from where the
// pointers stand.
//
// Every access adds it to its displacement. This lets a block reach its
// elements without moving the pointers to it, for example a tail block, which
// follows a loop of full blocks or a single full block.
struct block_pos_t {
    dim_t m;
    dim_t n;
    dim_t k;
};

// True if `v` can be encoded as a displacement or an immediate.
bool fits_int32(dim_t v) {
    return v <= INT32_MAX && v >= INT32_MIN;
}

// Builder configuration
//
// `conf_t` holds one configuration per module of the builder:
//   loop        - the loop nest: the batch, the leading dimensions, and the
//                 blocking
//   microkernel - the compute path and the data types of A, B, and the
//                 accumulators
//   output      - the output path: beta, the bias, the scales, and the
//                 attribute post-ops
//
// Every field is a build-time constant.

// How the product is computed. The caller chooses it when it creates the
// descriptor, and the kernel never changes it.
//
//   vector - broadcasts one A element and multiply-adds it with B vectors into
//            vector accumulators
enum class compute_path_t { vector };

// Loop nest configuration.
//
//   batch_kind  - how a batch element gives the address of its A and B
//   max_bs      - maximum batch size known at IR generation time
//   load_dim    - N, the columns of C
//   lda/ldb/ldc - leading dimensions of A, B, and C, in elements
//   bd_block    - M rows per block
//   ld_block    - N elements per vector register
//   ld_block2   - vector registers of N per block
//   rd_block    - K elements reduced per K block
//   bdb         - number of full M blocks
//   ldb2        - number of full N blocks
//   rdb         - number of full K blocks
//   bdb_tail    - M rows left over after the full M blocks
//   ldb2_tail   - full N registers left over after the full N blocks
//   ldb_tail    - N columns left over after every full N register
//   rdb_tail    - K elements left over after the full K blocks
struct loop_conf_t {
    brgemm_batch_kind_t batch_kind = brgemm_addr;
    dim_t max_bs = 0;
    dim_t load_dim = 0;
    dim_t lda = 0, ldb = 0, ldc = 0;
    int bd_block = 0, ld_block = 0, ld_block2 = 0, rd_block = 0;
    dim_t bdb = 0, ldb2 = 0, rdb = 0;
    int bdb_tail = 0, ldb2_tail = 0, ldb_tail = 0, rdb_tail = 0;
};

// Microkernel configuration.
//
//   compute_path - how the product is computed
//   dt_a/dt_b    - element data type of A and B in memory
//   dt_acc       - accumulation data type
struct microkernel_conf_t {
    compute_path_t compute_path = compute_path_t::vector;
    data_type_t dt_a = data_type::undef;
    data_type_t dt_b = data_type::undef;
    data_type_t dt_acc = data_type::undef;
};

// Output path configuration.
//
//   beta      - output scaling: 0 overwrites C, 1 accumulates into C
//   with_bias - whether a bias is added to the output
//   dt_c      - element data type of C and D in memory
//   dt_bias   - element data type of the bias
//   with_injector_postops - whether attribute post-ops (eltwise, binary, sum)
//               are requested
//   post_ops  - the attribute post-ops, applied through the post-ops injector
//   dst_md    - the destination memory descriptor, which a binary post-op
//               needs to locate its right-hand-side argument
//   with_src_scales  - whether a common source scale multiplies the output
//   with_wei_scales  - whether a weights scale multiplies the output
//   per_n_wei_scales - whether the weights scale has one value per output
//               column. Otherwise it is one common value
//   with_dst_scales  - whether a common destination scale multiplies the
//               output
//   dt_src_scales / dt_wei_scales - element data type of each scale
struct output_conf_t {
    float beta = 0.0f;
    bool with_bias = false;
    data_type_t dt_c = data_type::undef;
    data_type_t dt_bias = data_type::undef;
    bool with_injector_postops = false;
    post_ops_t post_ops;
    memory_desc_t dst_md;
    bool with_src_scales = false;
    bool with_wei_scales = false;
    bool per_n_wei_scales = false;
    bool with_dst_scales = false;
    data_type_t dt_src_scales = data_type::undef;
    data_type_t dt_wei_scales = data_type::undef;

    // True if the kernel has anything to apply on a post-ops call: the bias, a
    // scale, or an attribute post-op.
    bool has_post_ops() const {
        return with_bias || with_injector_postops || with_src_scales
                || with_wei_scales || with_dst_scales;
    }
};

// Builder configuration.
//
//   loop        - loop nest configuration
//   microkernel - microkernel configuration
//   output      - output path configuration
//
// The member functions derive the addressing of the builder from the module
// configurations.
struct conf_t {
    loop_conf_t loop;
    microkernel_conf_t microkernel;
    output_conf_t output;

    // Element sizes in bytes of A, B, C, and the bias. The bias size is 0
    // without a bias.
    int dt_sz_a() const { return (int)types::data_type_size(microkernel.dt_a); }
    int dt_sz_b() const { return (int)types::data_type_size(microkernel.dt_b); }
    int dt_sz_c() const { return (int)types::data_type_size(output.dt_c); }
    int dt_sz_bias() const {
        return output.with_bias ? (int)types::data_type_size(output.dt_bias)
                                : 0;
    }
    // Element size in bytes of a per-N weights scale, 0 for a common one,
    // which is never indexed.
    int dt_sz_wei_scales() const {
        return output.per_n_wei_scales
                ? (int)types::data_type_size(output.dt_wei_scales)
                : 0;
    }

    // Distance in bytes a B load prefetches ahead, one K block of B rows.
    dim_t rdb_b_off() const { return dt_sz_b() * loop.rd_block * loop.ldb; }

    // Displacements of one element of A, one vector of B, and one accumulator
    // of C of the block at `pos`, from where the pointers stand.
    //
    // These are the constants the builder encodes into the operation, the
    // `disp` of `ir::mem_t`. They are functions rather than expressions written
    // at each use because `init_conf()` range-checks the largest of them
    // against int32, and the check is only meaningful if there is consistency
    // between the check and the builder. A pointer move by `pos` adds the same
    // values, with every index 0.

    // A is read one element at a time and broadcast, so `rd` is an element
    // index.
    dim_t a_off(const block_pos_t &pos, int bd, int rd) const {
        return dt_sz_a() * ((pos.m + bd) * loop.lda + pos.k + rd);
    }

    // B is read one full vector per `ld`, so `rd` is a row index and `ld`
    // picks the vector within the N block.
    dim_t b_off(const block_pos_t &pos, int ld, int rd) const {
        return dt_sz_b() * ((pos.k + rd) * loop.ldb + ld_pos(pos, ld));
    }

    dim_t c_off(const block_pos_t &pos, int bd, int ld) const {
        return dt_sz_c() * ((pos.m + bd) * loop.ldc + ld_pos(pos, ld));
    }

    // One bias value per output column, so the offset has no row term.
    dim_t bias_off(const block_pos_t &pos, int ld) const {
        return dt_sz_bias() * ld_pos(pos, ld);
    }

    // A per-N weights scale is indexed like the bias.
    dim_t wei_scale_off(const block_pos_t &pos, int ld) const {
        return dt_sz_wei_scales() * ld_pos(pos, ld);
    }

    // Load-dimension element the vector `ld` of the block starts at, counted
    // from where the B and C pointers stand. B and C differ only in the
    // element size they scale it by.
    dim_t ld_pos(const block_pos_t &pos, int ld) const {
        return pos.n + (dim_t)ld * loop.ld_block;
    }
};

// M-loop input register classification
//
// The same split the GEMV IR kernel uses (see `brgemv_ir.cpp`), by whether a
// value advances across M-loop iterations. The one difference is that this
// loop nest has two levels over the output, M and N, so the level a register
// advances at is stated per field instead of shared by the struct.
//
// Design rule:
// - A field's vreg ID never changes after assignment.
// - Because of this, these structs are passed by const reference.
//
// Note:
// - Registers created inside a loop body (the accumulators, the B vectors, the
//   A broadcast, and the batch, A, and B pointers) are local temporaries and
//   are not included here.

// Registers that advance by a fixed byte offset as the nest walks the output.
struct advancing_regs_t {
    // Current C pointer. The N loop advances it by one block per iteration,
    // then the M loop rewinds it and steps to the next M block with one
    // constant. The classic kernel keeps a second base pointer for this
    // instead. One running pointer saves the general-purpose register.
    ir::vreg_t c_ptr = ir::vreg_t::none;
    // Pointer the finished block is stored through. It holds the `ptr_D`
    // kernel argument on a post-ops call and `ptr_C` otherwise, and can be the
    // same register as `c_ptr` (see `init_m_loop_input_regs()`). C and D have
    // the same data type and leading dimension (`init_output_conf()`), so it
    // advances like `c_ptr`.
    ir::vreg_t store_ptr = ir::vreg_t::none;
    // Byte offset into A of the current M block. Starts at 0 and advances by
    // one block per iteration of the M loop.
    ir::vreg_t a_off = ir::vreg_t::none;
    // Byte offset into B of the current N block. Advances by one block per
    // iteration of the N loop and is set back before the next M block.
    ir::vreg_t b_off = ir::vreg_t::none;
    // Current bias pointer. The bias is indexed by the load dimension only, so
    // it advances with the N loop and is rewound before the next M block.
    // `none` unless `with_bias`.
    ir::vreg_t bias_ptr = ir::vreg_t::none;
    // Current weights-scale pointer. A per-N scale advances and rewinds like
    // `bias_ptr`, a common one stays at its only element.
    // `none` unless `with_wei_scales`.
    ir::vreg_t wei_scale_ptr = ir::vreg_t::none;
};

// Registers that hold the same value for the entire M loop.
struct invariant_regs_t {
    // Base pointer of the batch-element array.
    ir::vreg_t batch = ir::vreg_t::none;
    // Batch size loop count. `none` when max_bs == 1 (single batch element).
    ir::vreg_t bs = ir::vreg_t::none;
    // A and B base pointers, the `ptr_A` and `ptr_B` kernel arguments, which
    // `brgemm_offs` adds the byte offsets of each batch element to. `none` for
    // `brgemm_addr`, where each element holds its own pointers.
    ir::vreg_t a_base = ir::vreg_t::none;
    ir::vreg_t b_base = ir::vreg_t::none;
    // The `do_post_ops` kernel argument. Non-zero applies the post-ops and
    // stores to D, zero stores to C. `none` when the kernel has no post-op.
    ir::vreg_t do_post_ops = ir::vreg_t::none;
    // Common source and destination scale pointers.
    // `none` unless `with_src_scales` and `with_dst_scales` respectively.
    ir::vreg_t src_scale_ptr = ir::vreg_t::none;
    ir::vreg_t dst_scale_ptr = ir::vreg_t::none;
};

// Complete input register set for the M loop, partitioned by whether values
// advance across iterations.
struct m_loop_input_regs_t {
    advancing_regs_t advancing;
    invariant_regs_t invariant;
};

// Sets up the M-loop input registers.
//
// Loads the kernel argument pointers and the batch count, and zeroes the
// running A and B offsets.
m_loop_input_regs_t init_m_loop_input_regs(ir::ir_t &ir, const conf_t &cfg) {
    m_loop_input_regs_t regs;

    regs.advancing.c_ptr = ir.new_gpr();
    ir.load_param(regs.advancing.c_ptr, GET_OFF(ptr_C));

    regs.invariant.batch = ir.new_gpr();
    ir.load_param(regs.invariant.batch, GET_OFF(batch));

    if (cfg.loop.max_bs > 1) {
        regs.invariant.bs = ir.new_gpr();
        ir.load_param(regs.invariant.bs, GET_OFF(BS));
    }

    if (cfg.loop.batch_kind == brgemm_offs) {
        regs.invariant.a_base = ir.new_gpr();
        ir.load_param(regs.invariant.a_base, GET_OFF(ptr_A));
        regs.invariant.b_base = ir.new_gpr();
        ir.load_param(regs.invariant.b_base, GET_OFF(ptr_B));
    }

    regs.advancing.a_off = ir.new_gpr();
    ir.mov_imm(regs.advancing.a_off, 0);

    regs.advancing.b_off = ir.new_gpr();
    ir.mov_imm(regs.advancing.b_off, 0);

    if (cfg.output.with_bias) {
        regs.advancing.bias_ptr = ir.new_gpr();
        ir.load_param(regs.advancing.bias_ptr, GET_OFF(ptr_bias));
    }

    if (cfg.output.with_src_scales) {
        regs.invariant.src_scale_ptr = ir.new_gpr();
        ir.load_param(regs.invariant.src_scale_ptr, GET_OFF(ptr_src_scales));
    }

    if (cfg.output.with_wei_scales) {
        regs.advancing.wei_scale_ptr = ir.new_gpr();
        ir.load_param(regs.advancing.wei_scale_ptr, GET_OFF(ptr_wei_scales));
    }

    if (cfg.output.with_dst_scales) {
        regs.invariant.dst_scale_ptr = ir.new_gpr();
        ir.load_param(regs.invariant.dst_scale_ptr, GET_OFF(ptr_dst_scales));
    }

    // The block goes to `ptr_D` when `do_post_ops` is set, and to `ptr_C`
    // otherwise. Resolve that once here so that the stores do not branch.
    //
    // A post-ops call with `beta == 1` reads C for the accumulators and writes
    // D, so the two pointers need separate registers. C is never read when
    // `beta == 0`, so one register is enough and it holds `ptr_D` on a post-ops
    // call.
    if (cfg.output.has_post_ops()) {
        regs.invariant.do_post_ops = ir.new_gpr();
        ir.load_param(regs.invariant.do_post_ops, GET_OFF(do_post_ops));

        if (cfg.output.beta == 0.0f) {
            regs.advancing.store_ptr = regs.advancing.c_ptr;
        } else {
            regs.advancing.store_ptr = ir.new_gpr();
            ir.mov_reg(regs.advancing.store_ptr, regs.advancing.c_ptr);
        }

        const int if_post_ops
                = ir.if_begin(regs.invariant.do_post_ops, ir::cmp_t::ne, 0);
        ir.load_param(regs.advancing.store_ptr, GET_OFF(ptr_D));
        ir.if_end(if_post_ops);
    } else {
        regs.advancing.store_ptr = regs.advancing.c_ptr;
    }

    return regs;
}

// Iteration lists
//
// Each level of the loop nest (M, N, and K) has a list of its iterations,
// stored as runs of consecutive iterations with the same shape. The shape is
// everything the code of an iteration depends on apart from its position:
//   M - rows of the block (`bd_block` or `bdb_tail`)
//   N - `n_shape_t`
//   K - elements of the reduction step (`rd_block` or `rdb_tail`)
//
// The schedule builds the lists and emits each level from its list, so where
// the tails are is decided by the list and not by the code that emits them.
// The batch is a runtime loop with one shape, so it needs no list.

// Shape of an N block.
//
//   ld_block2  - vector registers the block covers
//   is_ld_tail - whether its one register is partial, holding `ldb_tail`
//                elements
struct n_shape_t {
    int ld_block2;
    bool is_ld_tail;
};

// A run of consecutive iterations of one level with the same shape.
//
//   shape - the shape of each iteration
//   start - position of the first iteration, in elements of the level's
//           dimension
//   size  - elements each iteration covers, which is also the distance
//           between consecutive iterations
//   count - number of iterations
template <typename shape_t>
struct run_t {
    shape_t shape;
    dim_t start;
    dim_t size;
    dim_t count;
};

// Iteration lists of the loop nest, one per level.
struct iteration_lists_t {
    std::vector<run_t<int>> m;
    std::vector<run_t<n_shape_t>> n;
    std::vector<run_t<int>> k;
};

// Appends a run of `count` iterations of `size` elements right after the last
// run of `runs`. Nothing is appended when `count` is 0.
template <typename shape_t>
void add_run(std::vector<run_t<shape_t>> &runs, const shape_t &shape,
        dim_t size, dim_t count) {
    if (count == 0) return;
    const dim_t start = runs.empty()
            ? 0
            : runs.back().start + runs.back().count * runs.back().size;
    runs.push_back({shape, start, size, count});
}

// Builds the iteration lists of the looped schedule.
//
// As in `jit_brgemm_kernel_t`, the full blocks of each level come first, and
// each tail is a run of its own. N has two tails: the full registers left over
// after the full blocks, then the one masked register.
iteration_lists_t make_looped_lists(const loop_conf_t &loop) {
    iteration_lists_t lists;

    add_run(lists.m, loop.bd_block, loop.bd_block, loop.bdb);
    add_run(lists.m, loop.bdb_tail, loop.bdb_tail, loop.bdb_tail > 0 ? 1 : 0);

    add_run(lists.n, n_shape_t {loop.ld_block2, false},
            (dim_t)loop.ld_block2 * loop.ld_block, loop.ldb2);
    add_run(lists.n, n_shape_t {loop.ldb2_tail, false},
            (dim_t)loop.ldb2_tail * loop.ld_block, loop.ldb2_tail > 0 ? 1 : 0);
    add_run(lists.n, n_shape_t {1, true}, loop.ldb_tail,
            loop.ldb_tail > 0 ? 1 : 0);

    add_run(lists.k, loop.rd_block, loop.rd_block, loop.rdb);
    add_run(lists.k, loop.rdb_tail, loop.rdb_tail, loop.rdb_tail > 0 ? 1 : 0);
    return lists;
}

// Where the pointers of a looped level stand after `run` if they stood at
// `ptr_pos` before it. A runtime loop runs its step after every iteration, the
// last one included. A run of one iteration has no step.
template <typename shape_t>
dim_t ptr_pos_after(const run_t<shape_t> &run, dim_t ptr_pos) {
    return run.count > 1 ? ptr_pos + run.count * run.size : ptr_pos;
}

// Emits one level of the loop nest from its list, as the looped schedule does.
//
// Each run becomes a runtime loop whose step moves the pointers by one
// iteration, so one copy of the body serves the whole run. A run of one
// iteration is emitted once and has no step (see `emit_loop_imm()`). The
// pointers never move to it. It is reached through its position, which saves
// the instructions of a move.
//
//   runs    - the iteration list of the level
//   ptr_pos - where the pointers of the level stand, in elements of its
//             dimension. It is updated to where the level leaves them.
//   body    - `body(shape, pos)` emits one iteration `pos` elements away from
//             the pointers
//   step    - `step(n)` emits the move of the pointers by `n` elements
template <typename shape_t, typename body_t, typename step_t>
void emit_looped_level(ir::ir_t &ir, const std::vector<run_t<shape_t>> &runs,
        dim_t &ptr_pos, const body_t &body, const step_t &step) {
    for (const run_t<shape_t> &run : runs) {
        const dim_t pos = run.start - ptr_pos;
        ir::emit_loop_imm(ir, run.count, [&]() { body(run.shape, pos); },
                [&]() { step(run.size); });
        ptr_pos = ptr_pos_after(run, ptr_pos);
    }
}

// Largest displacement and pointer move of a looped level, in elements of its
// dimension.
//
//   last - largest element an iteration addresses, counted from the pointers
//   step - largest step of a runtime loop
//   end  - where the pointers stand after the level
//
// M is walked once and K once per batch element, each with the pointers at
// the first position. N is walked once per M block. The M step returns the N
// pointers, but an M block that is not in a runtime loop leaves them at `end`,
// and the next M block walks N from there. Its positions are then between
// `-end` and `last`.
struct looped_bounds_t {
    dim_t last;
    dim_t step;
    dim_t end;
};

template <typename shape_t>
looped_bounds_t get_looped_bounds(const std::vector<run_t<shape_t>> &runs) {
    looped_bounds_t b {0, 0, 0};
    for (const run_t<shape_t> &run : runs) {
        b.last = std::max(b.last, run.start - b.end + run.size - 1);
        if (run.count > 1) b.step = std::max(b.step, run.size);
        b.end = ptr_pos_after(run, b.end);
    }
    return b;
}

// Innermost reduction step, over `rd_loop` elements of K.
//
// Loads one B vector per N register, then for each M row broadcasts one A
// element and multiply-adds it into that row's accumulators. This is the
// `!n_bcast_1_load` variant of `gemm_microkernel()` in `jit_brgemm_kernel.cpp`.
void emit_microkernel(ir::ir_t &ir, const conf_t &cfg, const out_block_t &blk,
        const block_pos_t &pos, const std::vector<ir::vreg_t> &acc,
        const std::vector<ir::vreg_t> &b, ir::vreg_t a, ir::vreg_t a_ptr,
        ir::vreg_t b_ptr, int rd_loop) {

    for (int rd = 0; rd < rd_loop; rd++) {
        // Only the last register of a block can be partial, and a block that
        // has one holds nothing else, so the mask covers every B load here.
        for (int ld = 0; ld < blk.ld_block2; ld++) {
            if (blk.ld_tail_mask == ir::vreg_t::none)
                ir.vload(b[ld], b_ptr, cfg.b_off(pos, ld, rd),
                        cfg.microkernel.dt_b);
            else
                ir.vload_masked(b[ld], b_ptr, cfg.b_off(pos, ld, rd),
                        blk.ld_tail_mask, cfg.microkernel.dt_b);
        }

        // One prefetch per B register, issued on the first `ld_block2` rows, so
        // each reduction step fetches the next K block of B exactly once.
        int n_pf_b = 0;
        for (int bd = 0; bd < blk.bd_block; bd++) {
            ir.vload_bcast(
                    a, a_ptr, cfg.a_off(pos, bd, rd), cfg.microkernel.dt_a);
            if (n_pf_b < blk.ld_block2) {
                // The prefetch is one K block past the B loads, so it is the
                // only access whose displacement can leave the matrix.
                // `check_displacements()` does not cover it. A prefetch that
                // does not fit is dropped.
                const dim_t pf_off
                        = cfg.b_off(pos, n_pf_b, rd) + cfg.rdb_b_off();
                if (fits_int32(pf_off)) ir.prefetch(b_ptr, pf_off);
                n_pf_b++;
            }

            for (int ld = 0; ld < blk.ld_block2; ld++)
                ir.vdot(acc[bd * blk.ld_block2 + ld], b[ld], a);
        }
    }
}

// One batch element.
//
// Derives the A and B pointers of the element, shifts them to the current M and
// N block, then runs the reduction loop over K.
void emit_bs_body(ir::ir_t &ir, const conf_t &cfg,
        const m_loop_input_regs_t &regs, const iteration_lists_t &lists,
        const out_block_t &blk, const block_pos_t &pos,
        const std::vector<ir::vreg_t> &acc, const std::vector<ir::vreg_t> &b,
        ir::vreg_t a, ir::vreg_t batch_ptr) {

    const ir::vreg_t a_ptr = ir.new_gpr();
    const ir::vreg_t b_ptr = ir.new_gpr();

    // Where this element's A and B start. Mirrors `set_A_B_matrices()` in
    // `jit_brgemm_kernel.cpp`.
    switch (cfg.loop.batch_kind) {
        case brgemm_addr:
            ir.load(a_ptr, batch_ptr, GET_OFF_BATCH_ELEMENT(ptr.A));
            ir.load(b_ptr, batch_ptr, GET_OFF_BATCH_ELEMENT(ptr.B));
            break;
        case brgemm_offs:
            ir.load(a_ptr, batch_ptr, GET_OFF_BATCH_ELEMENT(offset.A));
            ir.add_reg(a_ptr, regs.invariant.a_base);
            ir.load(b_ptr, batch_ptr, GET_OFF_BATCH_ELEMENT(offset.B));
            ir.add_reg(b_ptr, regs.invariant.b_base);
            break;
        default: assert(!"unsupported batch kind"); break;
    }

    // Shift to the current M and N block.
    ir.add_reg(a_ptr, regs.advancing.a_off);
    ir.add_reg(b_ptr, regs.advancing.b_off);

    // Advance to the next batch element. A single batch element has no next
    // one, so nothing is emitted then.
    if (cfg.loop.max_bs > 1) {
        ir.add_imm(batch_ptr, sizeof(brgemm_batch_element_t));
        // The classic kernel prefetches the next element for the address kind
        // only.
        if (cfg.loop.batch_kind == brgemm_addr) ir.prefetch(batch_ptr, 0);
    }

    // Advance the A and B pointers by `rd` elements of K.
    auto step = [&](dim_t rd) {
        const block_pos_t d {0, 0, rd};
        ir.add_imm(a_ptr, cfg.a_off(d, 0, 0));
        ir.add_imm(b_ptr, cfg.b_off(d, 0, 0));
    };

    // The K tail needs no mask. A reduction step reads a full B vector along N
    // and one element of A, so a short tail is just fewer steps.
    dim_t k_ptr_pos = 0;
    emit_looped_level(ir, lists.k, k_ptr_pos, [&](int rd_loop, dim_t k) {
        emit_microkernel(ir, cfg, blk, {pos.m, pos.n, k}, acc, b, a, a_ptr,
                b_ptr, rd_loop);
    }, step);
}

// One N block.
//
// Holds one accumulator per (M row, N register), reduces them over the batch,
// and stores them to C, or to D on a post-ops call.
void emit_n_block(ir::ir_t &ir, const conf_t &cfg,
        const m_loop_input_regs_t &regs, const iteration_lists_t &lists,
        const out_block_t &blk, const block_pos_t &pos) {

    std::vector<ir::vreg_t> acc(blk.bd_block * blk.ld_block2, ir::vreg_t::none);

    for (int bd = 0; bd < blk.bd_block; bd++) {
        for (int ld = 0; ld < blk.ld_block2; ld++) {
            const int i = bd * blk.ld_block2 + ld;
            acc[i] = ir.new_vec(cfg.microkernel.dt_acc);
            ir.vzero(acc[i]);
        }
    }

    std::vector<ir::vreg_t> b(blk.ld_block2, ir::vreg_t::none);
    for (int ld = 0; ld < blk.ld_block2; ld++)
        b[ld] = ir.new_vec(cfg.microkernel.dt_b);

    // Batch reduction over the bs dimension.
    const ir::vreg_t batch_ptr = ir.new_gpr();
    ir.mov_reg(batch_ptr, regs.invariant.batch);

    const ir::vreg_t a = ir.new_vec(cfg.microkernel.dt_a);

    auto bs_body = [&]() {
        emit_bs_body(ir, cfg, regs, lists, blk, pos, acc, b, a, batch_ptr);
    };

    if (cfg.loop.max_bs > 1)
        ir::emit_loop_reg(ir, regs.invariant.bs, bs_body);
    else
        ir::emit_loop_imm(ir, 1, bs_body);

    // The kernel takes only 0 and 1 for beta. C is added after the reduction,
    // as in the classic kernel. Loading it into the accumulators up front
    // would make every FMA chain wait for those loads.
    if (cfg.output.beta != 0.0f) {
        for (int bd = 0; bd < blk.bd_block; bd++) {
            for (int ld = 0; ld < blk.ld_block2; ld++) {
                const ir::vreg_t c = ir.new_vec(cfg.output.dt_c);
                if (blk.ld_tail_mask == ir::vreg_t::none)
                    ir.vload(c, regs.advancing.c_ptr, cfg.c_off(pos, bd, ld),
                            cfg.output.dt_c);
                else
                    ir.vload_masked(c, regs.advancing.c_ptr,
                            cfg.c_off(pos, bd, ld), blk.ld_tail_mask,
                            cfg.output.dt_c);
                ir.vadd(acc[bd * blk.ld_block2 + ld], c);
            }
        }
    }

    if (cfg.output.has_post_ops()) {
        // The order is the one oneDNN defines and the classic kernel follows:
        //   src scale -> weights scale -> bias -> post-ops -> dst scale.
        // The scales are applied one at a time, as in the classic kernel, so
        // the result rounds the same way.
        const int if_post_ops
                = ir.if_begin(regs.invariant.do_post_ops, ir::cmp_t::ne, 0);

        if (cfg.output.with_src_scales) {
            const ir::vreg_t sc = ir.new_vec(cfg.output.dt_src_scales);
            ir.vload_bcast(sc, regs.invariant.src_scale_ptr, 0,
                    cfg.output.dt_src_scales);
            for (const ir::vreg_t &v : acc)
                ir.vmul(v, sc);
        }

        if (cfg.output.with_wei_scales && !cfg.output.per_n_wei_scales) {
            const ir::vreg_t sc = ir.new_vec(cfg.output.dt_wei_scales);
            ir.vload_bcast(sc, regs.advancing.wei_scale_ptr, 0,
                    cfg.output.dt_wei_scales);
            for (const ir::vreg_t &v : acc)
                ir.vmul(v, sc);
        }

        if (cfg.output.per_n_wei_scales) {
            // One scale vector per N register, shared by every M row of the
            // block.
            for (int ld = 0; ld < blk.ld_block2; ld++) {
                const ir::vreg_t sc = ir.new_vec(cfg.output.dt_wei_scales);
                if (blk.ld_tail_mask == ir::vreg_t::none)
                    ir.vload(sc, regs.advancing.wei_scale_ptr,
                            cfg.wei_scale_off(pos, ld),
                            cfg.output.dt_wei_scales);
                else
                    ir.vload_masked(sc, regs.advancing.wei_scale_ptr,
                            cfg.wei_scale_off(pos, ld), blk.ld_tail_mask,
                            cfg.output.dt_wei_scales);

                for (int bd = 0; bd < blk.bd_block; bd++)
                    ir.vmul(acc[bd * blk.ld_block2 + ld], sc);
            }
        }

        if (cfg.output.with_bias) {
            // One bias vector per N register, shared by every M row of the
            // block.
            for (int ld = 0; ld < blk.ld_block2; ld++) {
                const ir::vreg_t bias = ir.new_vec(cfg.output.dt_bias);
                if (blk.ld_tail_mask == ir::vreg_t::none)
                    ir.vload(bias, regs.advancing.bias_ptr,
                            cfg.bias_off(pos, ld), cfg.output.dt_bias);
                else
                    ir.vload_masked(bias, regs.advancing.bias_ptr,
                            cfg.bias_off(pos, ld), blk.ld_tail_mask,
                            cfg.output.dt_bias);

                for (int bd = 0; bd < blk.bd_block; bd++)
                    ir.vadd(acc[bd * blk.ld_block2 + ld], bias);
            }
        }

        if (cfg.output.with_injector_postops) {
            // The injector gets the address of the block and the offset of
            // each accumulator inside it, as `jit_brgemm_kernel_t` passes
            // `reg_aux_D` and `D_offset()`. A binary post-op decodes the
            // output coordinates of an accumulator from the register at run
            // time and from the offset at JIT time (`calculate_*_partial()` in
            // the binary injector), so an offset that leaves the block can
            // give the wrong coordinates. A block away from the pointers gets
            // its address in a register of its own. A sum post-op reads the
            // previous value from the same address.
            ir::vreg_t blk_ptr = regs.advancing.store_ptr;
            if (pos.m != 0 || pos.n != 0) {
                blk_ptr = ir.new_gpr();
                ir.mov_reg(blk_ptr, regs.advancing.store_ptr);
                ir.add_imm(blk_ptr, cfg.c_off(pos, 0, 0));
            }

            const block_pos_t blk_start {0, 0, 0};
            std::vector<dim_t> out_byte_off(acc.size());
            for (int bd = 0; bd < blk.bd_block; bd++)
                for (int ld = 0; ld < blk.ld_block2; ld++)
                    out_byte_off[bd * blk.ld_block2 + ld]
                            = cfg.c_off(blk_start, bd, ld);

            // A block is either all full registers or the one masked
            // register of the N tail, which holds `ldb_tail` elements.
            const int n_elems = blk.ld_tail_mask != ir::vreg_t::none
                    ? cfg.loop.ldb_tail
                    : cfg.loop.ld_block;
            ir.inject_postops(acc, blk_ptr, out_byte_off, n_elems);
        }

        if (cfg.output.with_dst_scales) {
            // The caller passes the inverted f32 destination scale, so it is a
            // multiply.
            const ir::vreg_t sc = ir.new_vec(data_type::f32);
            ir.vload_bcast(sc, regs.invariant.dst_scale_ptr, 0, data_type::f32);
            for (const ir::vreg_t &v : acc)
                ir.vmul(v, sc);
        }

        ir.if_end(if_post_ops);
    }

    // `store_ptr` already points at C or D, so the stores do not branch. Their
    // memory data type is fixed when the IR is built, which is why C and D must
    // share one.
    for (int bd = 0; bd < blk.bd_block; bd++) {
        for (int ld = 0; ld < blk.ld_block2; ld++) {
            const ir::vreg_t src = acc[bd * blk.ld_block2 + ld];

            if (blk.ld_tail_mask == ir::vreg_t::none) {
                ir.vstore(regs.advancing.store_ptr, cfg.c_off(pos, bd, ld), src,
                        cfg.output.dt_c);
            } else {
                ir.vstore_masked(regs.advancing.store_ptr,
                        cfg.c_off(pos, bd, ld), src, blk.ld_tail_mask,
                        cfg.output.dt_c);
            }
        }
    }
}

// Builds IR for BRGEMM.
//
// Computes:
//   C[i][j] = beta * C[i][j] + sum_bs sum_k A[i][k] * B[k][j]
//   (m = `bcast_dim`, n = `load_dim`, k = `reduce_dim` of the descriptor)
//
// A call that asks for post-ops applies the scales, bias and attribute
// post-ops, and stores to D instead of C:
//   D[i][j] = post_ops(C[i][j] * src_scale * wei_scale[j] + bias[j])
//             * dst_scale
//
// The output is partitioned into M blocks of `bd_block` rows, each split into
// N blocks of `ld_block2 * ld_block` columns. Each block keeps its result in
// registers across the whole batch and K reduction, then stores it once. The
// looped schedule walks N inside M, as `jit_brgemm_kernel_t` does.
void build_brgemm(const conf_t &cfg, ir::ir_t &ir) {
    const m_loop_input_regs_t regs = init_m_loop_input_regs(ir, cfg);
    const iteration_lists_t lists = make_looped_lists(cfg.loop);

    // Every partial N block is the same width, so one mask serves the whole
    // kernel.
    ir::vreg_t ld_tail_mask = ir::vreg_t::none;

    if (cfg.loop.ldb_tail > 0) {
        ld_tail_mask = ir.new_mask();
        ir.set_mask_imm(ld_tail_mask, cfg.loop.ldb_tail);
    }

    // Where the M and N pointers stand, and where the N pointers stood when
    // the current M block started.
    dim_t m_ptr_pos = 0, n_ptr_pos = 0, n_start = 0;

    // Advance the N pointers by `ld` columns. `store_ptr` is a separate
    // register only when `beta == 1` and the kernel has a post-op, so it needs
    // its own advance only then.
    auto n_step = [&](dim_t ld) {
        const block_pos_t d {0, ld, 0};
        ir.add_imm(regs.advancing.b_off, cfg.b_off(d, 0, 0));
        ir.add_imm(regs.advancing.c_ptr, cfg.c_off(d, 0, 0));
        if (regs.advancing.store_ptr != regs.advancing.c_ptr)
            ir.add_imm(regs.advancing.store_ptr, cfg.c_off(d, 0, 0));
        if (cfg.output.with_bias)
            ir.add_imm(regs.advancing.bias_ptr, cfg.bias_off(d, 0));
        if (cfg.output.per_n_wei_scales)
            ir.add_imm(regs.advancing.wei_scale_ptr, cfg.wei_scale_off(d, 0));
    };

    // Advance the M pointers by `bd` rows and return the N pointers to where
    // the M block found them.
    //
    // C moves along both dimensions with one `add`. The bias and a per-N
    // weights scale do not depend on M, so they only return. The B offset
    // depends on N only, so it is set rather than moved.
    auto m_step = [&](dim_t bd) {
        const block_pos_t d {bd, n_start - n_ptr_pos, 0};
        ir.add_imm(regs.advancing.a_off, cfg.a_off(d, 0, 0));
        ir.add_imm(regs.advancing.c_ptr, cfg.c_off(d, 0, 0));
        if (regs.advancing.store_ptr != regs.advancing.c_ptr)
            ir.add_imm(regs.advancing.store_ptr, cfg.c_off(d, 0, 0));
        if (cfg.output.with_bias && d.n != 0)
            ir.add_imm(regs.advancing.bias_ptr, cfg.bias_off(d, 0));
        if (cfg.output.per_n_wei_scales && d.n != 0)
            ir.add_imm(regs.advancing.wei_scale_ptr, cfg.wei_scale_off(d, 0));
        if (d.n != 0)
            ir.mov_imm(regs.advancing.b_off, cfg.b_off({0, n_start, 0}, 0, 0));
        n_ptr_pos = n_start;
    };

    emit_looped_level(ir, lists.m, m_ptr_pos, [&](int bd_block, dim_t m) {
        n_start = n_ptr_pos;
        emit_looped_level(
                ir, lists.n, n_ptr_pos, [&](const n_shape_t &shape, dim_t n) {
            const out_block_t blk {bd_block, shape.ld_block2,
                    shape.is_ld_tail ? ld_tail_mask : ir::vreg_t::none};
            emit_n_block(ir, cfg, regs, lists, blk, {m, n, 0});
        }, n_step);
    }, m_step);
}

// Picks the compute path the caller chose when it created the descriptor.
//
// The finalized descriptor already holds the choice (`is_ace()`, `is_tmm`), so
// it is read from there. Only the vector compute path exists so far, and the
// tile compute paths are rejected.
status_t init_compute_path(
        compute_path_t &compute_path, const brgemm_desc_t &brg) {
    VCONDCHECK_BRGEMM_IR(!brg.is_tmm && !brg.is_ace(),
            VERBOSE_UNSUPPORTED_FEATURE, "tile accumulation");

    compute_path = compute_path_t::vector;
    return status::success;
}

// Fills the loop nest configuration.
status_t init_loop_conf(loop_conf_t &loop, const brgemm_desc_t &brg) {
    using namespace utils;
    const brgemm_attr_t &brgattr = brg.brgattr;

    VCONDCHECK_BRGEMM_IR(one_of(brg.type, brgemm_addr, brgemm_offs),
            VERBOSE_UNSUPPORTED_FEATURE, "batch kind");
    VCONDCHECK_BRGEMM_IR(!brgattr.var_bs, VERBOSE_UNSUPPORTED_FEATURE,
            "variable batch size");
    VCONDCHECK_BRGEMM_IR(brg.layout == brgemm_row_major,
            VERBOSE_UNSUPPORTED_FEATURE, "column-major layout");
    VCONDCHECK_BRGEMM_IR(
            !brg.is_blocked, VERBOSE_UNSUPPORTED_FEATURE, "blocked layout");
    VCONDCHECK_BRGEMM_IR(everyone_is(false, brg.is_runtime_lda,
                                 brg.is_runtime_ldb, brg.is_runtime_ldc),
            VERBOSE_UNSUPPORTED_FEATURE, "runtime leading dimension");
    VCONDCHECK_BRGEMM_IR(
            everyone_is(0, brgattr.max_top_vpad, brgattr.max_bottom_vpad),
            VERBOSE_UNSUPPORTED_PAD_FEATURE, "virtual padding");
    VCONDCHECK_BRGEMM_IR(
            everyone_is(0, brgattr.max_top_bpad, brgattr.max_bottom_bpad),
            VERBOSE_UNSUPPORTED_PAD_FEATURE, "batch padding");
    VCONDCHECK_BRGEMM_IR(
            brgattr.bd_mask_level == 0, VERBOSE_UNSUPPORTED_FEATURE, "bd_mask");

    loop.batch_kind = brg.type;
    loop.max_bs = brgattr.max_bs;
    loop.load_dim = brg.load_dim;
    loop.lda = brg.LDA;
    loop.ldb = brg.LDB;
    loop.ldc = brg.LDC;
    loop.bd_block = brg.bd_block;
    loop.ld_block = brg.ld_block;
    loop.ld_block2 = brg.ld_block2;
    loop.rd_block = brg.rd_block;
    loop.bdb = brg.bdb;
    loop.ldb2 = brg.ldb2;
    loop.rdb = brg.rdb;
    loop.bdb_tail = brg.bdb_tail;
    loop.ldb2_tail = brg.ldb2_tail;
    loop.ldb_tail = brg.ldb_tail;
    loop.rdb_tail = brg.rdb_tail;
    return status::success;
}

// Fills the microkernel configuration of the vector compute path.
status_t init_microkernel_conf(
        microkernel_conf_t &microkernel, const brgemm_desc_t &brg) {
    using namespace data_type;

    // `avx2` and `avx512_core` compute f32 directly. The other ISAs receive
    // inputs already converted to f32.
    VCONDCHECK_BRGEMM_IR(utils::one_of(brg.isa_impl, avx2, avx512_core,
                                 avx512_core_fp16, avx10_2),
            VERBOSE_UNSUPPORTED_ISA);
    VCONDCHECK_BRGEMM_IR(utils::everyone_is(f32, brg.dt_a, brg.dt_b),
            VERBOSE_UNSUPPORTED_DT);
    VCONDCHECK_BRGEMM_IR(!brg.n_bcast_1_load, VERBOSE_UNSUPPORTED_FEATURE,
            "one-load microkernel");
    VCONDCHECK_BRGEMM_IR(!brg.embd_bcst, VERBOSE_UNSUPPORTED_FEATURE,
            "embedded broadcast microkernel");

    microkernel.dt_a = brg.dt_a;
    microkernel.dt_b = brg.dt_b;
    microkernel.dt_acc = f32;
    return status::success;
}

// Fills the output path configuration.
status_t init_output_conf(output_conf_t &output, const brgemm_desc_t &brg) {
    using namespace data_type;
    using namespace utils;
    const brgemm_attr_t &brgattr = brg.brgattr;

    VCONDCHECK_BRGEMM_IR(
            everyone_is(f32, brg.dt_c, brg.dt_d), VERBOSE_UNSUPPORTED_DT);
    VCONDCHECK_BRGEMM_IR(
            brg.alpha == 1.0f, VERBOSE_UNSUPPORTED_FEATURE, "alpha != 1");
    VCONDCHECK_BRGEMM_IR(brg.beta == 0.0f || brg.beta == 1.0f,
            VERBOSE_UNSUPPORTED_FEATURE, "beta != 0 && beta != 1");

    VCONDCHECK_BRGEMM_IR(!brg.req_s8s8_compensation,
            VERBOSE_UNSUPPORTED_FEATURE, "s8s8 compensation");
    VCONDCHECK_BRGEMM_IR(!brgattr.use_intermediate_c_buffer,
            VERBOSE_UNSUPPORTED_FEATURE, "intermediate C buffer");
    VCONDCHECK_BRGEMM_IR(everyone_is(brgemm_broadcast_t::none, brg.zp_type_a,
                                 brg.zp_type_b, brg.zp_type_c),
            VERBOSE_UNSUPPORTED_ZP_CFG);
    VCONDCHECK_BRGEMM_IR(!brgattr.generate_skip_accumulation,
            VERBOSE_UNSUPPORTED_FEATURE, "skip accumulation");
    VCONDCHECK_BRGEMM_IR(brgattr.hint_prefetchw == brgemm_prfw_default,
            VERBOSE_UNSUPPORTED_FEATURE, "store prefetch hint");

    // Post-ops go through the JIT injector. Accept eltwise, binary and sum, and
    // only binary arguments the injector can handle on this ISA.
    if (brg.attr()) {
        const memory_desc_wrapper dst_d(brg.dst_md());
        const std::vector<injector::post_op_type> accepted
                = {injector::eltwise, injector::binary, injector::sum};
        VCONDCHECK_BRGEMM_IR(
                injector::post_ops_ok({brg.isa_impl, accepted,
                        brg.attr()->post_ops_, &dst_d,
                        /*sum_at_pos_0_only=*/false,
                        /*sum_requires_scale_one=*/false,
                        /*sum_requires_zp_zero=*/false,
                        /*sum_requires_same_params=*/false,
                        binary_injector::
                                get_all_strategies_supported_by_injector()}),
                VERBOSE_UNSUPPORTED_POSTOP);
    }

    // Scales are f32 values the kernel broadcasts or loads per N register:
    // src and dst scales are common, the weights scale common or per-N.
    VCONDCHECK_BRGEMM_IR(
            !brg.has_per_k_scales(), VERBOSE_UNSUPPORTED_SCALES_CFG);
    VCONDCHECK_BRGEMM_IR(
            IMPLICATION(brg.with_src_scales, brg.dt_src_scales == f32),
            VERBOSE_UNSUPPORTED_SCALES_CFG);
    VCONDCHECK_BRGEMM_IR(
            IMPLICATION(brg.with_wei_scales, brg.dt_wei_scales == f32),
            VERBOSE_UNSUPPORTED_SCALES_CFG);
    VCONDCHECK_BRGEMM_IR(!brg.with_weights_scale_adjust,
            VERBOSE_UNSUPPORTED_FEATURE, "weights scale adjust");

    VCONDCHECK_BRGEMM_IR(IMPLICATION(brg.with_bias, brg.dt_bias == f32),
            VERBOSE_UNSUPPORTED_BIAS_CFG);
    VCONDCHECK_BRGEMM_IR(!brg.is_runtime_ldd, VERBOSE_UNSUPPORTED_FEATURE,
            "runtime leading dimension");

    output.beta = brg.beta;
    output.with_bias = brg.with_bias;
    output.dt_c = brg.dt_c;
    output.dt_bias = brg.dt_bias;
    output.with_injector_postops
            = brg.with_eltwise || brg.with_binary || brg.with_sum;
    if (output.with_injector_postops) {
        output.post_ops = brg.attr()->post_ops_;
        output.dst_md = *brg.dst_md();
    }
    output.with_src_scales = brg.with_src_scales;
    output.with_wei_scales = brg.with_wei_scales;
    output.per_n_wei_scales = brg.with_wei_scales && !brg.is_single_wei_scale;
    output.with_dst_scales = brg.with_dst_scales;
    output.dt_src_scales = brg.dt_src_scales;
    output.dt_wei_scales = brg.dt_wei_scales;

    // A post-ops call stores to D through the C displacements.
    VCONDCHECK_BRGEMM_IR(IMPLICATION(output.has_post_ops(), brg.LDC == brg.LDD),
            VERBOSE_UNSUPPORTED_FEATURE, "LDC != LDD");
    return status::success;
}

// Rejects a configuration whose addresses the builder cannot encode.
//
// Every address the builder emits is a base register plus a build-time
// displacement encoded in the instruction, and every pointer move is a
// build-time immediate. The largest of them come from the iteration lists the
// builder emits (see `get_looped_bounds()`). The B prefetch is the exception,
// see `emit_microkernel()`.
status_t check_displacements(const conf_t &conf) {
    const iteration_lists_t lists = make_looped_lists(conf.loop);
    const looped_bounds_t m = get_looped_bounds(lists.m);
    const looped_bounds_t n = get_looped_bounds(lists.n);
    const looped_bounds_t k = get_looped_bounds(lists.k);

    // `last` bounds the displacements, along N in both directions (see
    // `looped_bounds_t`). `move` bounds the pointer moves: one loop step per
    // level, and for N also the return in the M step. The M step does both in
    // one `add` on C, whose value is at most `c_off(move, 0, 0)`.
    const block_pos_t last {m.last, std::max(n.last, n.end), k.last};
    const block_pos_t move {m.step, std::max(n.step, n.end), k.step};

    VCONDCHECK_BRGEMM_IR(fits_int32(conf.a_off(last, 0, 0))
                    && fits_int32(conf.a_off(move, 0, 0)),
            VERBOSE_UNSUPPORTED_FEATURE, "A displacement overflows int32");
    VCONDCHECK_BRGEMM_IR(fits_int32(conf.b_off(last, 0, 0))
                    && fits_int32(conf.b_off(move, 0, 0)),
            VERBOSE_UNSUPPORTED_FEATURE, "B displacement overflows int32");
    VCONDCHECK_BRGEMM_IR(fits_int32(conf.c_off(last, 0, 0))
                    && fits_int32(conf.c_off(move, 0, 0)),
            VERBOSE_UNSUPPORTED_FEATURE, "C displacement overflows int32");
    VCONDCHECK_BRGEMM_IR(fits_int32(conf.bias_off(last, 0))
                    && fits_int32(conf.bias_off(move, 0)),
            VERBOSE_UNSUPPORTED_FEATURE, "bias displacement overflows int32");
    VCONDCHECK_BRGEMM_IR(fits_int32(conf.wei_scale_off(last, 0))
                    && fits_int32(conf.wei_scale_off(move, 0)),
            VERBOSE_UNSUPPORTED_FEATURE,
            "weights scale displacement overflows int32");

    return status::success;
}

// Reads the descriptor into `conf`.
//
// Returns `status::success` if the kernel supports the descriptor, otherwise
// `status::unimplemented`. This is the only code that reads the descriptor for
// the builder. Each part of `conf` has its own function, which rejects
// what its module does not support. A descriptor the kernel rejects falls back
// to the classic kernel.
//
// TODO: reject `mem_advice` or implement it. For the vector compute path the
// classic kernel loads B with `vmovrsd` when it is set, and matmul sets it on
// avx10_2.
status_t init_conf(conf_t &conf, const brgemm_desc_t &brg) {
    // GEMV and DGMM have kernels of their own.
    VCONDCHECK_BRGEMM_IR(!brg.is_gemv, VERBOSE_UNSUPPORTED_FEATURE, "gemv");
    VCONDCHECK_BRGEMM_IR(!brg.is_dgmm, VERBOSE_UNSUPPORTED_FEATURE, "dgmm");

    CHECK(init_compute_path(conf.microkernel.compute_path, brg));
    CHECK(init_loop_conf(conf.loop, brg));
    CHECK(init_microkernel_conf(conf.microkernel, brg));
    CHECK(init_output_conf(conf.output, brg));
    return check_displacements(conf);
}

// IR-based BRGEMM kernel.
struct jit_brgemm_ir_kernel_t : public brgemm_kernel_t {
    DECLARE_CPU_JIT_AUX_FUNCTIONS(jit_brgemm_ir_kernel_t)

    jit_brgemm_ir_kernel_t(cpu_isa_t isa, const conf_t &conf)
        : brgemm_kernel_t(jit_name(), isa), conf_(conf) {}

    void generate() override {
        ir::ir_t ir;
        build_brgemm(conf_, ir);

        ir::postops_config_t postops;
        if (conf_.output.with_injector_postops) {
            postops.post_ops = &conf_.output.post_ops;
            postops.dst_md = &conf_.output.dst_md;
            postops.rhs_arg_offset = GET_OFF(post_ops_binary_rhs_arg_vec);
            postops.dst_orig_off = GET_OFF(data_C_ptr_);
        }

        ir::generate_kernel(*this, ir, postops);
    }

private:
    conf_t conf_;
};

} // namespace

brgemm_kernel_t *create_brgemm_ir_kernel(const brgemm_desc_t &brg) {
    conf_t conf;
    if (init_conf(conf, brg) != status::success) return nullptr;
    return new jit_brgemm_ir_kernel_t(brg.isa_impl, conf);
}

} // namespace x64
} // namespace cpu
} // namespace impl
} // namespace dnnl
