#include <sys/mman.h>
/* This file is part of the dynarmic project.
 * Copyright (c) 2016 MerryMage
 * SPDX-License-Identifier: 0BSD
 */

#include <atomic>
#include <cstdio>
#include <algorithm>
#include <array>
#include <cstdlib>
#include <cstring>
#include <ctime>
#include <memory>
#include <mutex>

#include <unistd.h>

#include <boost/icl/interval_set.hpp>
#include <mcl/assert.hpp>
#include <mcl/bit_cast.hpp>
#include <mcl/scope_exit.hpp>

#include "dynarmic/backend/x64/a64_emit_x64.h"
#include "dynarmic/backend/x64/a64_jitstate.h"
#include "dynarmic/backend/x64/block_of_code.h"
#include "dynarmic/backend/x64/devirtualize.h"
#include "dynarmic/backend/x64/exclusive_monitor_friend.h"
#include "dynarmic/backend/x64/jitstate_info.h"
#include "dynarmic/common/atomic.h"
#include "dynarmic/common/x64_disassemble.h"
#include "dynarmic/frontend/A64/translate/a64_translate.h"
#include "dynarmic/interface/A64/a64.h"
#include "dynarmic/ir/basic_block.h"
#include "dynarmic/ir/opt/passes.h"

namespace Dynarmic::A64 {

// x86Code Speed 31 (debug): X86CODE_A64_LIVE_BINS=<file>: live translations binned by guest PC (dyld cache, placed
// Mach-Os in the cache window's top, anything else = unplaced app / plug-in code), rewritten every 256 blocks.
static void LiveBin(u64 pc, size_t insns, size_t bytes) {
    static const char* path = getenv("X86CODE_A64_LIVE_BINS");
    if (!path) return;
    static std::atomic<u64> n[3][3];
    const int b = pc >= 0x1c0000000ull && pc < 0x2ac000000ull ? 0 : pc >= 0x2ac000000ull && pc < 0x2c0000000ull ? 1 : 2;
    n[b][0]++; n[b][1] += insns; n[b][2] += bytes;
    if ((n[0][0] + n[1][0] + n[2][0]) % 256) return;
    char f[512];
    snprintf(f, sizeof f, "%s.%d", path, (int)getpid());
    if (FILE* o = fopen(f, "w")) {
        const char* nm[3] = {"cache", "placed", "other"};
        for (int i = 0; i < 3; i++)
            fprintf(o, "%s blocks %llu insns %llu x86 %llu\n", nm[i], (unsigned long long)n[i][0].load(), (unsigned long long)n[i][1].load(), (unsigned long long)n[i][2].load());
        fclose(o);
    }
}


using namespace Backend::X64;

static RunCodeCallbacks GenRunCodeCallbacks(A64::UserCallbacks* cb, CodePtr (*LookupBlock)(void* lookup_block_arg), void* arg, const A64::UserConfig& conf) {
    return RunCodeCallbacks{
        std::make_unique<ArgCallback>(LookupBlock, reinterpret_cast<u64>(arg)),
        std::make_unique<ArgCallback>(Devirtualize<&A64::UserCallbacks::AddTicks>(cb)),
        std::make_unique<ArgCallback>(Devirtualize<&A64::UserCallbacks::GetTicksRemaining>(cb)),
        conf.enable_cycle_counting,
    };
}

static std::function<void(BlockOfCode&)> GenRCP(const A64::UserConfig& conf) {
    return [conf](BlockOfCode& code) {
        if (conf.page_table) {
            code.mov(code.r14, mcl::bit_cast<u64>(conf.page_table));
        }
        if (conf.fastmem_pointer) {
            code.mov(code.r13, *conf.fastmem_pointer);
        }
    };
}

static Optimization::PolyfillOptions GenPolyfillOptions(const BlockOfCode& code) {
    return Optimization::PolyfillOptions{
        .sha256 = !code.HasHostFeature(HostFeature::SHA),
        .vector_multiply_widen = true,
    };
}

// x86Code: the translation side of a Jit (code, block map, emitter, fast dispatch table). A plain Jit owns one; with
// UserConfig::shared_translations several Jits (threads) share one. The dispatcher's block lookup finds the running
// Jit through a thread_local (t_running), so the emitted code does not depend on which Jit runs it.
struct Jit::SharedCode final {
    explicit SharedCode(UserConfig conf_)
            : conf(conf_)
            , block_of_code(GenRunCodeCallbacks(conf.callbacks, &LookupBlockThunk, nullptr, conf), JitStateInfo{A64JitState{}}, conf.code_cache_size, GenRCP(conf))
            , emitter(block_of_code, conf, nullptr)
            , polyfill_options(GenPolyfillOptions(block_of_code)) {
        emitter.shared_invalidate_gen = &invalidate_gen;
    }

    static CodePtr LookupBlockThunk(void*);

    const UserConfig conf;
    BlockOfCode block_of_code;
    A64EmitX64 emitter;
    Optimization::PolyfillOptions polyfill_options;
    std::recursive_mutex& mutex() { return emitter.shared_mutex; }
    Jit::SharedStats stats;  // under mutex()
    // Bumped under mutex() on every shared Invalidate/Clear so a thread that translated IR
    // without the lock can detect a concurrent invalidation and discard that IR.
    u64 invalidate_gen = 0;
};

Jit::SharedStats Jit::GetSharedStats(const SharedCode& shared) {
    return shared.stats;
}

void Jit::WithSharedLock(SharedCode& shared, void (*fn)(void*), void* arg) {
    std::unique_lock lock{shared.mutex()};
    fn(arg);
}

std::vector<std::uint64_t> Jit::GetDynamicDescriptors(SharedCode& shared, std::uint64_t lo, std::uint64_t hi) {
    return shared.emitter.DynamicDescriptors(lo, hi);
}

std::vector<std::uint64_t> Jit::GetUsedImageDescriptors(SharedCode& shared, std::uint64_t lo, std::uint64_t hi) {
    return shared.emitter.UsedImageDescriptors(lo, hi);
}

void Jit::SetCodeCacheAddress(std::uint64_t address) {
    Backend::X64::SetNextCodeCacheAddress(address);
}

void Jit::SetHostCallStubs(void* base, std::size_t bytes) {
    Backend::X64::SetHostCallStubs(base, bytes);
}

void Jit::SetFastDispatchEntries(std::size_t n) {
    Backend::X64::SetFastDispatchEntries(n);
}

std::string Jit::GetMemoryReport(SharedCode& shared) {
    std::unique_lock lock{shared.mutex()};
    return shared.emitter.MemoryReport();
}

std::shared_ptr<Jit::SharedCode> Jit::MakeSharedCode(UserConfig conf) {
    ASSERT(conf.shared_translations);
    return std::make_shared<SharedCode>(conf);
}

std::size_t Jit::SavePersistentCache(SharedCode& shared, const std::string& path,
                                     const std::uint8_t cache_uuid[16], std::uint64_t build_id,
                                     std::uint64_t cache_lo, std::uint64_t cache_hi) {
    return shared.emitter.SavePersistentCache(path, cache_uuid, build_id, cache_lo, cache_hi);  // locks itself
}

std::size_t Jit::LoadPersistentCache(SharedCode& shared, const std::string& path,
                                     const std::uint8_t cache_uuid[16], std::uint64_t build_id,
                                     std::uint64_t cache_lo, std::uint64_t cache_hi, bool shared_image) {
    std::unique_lock lock{shared.mutex()};
    const size_t n = shared.emitter.LoadPersistentCache(path, cache_uuid, build_id, cache_lo, cache_hi, shared_image);
    if (n) {
        shared.stats.blocks += n;
    }
    return n;
}

struct Jit::Impl final {
public:
    Impl(Jit*, UserConfig thread_conf, std::shared_ptr<SharedCode> shared_)
            : shared(shared_ ? std::move(shared_) : std::make_shared<SharedCode>(thread_conf))
            , conf(shared->conf)
            , block_of_code(shared->block_of_code)
            , emitter(shared->emitter)
            , polyfill_options(shared->polyfill_options) {
        ASSERT(conf.page_table_address_space_bits >= 12 && conf.page_table_address_space_bits <= 64);
        jit_state.tpidr_el0_ptr = thread_conf.tpidr_el0;
        jit_state.tpidrro_el0_ptr = thread_conf.tpidrro_el0;
        if (conf.global_monitor) {
            jit_state.excl_address_ptr = GetExclusiveMonitorAddressPointer(conf.global_monitor, thread_conf.processor_id);
            jit_state.excl_value_ptr = GetExclusiveMonitorValuePointer(conf.global_monitor, thread_conf.processor_id);
            jit_state.excl_lock_ptr =
                reinterpret_cast<void*>(const_cast<int*>(GetExclusiveMonitorLockPointer(conf.global_monitor)));
            jit_state.excl_addresses_base = GetExclusiveMonitorAddressPointer(conf.global_monitor, 0);
            if (conf.shared_translations && conf.HasOptimization(OptimizationFlag::Unsafe_IgnoreGlobalMonitor)) {
                jit_state.excl_address_ptr = &jit_state.own_excl_address;
                jit_state.excl_value_ptr = jit_state.own_excl_value;
            }
        }
    }

    ~Impl() = default;

    void Pretranslate(u64 location_descriptor) {
        GetBlock(IR::LocationDescriptor{location_descriptor});
    }
    bool PretranslateCollect(u64 location_descriptor, std::vector<u64>& successors) {
        const u64 before = shared ? shared->stats.blocks : 0;
        emitter.aot_successors = &successors;
        GetBlock(IR::LocationDescriptor{location_descriptor});
        emitter.aot_successors = nullptr;
        return !shared || shared->stats.blocks != before;
    }

    HaltReason Run() {
        // x86code: Run may be re-entered from a callback (a native function calling back into guest code on the same
        // thread). The caller saves and restores the guest state around the nested run. Code may only be freed at the
        // outermost level: the outer run is still inside a block. A nested run passes cache invalidation requests on.
        const bool nested = run_depth > 0;
        if (!nested) {
            PerformRequestedCacheInvalidation(static_cast<HaltReason>(Atomic::Load(&jit_state.halt_reason)));
        }
        // Shared IC invalidate unlinks blocks but does not touch per-thread RSB. Drop stale return
        // predictions whenever we observe a newer invalidate_gen (monotonic, lock-free read).
        if (conf.shared_translations && shared) {
            const u64 gen = shared->invalidate_gen;
            if (gen != rsb_invalidate_gen) {
                rsb_invalidate_gen = gen;
                jit_state.ResetRSB();
            }
            jit_state.invalidate_gen_ptr = &shared->invalidate_gen;
            jit_state.rsb_gen = rsb_invalidate_gen;
        }

        is_executing = true;
        ++run_depth;
        Impl* const outer_running = t_running;
        t_running = this;
        SCOPE_EXIT {
            t_running = outer_running;
            if (--this->run_depth == 0) {
                this->is_executing = false;
            }
        };

        // TODO: Check code alignment

        const CodePtr current_code_ptr = [this] {
            // RSB optimization
            const u32 new_rsb_ptr = (jit_state.rsb_ptr - 1) & A64JitState::RSBPtrMask;
            if (jit_state.GetUniqueHash() == jit_state.rsb_location_descriptors[new_rsb_ptr]) {
                jit_state.rsb_ptr = new_rsb_ptr;
                return reinterpret_cast<CodePtr>(jit_state.rsb_codeptrs[new_rsb_ptr]);
            }

            return GetCurrentBlock();
        }();

        const HaltReason hr = block_of_code.RunCode(&jit_state, current_code_ptr);

        if (!nested) {
            PerformRequestedCacheInvalidation(hr);
        } else if (Has(hr, HaltReason::CacheInvalidation)) {
            Atomic::Or(&jit_state.halt_reason, static_cast<u32>(HaltReason::CacheInvalidation));
        }

        return hr;
    }

    HaltReason Step() {
        ASSERT(!is_executing);
        PerformRequestedCacheInvalidation(static_cast<HaltReason>(Atomic::Load(&jit_state.halt_reason)));

        is_executing = true;
        Impl* const outer_running = t_running;
        t_running = this;
        SCOPE_EXIT {
            t_running = outer_running;
            this->is_executing = false;
        };

        const HaltReason hr = block_of_code.StepCode(&jit_state, GetCurrentSingleStep());

        PerformRequestedCacheInvalidation(hr);

        return hr;
    }

    void ClearCache() {
        if (conf.shared_translations) {
            // Must use emitter.ClearCache() (O(map size) clear of descriptors/FD/block_ranges), not a
            // full-range InvalidateCacheRanges. Invalidate leaves block_ranges populated (dynarmic TODO)
            // and walks every block under the shared mutex — after minutes of SpringBoard that stalls
            // every thread for seconds and surfaces as BKS/XPC assert failures.
            std::unique_lock lock{shared->mutex()};
            ++shared->invalidate_gen;
            emitter.ClearCache();
            return;
        }
        std::unique_lock lock{invalidation_mutex};
        invalidate_entire_cache = true;
        HaltExecution(HaltReason::CacheInvalidation);
    }

    void InvalidateCacheRange(u64 start_address, size_t length) {
        const auto end_address = static_cast<u64>(start_address + length - 1);
        const auto range = boost::icl::discrete_interval<u64>::closed(start_address, end_address);
        if (conf.shared_translations) {
            std::unique_lock lock{shared->mutex()};
            // x86code: bump the generation (every thread drops its whole RSB on its next return) only when a block was
            // actually unlinked. JavaScriptCore calls sys_icache_invalidate for every code write and patch (thousands
            // per page load), mostly on freshly written code that was never translated: no RSB entry can point there.
            // Bumped after the unlink, still under the lock, so a thread seeing the new gen also sees the unlinked blocks.
            if (emitter.InvalidateCacheRanges(boost::icl::interval_set<u64>{range})) {
                ++shared->invalidate_gen;
            }
            return;
        }
        std::unique_lock lock{invalidation_mutex};
        invalid_cache_ranges.add(range);
        HaltExecution(HaltReason::CacheInvalidation);
    }

    void Reset() {
        ASSERT(!is_executing);
        A64JitState fresh{};
        fresh.tpidr_el0_ptr = jit_state.tpidr_el0_ptr;
        fresh.tpidrro_el0_ptr = jit_state.tpidrro_el0_ptr;
        fresh.excl_address_ptr = jit_state.excl_address_ptr;
        fresh.excl_value_ptr = jit_state.excl_value_ptr;
        fresh.excl_lock_ptr = jit_state.excl_lock_ptr;
        fresh.excl_addresses_base = jit_state.excl_addresses_base;
        jit_state = fresh;  // own_excl_* live in jit_state itself, so excl_*_ptr stay valid
    }

    void HaltExecution(HaltReason hr) {
        Atomic::Or(&jit_state.halt_reason, static_cast<u32>(hr));
    }

    void ClearHalt(HaltReason hr) {
        Atomic::And(&jit_state.halt_reason, ~static_cast<u32>(hr));
    }

    u64 GetSP() const {
        return jit_state.sp;
    }

    void SetSP(u64 value) {
        jit_state.sp = value;
    }

    u64 GetPC() const {
        return jit_state.pc;
    }

    void SetPC(u64 value) {
        jit_state.pc = value;
    }

    Jit::StatePointers GetStatePointers() {
        return {jit_state.reg.data(), &jit_state.sp, &jit_state.pc, jit_state.vec.data()};
    }

    u64 GetRegister(size_t index) const {
        if (index == 31)
            return GetSP();
        return jit_state.reg.at(index);
    }

    void SetRegister(size_t index, u64 value) {
        if (index == 31)
            return SetSP(value);
        jit_state.reg.at(index) = value;
    }

    std::array<u64, 31> GetRegisters() const {
        return jit_state.reg;
    }

    void SetRegisters(const std::array<u64, 31>& value) {
        jit_state.reg = value;
    }

    Vector GetVector(size_t index) const {
        return {jit_state.vec.at(index * 2), jit_state.vec.at(index * 2 + 1)};
    }

    void SetVector(size_t index, Vector value) {
        jit_state.vec.at(index * 2) = value[0];
        jit_state.vec.at(index * 2 + 1) = value[1];
    }

    std::array<Vector, 32> GetVectors() const {
        std::array<Vector, 32> ret;
        static_assert(sizeof(ret) == sizeof(jit_state.vec));
        std::memcpy(ret.data(), jit_state.vec.data(), sizeof(jit_state.vec));
        return ret;
    }

    void SetVectors(const std::array<Vector, 32>& value) {
        static_assert(sizeof(value) == sizeof(jit_state.vec));
        std::memcpy(jit_state.vec.data(), value.data(), sizeof(jit_state.vec));
    }

    u32 GetFpcr() const {
        return jit_state.GetFpcr();
    }

    void SetFpcr(u32 value) {
        jit_state.SetFpcr(value);
    }

    u32 GetFpsr() const {
        return jit_state.GetFpsr();
    }

    void SetFpsr(u32 value) {
        jit_state.SetFpsr(value);
    }

    u32 GetPstate() const {
        return jit_state.GetPstate();
    }

    void SetPstate(u32 value) {
        jit_state.SetPstate(value);
    }

    void ClearExclusiveState() {
        jit_state.exclusive_state = 0;
    }

    bool IsExecuting() const {
        return is_executing;
    }

    void DumpDisassembly() const {
        const size_t size = reinterpret_cast<const char*>(block_of_code.getCurr()) - reinterpret_cast<const char*>(block_of_code.GetCodeBegin());
        Common::DumpDisassembledX64(block_of_code.GetCodeBegin(), size);
    }

    std::vector<std::string> Disassemble() const {
        const size_t size = reinterpret_cast<const char*>(block_of_code.getCurr()) - reinterpret_cast<const char*>(block_of_code.GetCodeBegin());
        return Common::DisassembleX64(block_of_code.GetCodeBegin(), size);
    }

    // Perf 1: initial-exec (no __tls_get_addr per LookupBlockThunk; 8 bytes of glibc's static TLS surplus)
    static thread_local Impl* t_running __attribute__((tls_model("initial-exec")));
    CodePtr GetCurrentBlock() {
        return GetBlock(GetCurrentLocation());
    }

private:

    IR::LocationDescriptor GetCurrentLocation() const {
        return IR::LocationDescriptor{jit_state.GetUniqueHash()};
    }

    CodePtr GetCurrentSingleStep() {
        return GetBlock(A64::LocationDescriptor{GetCurrentLocation()}.SetSingleStepping(true));
    }

    CodePtr GetBlock(IR::LocationDescriptor current_location) {
        // Shared mode: hold the mutex only for map lookup and Emit. IR Translate/opts run unlocked so
        // other threads can still LookupBlock/Emit. A concurrent Invalidate bumps invalidate_gen; if it
        // changed while we translated, discard the IR and retry (the map may already have a fresh block).
        std::unique_lock lock{shared->mutex(), std::defer_lock};
        // x86Code Speed 8: FastDispatch first (re-entry from the run loop after native calls: ~15% of Preferences went
        // to the lf_map path), then the lock-free map, then the locked path. Entries are only ever written with the
        // shared mutex held, which every invalidation also holds: a thread that invalidated code it just wrote can
        // never find the old block here afterwards (Speed 7's lock-free fill could put one back: iconservicesagent and
        // Preferences crashes). After a lock-free hit the entry is filled only if the mutex is free (try_lock), from
        // a lookup under it.
        const bool fd = conf.shared_translations && fd_fill;
        const bool count = PerfCounters() && shared;
        if (count) {
            Count(shared->stats.getblock);
        }
        // Perf 1: per-thread L0 first (see L0Entry)
        L0Entry* l0e = nullptr;
        if (fd && l0_on && !fd_verify) {
            const u64 gen = shared->invalidate_gen;
            if (gen != l0_gen) {
                l0.fill(L0Entry{~0ull, nullptr});
                l0_gen = gen;
            }
            l0e = &L0Slot(current_location.Value());
            if (l0e->desc == current_location.Value()) {
                if (count) {
                    Count(shared->stats.l0_hits);
                }
                return l0e->ep;
            }
        }
        if (fd) {
            if (const CodePtr ep = emitter.FastDispatchProbe(current_location.Value())) {
                if (!fd_verify) {
                    if (count) {
                        Count(shared->stats.probe_hits);
                    }
                    if (l0e) {
                        *l0e = L0Entry{current_location.Value(), ep};
                    }
                    return ep;
                }
                // X86CODE_A64_GETBLOCK_FD_VERIFY=1 (debug): check every probe hit against the map under the mutex.
                lock.lock();
                const auto block = emitter.GetBasicBlock(current_location);
                const CodePtr want = block ? block->entrypoint : nullptr;
                if (want != ep) {
                    std::fprintf(stderr, "a64 getblock-fd: MISMATCH desc %#llx probe %p (owner %#llx) map %p (owner %#llx) gen %llu\n",
                                 (unsigned long long)current_location.Value(), (const void*)ep, (unsigned long long)emitter.OwnerOf(ep),
                                 (const void*)want, (unsigned long long)(want ? emitter.OwnerOf(want) : 0),
                                 (unsigned long long)shared->invalidate_gen);
                    const u32 end = fill_ring_pos.load();
                    int shown = 0;
                    for (u32 k = 0; k < kFillRing && shown < 4; k++) {
                        const FillRec& f = fill_ring[(end - 1 - k) % kFillRing];
                        if (f.desc == current_location.Value() || f.code == ep) {
                            std::fprintf(stderr, "a64 getblock-fd:   fill#%u desc %#llx code %p path %u gen %u tid %d\n", end - 1 - k,
                                         (unsigned long long)f.desc, f.code, f.path, f.gen, f.tid);
                            shown++;
                        }
                    }
                }
                if (want) {
                    return want;
                }
                lock.unlock();
            }
        }
        if (conf.shared_translations) {
            if (const CodePtr ep = emitter.LookupEntrypoint(current_location)) {
                if (fd && lock.try_lock()) {
                    if (const CodePtr now = emitter.LookupEntrypoint(current_location)) {
                        emitter.FastDispatchFill(current_location.Value(), now);
                        RecordFill(current_location.Value(), now, 1);
                    }
                }
                if (count) {
                    Count(shared->stats.lf_hits);
                }
                if (l0e) {
                    *l0e = L0Entry{current_location.Value(), ep};
                }
                return ep;
            }
        }
        for (;;) {
            if (conf.shared_translations) {
                lock.lock();
            }
            shared->stats.lookups++;
            if (auto block = emitter.GetBasicBlock(current_location)) {
                if (fd) {
                    emitter.FastDispatchFill(current_location.Value(), block->entrypoint);
                    RecordFill(current_location.Value(), block->entrypoint, 2);
                }
                if (l0e) {
                    *l0e = L0Entry{current_location.Value(), block->entrypoint};
                }
                return block->entrypoint;
            }
            const u64 gen_at_miss = conf.shared_translations ? shared->invalidate_gen : 0;
            if (conf.shared_translations) {
                lock.unlock();
            }

            timespec t0;
            clock_gettime(CLOCK_MONOTONIC, &t0);

            // JIT Compile (unlocked when shared): MemoryReadCode must not need the shared mutex.
            const auto get_code = [this](u64 vaddr) { return conf.callbacks->MemoryReadCode(vaddr); };
            // x86Code: hand-written objc_msgSend probe (no IR translate / no CallSVC).
            if (conf.inline_objc_msgsend != 0) {
                const A64::LocationDescriptor want{current_location};
                if (want.PC() == conf.inline_objc_msgsend && !want.SingleStepping()) {
                    if (conf.shared_translations) {
                        lock.lock();
                        if (auto block = emitter.GetBasicBlock(current_location))
                            return block->entrypoint;
                        if (shared->invalidate_gen != gen_at_miss) {
                            lock.unlock();
                            continue;
                        }
                    }
                    const auto descriptor = emitter.EmitInlineObjCMsgSend(current_location);
                    if (conf.shared_translations) {
                        shared->stats.blocks++;
                        shared->stats.guest_instructions += 8;
                        shared->stats.code_bytes += descriptor.size;
                    }
                    return descriptor.entrypoint;
                }
            }
            A64::TranslationOptions topts;
            topts.define_unpredictable_behaviour = conf.define_unpredictable_behaviour;
            topts.wall_clock_cntpct = conf.wall_clock_cntpct;
            topts.memory_read_code = get_code;
            topts.fuse_svc_ret = conf.fuse_svc_ret;
            IR::Block ir_block = A64::Translate(A64::LocationDescriptor{current_location}, get_code, topts);
            Optimization::PolyfillPass(ir_block, polyfill_options);
            Optimization::A64CallbackConfigPass(ir_block, conf);
            Optimization::NamingPass(ir_block);
            if (conf.HasOptimization(OptimizationFlag::GetSetElimination) && !conf.check_halt_on_memory_access) {
                Optimization::A64GetSetElimination(ir_block);
                Optimization::DeadCodeElimination(ir_block);
            }
            if (conf.HasOptimization(OptimizationFlag::ConstProp)) {
                Optimization::ConstantPropagation(ir_block);
                Optimization::DeadCodeElimination(ir_block);
            }
            if (conf.HasOptimization(OptimizationFlag::MiscIROpt)) {
                Optimization::A64MergeInterpretBlocksPass(ir_block, conf.callbacks);
            }
            if (conf.link_import_stubs && conf.HasOptimization(OptimizationFlag::ConstProp)) {
                Optimization::A64StubLinkPass(ir_block, conf.callbacks);
            }
            Optimization::IdentityRemovalPass(ir_block);
            Optimization::VerificationPass(ir_block);
            const size_t guest_instructions = ir_block.CycleCount();

            if (conf.shared_translations) {
                lock.lock();
                if (shared->invalidate_gen != gen_at_miss) {
                    // Memory may have changed; another thread may already have a valid block.
                    lock.unlock();
                    continue;
                }
                if (auto block = emitter.GetBasicBlock(current_location))
                    return block->entrypoint;
            }

            constexpr size_t MINIMUM_REMAINING_CODESIZE = 1 * 1024 * 1024;
            if (block_of_code.SpaceRemaining() < MINIMUM_REMAINING_CODESIZE) {
                // Shared code is never freed: other threads may be inside it (or return into it from native calls).
                ASSERT_MSG(!conf.shared_translations, "dynarmic: shared code cache full ({} bytes)", conf.code_cache_size);
                // Immediately evacuate cache
                invalidate_entire_cache = true;
                PerformRequestedCacheInvalidation(HaltReason::CacheInvalidation);
            }
            block_of_code.EnsureMemoryCommitted(MINIMUM_REMAINING_CODESIZE);

            const auto start_code = block_of_code.getCurr<const u8*>();
            // Emit may re-enter GetBlock via LookupBlock (block linking); recursive_mutex allows that.
            const CodePtr entrypoint = emitter.Emit(ir_block).entrypoint;
            timespec t1;
            clock_gettime(CLOCK_MONOTONIC, &t1);
            shared->stats.blocks++;
            shared->stats.guest_instructions += guest_instructions;
            shared->stats.code_bytes += block_of_code.getCurr<const u8*>() - start_code;
            shared->stats.translate_ns += (t1.tv_sec - t0.tv_sec) * 1000000000ull + t1.tv_nsec - t0.tv_nsec;
            LiveBin(A64::LocationDescriptor{current_location}.PC(), guest_instructions, block_of_code.getCurr<const u8*>() - start_code);
            return entrypoint;
        }
    }

    void PerformRequestedCacheInvalidation(HaltReason hr) {
        if (Has(hr, HaltReason::CacheInvalidation)) {
            std::unique_lock lock{invalidation_mutex};

            ClearHalt(HaltReason::CacheInvalidation);

            if (!invalidate_entire_cache && invalid_cache_ranges.empty()) {
                return;
            }

            jit_state.ResetRSB();
            if (invalidate_entire_cache) {
                block_of_code.ClearCache();
                emitter.ClearCache();
            } else {
                emitter.InvalidateCacheRanges(invalid_cache_ranges);
            }
            invalid_cache_ranges.clear();
            invalidate_entire_cache = false;
        }
    }

    bool is_executing = false;
    size_t run_depth = 0;
    u64 rsb_invalidate_gen = 0;  // last shared->invalidate_gen we ResetRSB'd for

    // x86Code Perf 1: a small direct-mapped cache in front of FastDispatchProbe, one per Jit (= per guest thread, so
    // no locking). GetBlock runs on every re-entry from the run loop (each native call returns through it) and on the
    // emitted dispatcher's misses; the shared FastDispatch table is megabytes of hashed slots, so ~half of the probe's
    // time was the load of a cold slot (11% of a cold Settings launch in the probe alone). The return sites of native
    // calls repeat, so a few KB per thread holds them. Tagged with shared->invalidate_gen (the RSB's lock-free check):
    // every invalidation bumps it, so the cache is dropped before any lookup after one, as the probe's own guarantee
    // (a thread that invalidated code never finds the old block afterwards). X86CODE_A64_GETBLOCK_L0=0 turns it off.
    struct L0Entry {
        u64 desc;
        CodePtr ep;
    };
    static constexpr size_t kL0 = 256;
    std::array<L0Entry, kL0> l0{};
    u64 l0_gen = ~0ull;
    const bool l0_on = !(std::getenv("X86CODE_A64_GETBLOCK_L0") && std::atoi(std::getenv("X86CODE_A64_GETBLOCK_L0")) == 0);
    L0Entry& L0Slot(u64 desc) { return l0[((desc >> 2) ^ (desc >> 11)) & (kL0 - 1)]; }

public:
    // Perf 1: GetBlock path counters in SharedStats, only with X86CODE_A64_PROFILE (relaxed atomic adds)
    static bool PerfCounters() {
        static const bool on = std::getenv("X86CODE_A64_PROFILE") != nullptr;
        return on;
    }
    static void Count(u64& c) { __atomic_fetch_add(&c, 1, __ATOMIC_RELAXED); }
    u64 CurrentPC() const { return jit_state.pc; }
    Jit::SharedStats& SharedStatsRef() {
        static Jit::SharedStats unshared;
        return shared ? shared->stats : unshared;
    }

private:

    std::shared_ptr<SharedCode> shared;
    const UserConfig& conf;
    A64JitState jit_state;
    BlockOfCode& block_of_code;
    A64EmitX64& emitter;
    const Optimization::PolyfillOptions& polyfill_options;
    // x86Code Speed 8: GetBlock probes/fills FastDispatch (default on since Speed 9; X86CODE_A64_GETBLOCK_FD=0 off). Declared after
    // conf (it reads it).
    const bool fd_fill = conf.HasOptimization(OptimizationFlag::FastDispatch) && A64EmitX64::GetBlockFillsFastDispatch();
    const bool fd_verify = std::getenv("X86CODE_A64_GETBLOCK_FD_VERIFY") != nullptr;
    struct FillRec {
        u64 desc;
        const void* code;
        u32 path, gen;
        int tid;
    };
    static constexpr u32 kFillRing = 1u << 16;
    static inline FillRec fill_ring[kFillRing];
    static inline std::atomic<u32> fill_ring_pos{0};
    void RecordFill(u64 desc, CodePtr code, u32 path) {
        if (!fd_verify) {
            return;
        }
        fill_ring[fill_ring_pos.fetch_add(1) % kFillRing] = {desc, code, path, static_cast<u32>(shared->invalidate_gen), static_cast<int>(gettid())};
    }

    bool invalidate_entire_cache = false;
    boost::icl::interval_set<u64> invalid_cache_ranges;
    std::mutex invalidation_mutex;
};

thread_local Jit::Impl* Jit::Impl::t_running __attribute__((tls_model("initial-exec"))) = nullptr;

// Perf 1 (X86CODE_A64_PROFILE): which guest PCs reach the dispatcher's C++ lookup, approximately (racy counts in a
// fixed open-addressed table; a full table stops recording new PCs)
namespace {
constexpr size_t kThunkTop = 8192;
struct ThunkPc {
    u64 pc;
    u64 n;
};
ThunkPc g_thunk_top[kThunkTop];
ThunkPc g_thunk_ra[kThunkTop];  // by the emitted call site (return address of the LookupBlock call)
void RecordThunkPc(u64 pc, ThunkPc* tab = g_thunk_top) {
    for (size_t i = (pc >> 2) * 0x9E3779B97F4A7C15ull >> 51, k = 0; k < 16; k++, i = (i + 1) & (kThunkTop - 1)) {
        u64 cur = __atomic_load_n(&tab[i].pc, __ATOMIC_RELAXED);
        if (cur == 0 && __atomic_compare_exchange_n(&tab[i].pc, &cur, pc, false, __ATOMIC_RELAXED, __ATOMIC_RELAXED)) {
            cur = pc;
        }
        if (cur == pc) {
            __atomic_fetch_add(&tab[i].n, 1, __ATOMIC_RELAXED);
            return;
        }
    }
}
}  // namespace

std::vector<std::pair<std::uint64_t, std::uint64_t>> Jit::TopThunkTargets(std::size_t n, bool callers) {
    std::vector<std::pair<std::uint64_t, std::uint64_t>> v;
    for (const auto& e : (callers ? g_thunk_ra : g_thunk_top)) {
        if (e.pc) {
            v.push_back({e.n, e.pc});
        }
    }
    std::sort(v.rbegin(), v.rend());
    if (v.size() > n) {
        v.resize(n);
    }
    return v;
}

CodePtr Jit::SharedCode::LookupBlockThunk(void*) {
    if (Jit::Impl::PerfCounters()) {
        Jit::Impl::Count(Jit::Impl::t_running->SharedStatsRef().thunk);
        RecordThunkPc(Jit::Impl::t_running->CurrentPC());
        RecordThunkPc(reinterpret_cast<u64>(__builtin_return_address(0)), g_thunk_ra);
    }
    return Jit::Impl::t_running->GetCurrentBlock();
}

Jit::Jit(UserConfig conf)
        : impl(std::make_unique<Jit::Impl>(this, conf, nullptr)) {}

Jit::Jit(UserConfig conf, std::shared_ptr<SharedCode> shared)
        : impl(std::make_unique<Jit::Impl>(this, conf, std::move(shared))) {}

Jit::~Jit() = default;

void Jit::Pretranslate(std::uint64_t location_descriptor) {
    impl->Pretranslate(location_descriptor);
}

bool Jit::PretranslateCollect(std::uint64_t location_descriptor, std::vector<std::uint64_t>& successors) {
    return impl->PretranslateCollect(location_descriptor, successors);
}

void Jit::BeginChunk(SharedCode& shared, std::uint64_t code_off) {
    shared.emitter.BeginChunk(code_off);
}

std::uint64_t Jit::ChunkCodeEnd(SharedCode& shared) {
    std::unique_lock lock{shared.mutex()};
    return static_cast<std::uint64_t>(shared.block_of_code.getCurr<const std::uint8_t*>() -
                                      static_cast<const std::uint8_t*>(shared.block_of_code.GetCodeBegin()));
}

std::uint64_t Jit::CodeCapacity(SharedCode& shared) {
    std::unique_lock lock{shared.mutex()};
    return static_cast<std::uint64_t>(shared.block_of_code.getCurr<const std::uint8_t*>() -
                                      static_cast<const std::uint8_t*>(shared.block_of_code.GetCodeBegin())) +
           shared.block_of_code.SpaceRemaining();
}

void Jit::DiscardCode(SharedCode& shared, std::uint64_t from_off, std::uint64_t to_off) {
    std::unique_lock lock{shared.mutex()};
    auto* b = static_cast<std::uint8_t*>(const_cast<void*>(shared.block_of_code.GetCodeBegin()));
    const std::uint64_t lo = (reinterpret_cast<std::uint64_t>(b + from_off) + 4095) & ~4095ull;
    const std::uint64_t hi = reinterpret_cast<std::uint64_t>(b + to_off) & ~4095ull;
    if (hi > lo) {
        madvise(reinterpret_cast<void*>(lo), hi - lo, MADV_DONTNEED);
    }
}

std::size_t Jit::SaveChunk(SharedCode& shared, const std::string& path, const std::uint8_t cache_uuid[16], std::uint64_t build_id,
                           std::uint64_t cache_lo, std::uint64_t cache_hi, std::uint64_t code_off) {
    return shared.emitter.SaveChunk(path, cache_uuid, build_id, cache_lo, cache_hi, code_off);
}

void Jit::SetConstantPoolRegion(SharedCode& shared, const std::vector<std::uint8_t>& pool, std::size_t region_off) {
    shared.emitter.SetConstantPoolRegion(pool, region_off);
}

std::size_t Jit::ConstantPoolUsed(SharedCode& shared) {
    std::unique_lock lock{shared.mutex()};
    return shared.block_of_code.GetConstantPoolUsedBytes();
}

std::vector<std::uint8_t> Jit::ReadPersistentPool(const std::string& path) {
    return A64EmitX64::ReadPersistentPool(path);
}

std::vector<std::uint64_t> Jit::ReadPersistentDescriptors(const std::string& path, const std::uint8_t cache_uuid[16],
                                                          std::uint64_t build_id) {
    return A64EmitX64::ReadPersistentDescriptors(path, cache_uuid, build_id);
}

HaltReason Jit::Run() {
    return impl->Run();
}

HaltReason Jit::Step() {
    return impl->Step();
}

void Jit::ClearCache() {
    impl->ClearCache();
}

void Jit::InvalidateCacheRange(u64 start_address, size_t length) {
    impl->InvalidateCacheRange(start_address, length);
}

void Jit::Reset() {
    impl->Reset();
}

void Jit::HaltExecution(HaltReason hr) {
    impl->HaltExecution(hr);
}

void Jit::ClearHalt(HaltReason hr) {
    impl->ClearHalt(hr);
}

u64 Jit::GetSP() const {
    return impl->GetSP();
}

void Jit::SetSP(u64 value) {
    impl->SetSP(value);
}

u64 Jit::GetPC() const {
    return impl->GetPC();
}

void Jit::SetPC(u64 value) {
    impl->SetPC(value);
}

Jit::StatePointers Jit::GetStatePointers() {
    return impl->GetStatePointers();
}

u64 Jit::GetRegister(size_t index) const {
    return impl->GetRegister(index);
}

void Jit::SetRegister(size_t index, u64 value) {
    impl->SetRegister(index, value);
}

std::array<u64, 31> Jit::GetRegisters() const {
    return impl->GetRegisters();
}

void Jit::SetRegisters(const std::array<u64, 31>& value) {
    impl->SetRegisters(value);
}

Vector Jit::GetVector(size_t index) const {
    return impl->GetVector(index);
}

void Jit::SetVector(size_t index, Vector value) {
    impl->SetVector(index, value);
}

std::array<Vector, 32> Jit::GetVectors() const {
    return impl->GetVectors();
}

void Jit::SetVectors(const std::array<Vector, 32>& value) {
    impl->SetVectors(value);
}

u32 Jit::GetFpcr() const {
    return impl->GetFpcr();
}

void Jit::SetFpcr(u32 value) {
    impl->SetFpcr(value);
}

u32 Jit::GetFpsr() const {
    return impl->GetFpsr();
}

void Jit::SetFpsr(u32 value) {
    impl->SetFpsr(value);
}

u32 Jit::GetPstate() const {
    return impl->GetPstate();
}

void Jit::SetPstate(u32 value) {
    impl->SetPstate(value);
}

void Jit::ClearExclusiveState() {
    impl->ClearExclusiveState();
}

bool Jit::IsExecuting() const {
    return impl->IsExecuting();
}

void Jit::DumpDisassembly() const {
    return impl->DumpDisassembly();
}

std::vector<std::string> Jit::Disassemble() const {
    return impl->Disassemble();
}

}  // namespace Dynarmic::A64
