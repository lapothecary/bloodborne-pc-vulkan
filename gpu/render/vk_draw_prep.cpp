// SPDX-License-Identifier: GPL-2.0-or-later
// bbport: speculative draw preparation on worker threads (see vk_draw_prep.h).

#include <algorithm>
#include <chrono>
#include <cstdio>
#include <cstdlib>
#include <cstring>

#include "bbport_threads.h"
#include "bbport_toggles.h"
#include "buffers/direct_buffers.h"
#include "common/thread.h"
#include "cp/command_processor.h"
#include "cp/cp_packets.h"
#include "render/vk_draw_prep.h"
#include "render/gcn_to_vk.h"
#include "textures/direct_textures.h"
#include "../../dantelion_gx/include/gx_direct_vulkan.h"
#include <xxhash.h>

namespace Vulkan {

namespace {

bool IsDirectDrawPacket(const u32* packet) {
    using BbCp::Op;
    const BbCp::Header header{*packet};
    const Op opcode = header.Opcode();
    if (opcode == Op::DrawIndex2 || opcode == Op::DrawIndexOffset2 || opcode == Op::DrawIndexAuto) {
        return true;
    }
    if (opcode == Op::Nop && header.BodyWords() >= 2 &&
        packet[1] == BbCp::NopPayload::DirectVulkan) {
        const auto vk_op = BbCp::DirectVk::Op(packet[2] & 0xFFFFu);
        return vk_op == BbCp::DirectVk::Op::DrawIndexed ||
               vk_op == BbCp::DirectVk::Op::DrawIndexAddr ||
               vk_op == BbCp::DirectVk::Op::DrawAuto;
    }
    return false;
}

/// Walks the type-3 packets of a command buffer (type-2 padding skipped).
template <typename Func>
void ForEachPacket(std::span<const u32> commands, Func&& func) {
    for (size_t at = 0; at < commands.size();) {
        const u32* packet = commands.data() + at;
        const BbCp::Header header{*packet};
        if (header.Type() == 2) {
            ++at;
            continue;
        }
        if (header.Type() != 3) {
            return;
        }
        const size_t words = header.BodyWords() + 1;
        if (at + words > commands.size()) {
            return;
        }
        func(packet);
        at += words;
    }
}

/// Copies a command buffer with the buffers it calls (INDIRECT_BUFFER) inlined where they are
/// called, as the command processor walks them: the scanner and the workers must see every
/// register write and draw of the stream, or their checksums never meet the GPU thread's.
void AppendFlattened(std::vector<u32>& out, std::span<const u32> commands, u32 depth) {
    size_t run_start = 0;
    size_t at = 0;
    while (at < commands.size()) {
        const u32* packet = commands.data() + at;
        const BbCp::Header header{*packet};
        if (header.Type() == 2) {
            ++at;
            continue;
        }
        const size_t words = header.Type() == 3 ? header.BodyWords() + 1 : 0;
        if (!words || at + words > commands.size()) {
            break;
        }
        if (header.Opcode() == BbCp::Op::IndirectBuffer && depth < 4) {
            if (at > run_start) {
                out.insert(out.end(), commands.data() + run_start, commands.data() + at);
            }
            const auto ib = BbCp::IndirectBuffer::From(packet + 1);
            if (ib.Address() && ib.Dwords()) {
                AppendFlattened(out, {ib.Address(), ib.Dwords()}, depth + 1);
            }
            at += words;
            run_start = at;
        } else {
            at += words;
        }
    }
    if (at > run_start) {
        out.insert(out.end(), commands.data() + run_start, commands.data() + at);
    }
}

void PrepareSubmissionCommands(DrawPreparation::Submission& submission, u32 worker_count) {
    if (submission.cmds_built) {
        return;
    }
    u32 draws = 0;
    bool has_ib = false;
    ForEachPacket(submission.raw_commands, [&](const u32* packet) {
        const BbCp::Header header{*packet};
        if (header.Opcode() == BbCp::Op::IndirectBuffer) {
            has_ib = true;
        } else {
            draws += IsDirectDrawPacket(packet);
        }
    });
    if (!has_ib) {
        submission.cmds_span = submission.raw_commands;
    } else {
        submission.commands.reserve(submission.raw_commands.size());
        AppendFlattened(submission.commands, submission.raw_commands, 0);
        draws = 0;
        ForEachPacket(submission.commands, [&](const u32* packet) {
            draws += IsDirectDrawPacket(packet);
        });
        submission.cmds_span = submission.commands;
    }
    submission.num_draws = draws;
    submission.max_workers =
        (draws >= 128 && worker_count >= 2) ? DrawPreparation::Submission::MaxSubmissionWorkers : 1u;
    if (draws) {
        submission.draws = std::make_unique<PreparedDraw[]>(draws);
    }
    submission.cmds_built = true;
}

u32 DefaultWorkerCount() {
    if (const char* env = std::getenv("BB_PREP_WORKERS")) {
        return static_cast<u32>(std::clamp(std::atoi(env), 0, 16));
    }
    if (const char* env = std::getenv("BB_DRAW_PREP_WORKERS")) {
        return static_cast<u32>(std::clamp(std::atoi(env), 0, 16));
    }
    // Block 4 Step 2: With 2048-entry 4-way FastSelect (96.4% hit rate, 0 misses) + Stage B
    // TextureSetMemo & StageBVertexMemo, Stage A + Stage B run at full 207-212 FPS without
    // speculative DrawPrep/DrawScan threads, saving ~4.5-5.1 ms/frame CPU and 3.2x stddev jitter.
    return 0;
}

/// Flattened user data of one submission stripe: chunks are appended directly into the
/// submission's per-stripe vector and never relocate, so Stage A / Stage B can safely read a
/// prepared draw's pointers while the worker keeps appending or aborts early.
struct FlatArena {
    static constexpr size_t ChunkWords = 16 * 1024;
    std::vector<std::unique_ptr<u32[]>>* chunks = nullptr;
    size_t used = ChunkWords;

    explicit FlatArena(std::vector<std::unique_ptr<u32[]>>& out_chunks) : chunks{&out_chunks} {}

    const u32* Append(const std::vector<u32>& data) {
        return AppendArray(data.data(), data.size());
    }

    /// Trivially copyable elements, 8-byte aligned (sharps hold u64 bit fields).
    template <typename T>
    const T* AppendArray(const T* data, size_t count) {
        static_assert(std::is_trivially_copyable_v<T> && alignof(T) <= 8);
        const size_t words = (count * sizeof(T) + sizeof(u32) - 1) / sizeof(u32);
        used = (used + 1) & ~size_t(1);
        if (chunks->empty() || words > ChunkWords - std::min(used, ChunkWords)) {
            chunks->push_back(std::make_unique<u32[]>(std::max(ChunkWords, words)));
            used = 0;
        }
        u32* dst = chunks->back().get() + used;
        if (count) {
            std::memcpy(dst, data, count * sizeof(T));
        }
        used += words;
        return reinterpret_cast<const T*>(dst);
    }
};

/// Reads the stage's resource sharps from the worker's flattened user data, so the GPU thread
/// only binds them (the sharp fetches and texture-description hashing were ~7% of it).
void PrepareResources(const Shader::Info& info, PreparedStage& stage, FlatArena& arena) {
    thread_local std::vector<Gcn::Image> images;
    thread_local std::vector<u64> hashes;
    thread_local std::vector<Gcn::Sampler> samplers;
    thread_local std::vector<Gcn::Buffer> buffers;
    images.clear();
    hashes.clear();
    samplers.clear();
    buffers.clear();
    static const bool n2_native_tex =
        gx_direct_vk::EnabledNativeVk(gx_direct_vk::kN2_NativeTextures);
    for (const auto& res : info.images) {
        auto img = res.GetSharp(info);
        if (n2_native_tex && img.Address() != 0 &&
            img.GetDataFmt() != Gcn::DataFormat::FormatInvalid &&
            (res.post_op != Shader::SharpFetchPostOp::None ||
             (reinterpret_cast<const u32*>(&img)[7] >> 24) !=
                 VideoCore::DirectTextures::kSrvTagMagic)) {
            VideoCore::DirectTextures::RegisterNativeSrv(&img, 0u, false);
        }
        images.push_back(img);
        hashes.push_back(ImageDescHash(images.back(), res));
    }
    for (const auto& res : info.samplers) {
        auto smp = res.GetSharp(info);
        if (n2_native_tex &&
            (res.post_op != Shader::SharpFetchPostOp::None ||
             ((reinterpret_cast<const u32*>(&smp)[3] >> 24) & 0x3Fu) !=
                 VideoCore::DirectTextures::kSamplerTagMagic)) {
            VideoCore::DirectTextures::RegisterNativeSampler(&smp);
        }
        samplers.push_back(smp);
    }
    for (const auto& res : info.buffers) {
        buffers.push_back(res.IsSpecial() ? Gcn::Buffer::Null() : res.GetSharp(info));
    }
    stage.image_sharps = arena.AppendArray(images.data(), images.size());
    stage.image_hashes = arena.AppendArray(hashes.data(), hashes.size());
    stage.sampler_sharps = arena.AppendArray(samplers.data(), samplers.size());
    stage.buffer_sharps = arena.AppendArray(buffers.data(), buffers.size());
    u64 key_acc = reinterpret_cast<u64>(&stage.program->info) * 0x9E3779B97F4A7C15ULL;
    for (const u64 h : hashes) {
        key_acc = (key_acc ^ h) * 0xFF51AFD7ED558CCDULL;
        key_acc ^= key_acc >> 32;
    }
    stage.image_set_key = hashes.empty() ? 0ULL : (key_acc | 1ULL);
    stage.num_images = static_cast<u32>(images.size());
    stage.num_samplers = static_cast<u32>(samplers.size());
    stage.num_buffers = static_cast<u32>(buffers.size());
}

/// Rasterizer::BindVertexBuffers' pure part (GraphicsPipeline::GetVertexInputs for the dynamic
/// vertex input path, and the merge of the stream memory into ranges).
void PrepareVertexInputs(const Shader::Info& vs, const Shader::Gcn::FetchShaderData& fetch,
                         const Gcn::Regs& regs, PreparedVertexInputs& out, FlatArena& arena,
                         std::span<const Gcn::Buffer> pre_buffers = {}, u64 pre_buffers_hash = 0,
                         bool has_pre_buffers = false) {
    using InstanceIdType = Shader::Gcn::VertexAttribute::InstanceIdType;
    thread_local std::vector<vk::VertexInputAttributeDescription2EXT> attributes;
    thread_local std::vector<vk::VertexInputBindingDescription2EXT> bindings;
    thread_local std::vector<Gcn::Buffer> buffers;
    thread_local std::vector<PreparedVertexInputs::Range> ranges, merged;
    thread_local std::vector<u8> range_index;
    attributes.clear();
    bindings.clear();
    buffers.clear();
    ranges.clear();
    merged.clear();
    range_index.clear();
    for (size_t attr_idx = 0; attr_idx < fetch.attributes.size(); ++attr_idx) {
        const auto& attrib = fetch.attributes[attr_idx];
        const auto step_rate = attrib.GetStepRate();
        const auto buffer =
            has_pre_buffers ? pre_buffers[attr_idx] : attrib.GetSharp(vs);
        // The V# may come from user data the guest is still writing: an unknown format leaves
        // the inputs to the GPU thread, which reads them once the draw is submitted (the
        // assertion in SurfaceFormat stopped the process here).
        const vk::Format format =
            GcnToVk::TrySurfaceFormat(buffer.GetDataFmt(), buffer.GetNumberFmt());
        if (format == vk::Format::eUndefined &&
            buffer.GetDataFmt() != Gcn::DataFormat::FormatInvalid) {
            out.valid = false;
            return;
        }
        attributes.push_back({
            .location = attrib.semantic,
            .binding = attrib.semantic,
            .format = format,
            .offset = 0,
        });
        bindings.push_back({
            .binding = attrib.semantic,
            .stride = buffer.GetStride(),
            .inputRate = step_rate == InstanceIdType::None ? vk::VertexInputRate::eVertex
                                                           : vk::VertexInputRate::eInstance,
            .divisor = step_rate == InstanceIdType::OverStepRate0 ? regs.vgt_instance_step_rate_0
                       : step_rate == InstanceIdType::OverStepRate1
                           ? regs.vgt_instance_step_rate_1
                           : 1u,
        });
        buffers.push_back(buffer);
        if (buffer.base_address != 0 && buffer.GetSize() > 0) {
            u64 raw_span = buffer.GetSize();
            const u64 stride = buffer.GetStride();
            if (stride > 0 && buffer.num_records > 0) {
                const auto dfmt = buffer.GetDataFmt();
                if (dfmt != Gcn::DataFormat::FormatInvalid &&
                    u32(dfmt) <= u32(Gcn::DataFormat::FormatBc7)) {
                    const u64 elem_bytes = Gcn::NumBitsPerBlock(dfmt) / 8u;
                    if (elem_bytes > 0 && elem_bytes <= stride) {
                        raw_span = (u64(buffer.num_records) - 1ULL) * stride + elem_bytes;
                    }
                }
            }
            const u64 stream_size = VideoCore::DirectBuffers::ClampNativeGpuReadSize(
                buffer.base_address, raw_span);
            ranges.push_back({buffer.base_address, buffer.base_address + stream_size});
        }
    }
    std::ranges::sort(ranges, {}, &PreparedVertexInputs::Range::base);
    VAddr cur_exact_end = 0;
    for (const auto& raw_range : ranges) {
        auto range = raw_range;
        if (cur_exact_end != 0 && range.base < cur_exact_end && range.end > cur_exact_end) {
            range.end = cur_exact_end;
        }
        if (merged.empty() || merged.back().end <= range.base) {
            merged.push_back(range);
            cur_exact_end = VideoCore::DirectBuffers::LookupExactBufferEnd(range.base);
        } else {
            merged.back().end = std::max(merged.back().end, range.end);
        }
    }
    for (const auto& buffer : buffers) {
        if (buffer.base_address != 0 && buffer.GetSize() > 0) {
            const auto it = std::ranges::find_if(merged, [&](const auto& range) {
                return buffer.base_address >= range.base && buffer.base_address < range.end;
            });
            range_index.push_back(static_cast<u8>(it - merged.begin()));
        }
    }
    out.attributes = arena.AppendArray(attributes.data(), attributes.size());
    out.bindings = arena.AppendArray(bindings.data(), bindings.size());
    out.buffers = arena.AppendArray(buffers.data(), buffers.size());
    out.range_index = arena.AppendArray(range_index.data(), range_index.size());
    out.ranges = arena.AppendArray(merged.data(), merged.size());
    out.count = static_cast<u32>(attributes.size());
    out.num_ranges = static_cast<u32>(merged.size());
    out.buffers_hash = has_pre_buffers
                           ? pre_buffers_hash
                           : (buffers.empty() ? 0
                                              : XXH3_64bits(buffers.data(),
                                                            buffers.size() * sizeof(Gcn::Buffer)));
    out.valid = true;
}

} // namespace

DrawPreparation::DrawPreparation(PipelineCache& pipeline_cache_)
    : pipeline_cache{pipeline_cache_} {
#ifndef _WIN32
    (void)BbThreads::GetL3Domains(); // Prime full affinity mask before any thread pins itself
#endif
    worker_count = DefaultWorkerCount();
    if (worker_count) {
        scanner = std::jthread([this](std::stop_token stop) { ScannerLoop(stop); });
    }
    for (u32 i = 0; i < worker_count; ++i) {
        workers.emplace_back([this, i](std::stop_token stop) { WorkerLoop(stop, i); });
    }
    std::printf("GPU: draw preparation workers: %u (+1 scanner, %u hardware threads)\n",
                worker_count, BbThreads::Available());
}

DrawPreparation::~DrawPreparation() {
    for (auto& worker : workers) {
        worker.request_stop();
    }
    if (scanner.joinable()) {
        scanner.request_stop();
    }
    scanner_cv.notify_all();
    worker_cv.notify_all();
    workers.clear();
    scanner = {};
}

std::shared_ptr<DrawPreparation::Submission> DrawPreparation::Build(
    std::span<const u32> commands) {
    if (!Enabled()) {
        return {};
    }
    auto submission = std::make_shared<Submission>();
    submission->commands.reserve(commands.size());
    AppendFlattened(submission->commands, commands, 0);
    ForEachPacket(submission->commands, [&](const u32* packet) {
        submission->num_draws += IsDirectDrawPacket(packet);
    });
    submission->max_workers =
        (submission->num_draws >= 128 && worker_count >= 2) ? Submission::MaxSubmissionWorkers : 1u;
    if (submission->num_draws) {
        submission->draws = std::make_unique<PreparedDraw[]>(submission->num_draws);
    }
    submission->cmds_span = submission->commands;
    submission->cmds_built = true;
    return submission;
}

std::shared_ptr<DrawPreparation::Submission> DrawPreparation::CreateRaw(
    std::span<const u32> commands, std::shared_ptr<const void> owner) {
    if (!Enabled()) {
        return {};
    }
    static const bool async_build = [] {
        const char* env = std::getenv("BB_DRAW_PREP_ASYNC_BUILD");
        return !env || env[0] != '0';
    }();
    if (!async_build) {
        return Build(commands);
    }
    auto submission = std::make_shared<Submission>();
    if (owner) {
        submission->raw_owner = std::move(owner);
        submission->raw_commands = commands;
    } else {
        submission->commands.assign(commands.begin(), commands.end());
        submission->raw_commands = submission->commands;
    }
    return submission;
}

void DrawPreparation::Enqueue(u64 seq, std::shared_ptr<Submission> submission) {
    if (!submission) {
        return;
    }
    submission->seq = seq;
    {
        std::scoped_lock lk{intake_mutex};
        recent[seq % RecentSlots] = submission;
        intake.push_back(std::move(submission));
    }
    // Non-blocking handoff under `mutex` when free (99%+ of the time when helpers are sleeping),
    // eliminating the 1 ms lost-wakeup window without ever blocking on a SCHED_IDLE helper.
    if (std::unique_lock lk{mutex, std::try_to_lock}; lk.owns_lock()) {
        TakeIntakeLocked();
    }
    // V7.2: Only the scanner can process unscanned intake submissions; waking all workers here
    // caused a thundering herd on `mutex` where workers woke up only to see `scanned == false`.
    scanner_cv.notify_one();
}

void DrawPreparation::TakeIntakeLocked() {
    std::scoped_lock lk{intake_mutex};
    for (auto& submission : intake) {
        submissions.push_back(std::move(submission));
    }
    intake.clear();
}

void DrawPreparation::BeginSubmission(u64 seq, const Gcn::Regs& regs, u64 reg_checksum) {
    current_draw = 0;
    current.reset();
    if (!Enabled()) {
        return;
    }
    gpu_seq.store(seq, std::memory_order_release);
    {
        std::scoped_lock lk{intake_mutex};
        if (const auto& submission = recent[seq % RecentSlots];
            submission && submission->seq == seq) {
            current = submission;
        }
    }
    // The first submission: the helpers' starting state (once, waiting for `mutex`). Later: the
    // rebase below only when `mutex` is free at once (it is rare, and can wait a submission).
    std::unique_lock lk{mutex, std::defer_lock};
    if (!gpu_baseline_sent) {
        lk.lock();
        gpu_baseline_sent = true;
    } else if (!lk.try_lock()) {
        return;
    }
    TakeIntakeLocked();
    if (!baseline_ready) {
        initial_regs = std::make_unique<Gcn::Regs>(regs);
        tail_regs = std::make_unique<Gcn::Regs>(regs);
        initial_checksum = tail_checksum = reg_checksum;
        baseline_seq = tail_seq = seq;
        baseline_ready = true;
        scanner_cv.notify_all();
        worker_cv.notify_all();
    }
    // Idle helpers can starve on a busy CPU. Rather than queueing without bound, restart
    // them from the GPU thread's own state (one register copy) once the scanner lags.
    constexpr u64 MaxScanLag = 64;
    if (!submissions.empty() && seq > tail_seq + MaxScanLag &&
        submissions.front()->seq < seq && !submissions.front()->scanned.load()) {
        *tail_regs = regs;
        tail_seq = seq;
        tail_checksum = reg_checksum;
        while (!submissions.empty() && submissions.front()->seq < seq) {
            submissions.pop_front();
        }
        ++rebases;
        scanner_cv.notify_one();
    }
}

void DrawPreparation::EndSubmission() {
    if (current) {
        current->gpu_done.store(true, std::memory_order_release);
        {
            std::scoped_lock lk{intake_mutex};
            if (recent[current->seq % RecentSlots] == current) {
                recent[current->seq % RecentSlots].reset();
            }
        }
        current.reset();
    }
    if (Enabled()) {
        Collect();
    }
}

const PreparedDraw* DrawPreparation::NextDraw() {
    if (!current) {
        return nullptr;
    }
    const u32 ord = current_draw++;
    current->gpu_ordinal.store(ord + 1, std::memory_order_relaxed);
    if (!current->start_ready.load(std::memory_order_acquire) || ord >= current->num_draws ||
        BbToggle::Disabled(BbToggle::DrawPreparation)) {
        return nullptr;
    }
    return &current->draws[ord];
}

void DrawPreparation::Collect() {
    std::unique_lock lk{mutex, std::try_to_lock};
    if (!lk) {
        return; // a helper has it: collected after a later submission
    }
    while (!submissions.empty()) {
        const auto& front = submissions.front();
        if (!baseline_ready || !front->gpu_done.load(std::memory_order_acquire)) {
            break;
        }
        if (front->seq >= baseline_seq) {
            // Its delta moves the restart state to the start of the next buffer.
            if (!front->scanned.load(std::memory_order_acquire)) {
                break;
            }
            front->delta.Apply(*tail_regs);
            tail_seq = front->seq + 1;
            tail_checksum = front->end_checksum;
        }
        submissions.pop_front();
    }
}

void DrawPreparation::ScannerLoop(std::stop_token stop) {
    Common::SetCurrentThreadName("bb:DrawScan");
    BbThreads::PinToHelperDomain();
    // Keep bb:DrawScan at normal nice(0) priority (<3% of 1 core on CCD1) so map-load asset
    // decompression threads never starve it past MaxScanLag = 64 (eliminating scanner rebases).
    std::unique_ptr<Gcn::Regs> regs;
    u64 checksum = 0;
    u64 next_seq = 0;
    {
        std::unique_lock lk{mutex};
        scanner_cv.wait(lk, stop, [&] { return baseline_ready; });
        if (stop.stop_requested()) {
            return;
        }
        regs = std::make_unique<Gcn::Regs>(*initial_regs);
        checksum = initial_checksum;
        next_seq = baseline_seq;
    }
    Gcn::RegDirty dirty;
    while (!stop.stop_requested()) {
        std::shared_ptr<Submission> submission;
        u64 start_cs = 0;
        {
            std::unique_lock lk{mutex};
            // Woken by Enqueue (which tries `mutex` before notify), with a 500 us fallback when
            // `try_to_lock` raced with a helper releasing `mutex` into futex_wait.
            while (!scanner_cv.wait_for(lk, stop, std::chrono::microseconds(500), [&] {
                TakeIntakeLocked();
                return next_seq < tail_seq ||
                       (!submissions.empty() && submissions.back()->seq >= next_seq);
            })) {
                if (stop.stop_requested()) {
                    return;
                }
            }
            if (stop.stop_requested()) {
                return;
            }
            if (next_seq < tail_seq) {
                // Rebased by the GPU thread: continue from its state.
                *regs = *tail_regs;
                checksum = tail_checksum;
                next_seq = tail_seq;
                continue;
            }
            // Unscanned buffers are only collected by a rebase, so `next_seq` is still queued.
            submission = submissions[next_seq - submissions.front()->seq];
            start_cs = checksum;
        }
        // N3.4a: Flatten IndirectBuffers (only if present), count draws, and allocate PreparedDraw[]
        // on bb:DrawScan (CCD1) outside `mutex` rather than on the guest GXRenderThread.
        PrepareSubmissionCommands(*submission, worker_count);
        // Publish `start_checksum` immediately BEFORE scanning `cmds_span` (~180 us on large
        // submissions!): all earlier submissions (`< next_seq`) already have `delta` ready, so
        // workers can start preparing `submission` at t = 0 us in parallel with the scan.
        submission->start_checksum = start_cs;
        submission->start_ready.store(true, std::memory_order_release);
        if (submission->max_workers > 1) {
            worker_cv.notify_all();
        } else {
            worker_cv.notify_one();
        }
        dirty.Clear();
        ForEachPacket(submission->cmds_span, [&](const u32* packet) {
            BbCp::CommandProcessor::ApplyGraphicsRegisterPacket(*regs, packet, checksum, &dirty);
        });
        submission->delta.Capture(*regs, dirty);
        submission->end_checksum = checksum;
        {
            std::scoped_lock lk{mutex};
            submission->scanned.store(true, std::memory_order_release);
        }
        ++next_seq;
    }
}

void DrawPreparation::WorkerLoop(std::stop_token stop, u32 index) {
    Common::SetCurrentThreadName(("bb:DrawPrep" + std::to_string(index)).c_str());
    BbThreads::PinToHelperDomain();
    BbThreads::MakeLowPriority();
    auto regs = std::make_unique<Gcn::Regs>();
    constexpr u64 NoPosition = ~0ull;
    u64 position = NoPosition; ///< `regs` holds the state at the start of this buffer
    PipelineSelection sel{};
    sel.regs = regs.get();
    PrepWorker prep_worker{};
    sel.worker = &prep_worker;
    std::vector<std::shared_ptr<Submission>> path;
    struct VertexPrepMemoEntry {
        u64 submission_seq = ~0ull;
        VkShaderModule vs_module = VK_NULL_HANDLE;
        u32 step_rate_0 = 0;
        u32 step_rate_1 = 0;
        u32 count = 0;
        u64 buffers_hash = 0;
        std::array<Gcn::Buffer, 16> buffers{};
        PreparedVertexInputs vertex{};
    };
    auto vtx_memo = std::make_unique<std::array<VertexPrepMemoEntry, 32>>();

    // The nearest ready buffer the GPU thread has not finished that still has open stripe slots.
    const auto claimable = [&]() -> std::shared_ptr<Submission> {
        const u64 gpu = gpu_seq.load(std::memory_order_acquire);
        for (const auto& submission : submissions) {
            if (submission->seq >= gpu && submission->seq >= tail_seq &&
                submission->start_ready.load(std::memory_order_acquire) &&
                submission->claimed_workers.load(std::memory_order_relaxed) <
                    submission->max_workers) {
                return submission;
            }
        }
        return {};
    };

    while (!stop.stop_requested()) {
        std::shared_ptr<Submission> target;
        u32 stripe_id = 0;
        u32 num_stripes = 1;
        bool more_claimable = false;
        {
            std::unique_lock lk{mutex};
            // gpu_seq moves without the lock: keep the candidate the predicate found.
            worker_cv.wait(lk, stop, [&] {
                TakeIntakeLocked();
                target = baseline_ready ? claimable() : nullptr;
                return target != nullptr;
            });
            if (stop.stop_requested() || !target) {
                return;
            }
            stripe_id = target->claimed_workers.fetch_add(1, std::memory_order_relaxed);
            num_stripes = target->max_workers;
            more_claimable = (claimable() != nullptr);
            // Buffers between this worker's state and the target: their deltas. A position
            // already collected (or past the target) restarts from the queue's tail state.
            if (position == NoPosition || position < tail_seq || position > target->seq) {
                *regs = *tail_regs;
                position = tail_seq;
            }
            const u64 front = submissions.front()->seq;
            path.clear();
            for (u64 seq = position; seq < target->seq; ++seq) {
                path.push_back(submissions[seq - front]);
            }
        }
        if (more_claimable) {
            worker_cv.notify_one();
        }
        for (const auto& step : path) {
            step->delta.Apply(*regs);
        }
        path.clear();
        u64 checksum = target->start_checksum;
        u32 ordinal = 0;
        FlatArena arena{target->worker_flat_chunks[stripe_id]};
        bool aborted = false;
        const auto cmds = target->cmds_span;
        for (size_t at = 0; at < cmds.size();) {
            const u32* packet = cmds.data() + at;
            const BbCp::Header header{*packet};
            if (header.Type() == 2) {
                ++at;
                continue;
            }
            if (header.Type() != 3) {
                break;
            }
            const size_t words = header.BodyWords() + 1;
            if (at + words > cmds.size()) {
                break;
            }
            at += words;

            BbCp::CommandProcessor::ApplyGraphicsRegisterPacket(*regs, packet, checksum);
            if (!IsDirectDrawPacket(packet)) {
                continue;
            }
            const u64 cur_gpu = gpu_seq.load(std::memory_order_acquire);
            if (target->seq < cur_gpu) {
                // Stage A already retired this entire submission; abort immediately.
                aborted = true;
                break;
            }
            const bool my_stripe =
                (num_stripes == 1) ||
                (((ordinal / Submission::StripeDraws) % num_stripes) == stripe_id);
            if (my_stripe && ordinal < target->num_draws) {
                // If Stage A is currently executing this submission, never burn CPU behind it:
                // skip straight ahead by 12 draws (register replay above costs ~0.03 us/draw).
                const bool overtaken =
                    (target->seq == cur_gpu) &&
                    (ordinal < target->gpu_ordinal.load(std::memory_order_relaxed) + 12u);
                if (!overtaken) {
                    auto& draw = target->draws[ordinal];
                    prep_worker.stages.clear();
                    prep_worker.failed = false;
                    sel.draw_indirect_params = {};
                    if (pipeline_cache.PrepareGraphicsPipeline(sel)) {
                        draw.reg_checksum = checksum;
                        draw.key = sel.graphics_key;
                        draw.key_hash = std::hash<GraphicsPipelineKey>{}(draw.key);
                        draw.num_stages = static_cast<u32>(prep_worker.stages.size());
                        for (u32 i = 0; i < draw.num_stages; ++i) {
                            const auto& stage = prep_worker.stages[i];
                            draw.stages[i] = {
                                .program = stage.program,
                                .hash = stage.hash,
                                .hw_stage = stage.hw_stage,
                                .pgm_base = stage.pgm_base,
                                .flat = arena.Append(*stage.flat),
                                .flat_size = static_cast<u32>(stage.flat->size()),
                            };
                            PrepareResources(*stage.worker_info, draw.stages[i], arena);
                        }
                        draw.vertex.valid = false;
                        const auto* vs = sel.infos[static_cast<u32>(Shader::SwStage::Vertex)];
                        if (vs && sel.fetch_shader) {
                            const u32 attr_count =
                                static_cast<u32>(sel.fetch_shader->attributes.size());
                            if (attr_count <= 16) [[likely]] {
                                std::array<Gcn::Buffer, 16> cur_buffers{};
                                for (u32 a = 0; a < attr_count; ++a) {
                                    cur_buffers[a] =
                                        sel.fetch_shader->attributes[a].GetSharp(*vs);
                                }
                                const u64 b_hash =
                                    attr_count
                                        ? XXH3_64bits(cur_buffers.data(),
                                                      attr_count * sizeof(Gcn::Buffer))
                                        : 0ULL;
                                const VkShaderModule vs_mod = static_cast<VkShaderModule>(
                                    sel.modules[static_cast<u32>(Shader::SwStage::Vertex)]);
                                auto& entry = (*vtx_memo)
                                    [(b_hash ^ (reinterpret_cast<uintptr_t>(vs_mod) >> 4)) & 31];
                                if (entry.submission_seq == target->seq &&
                                    entry.vs_module == vs_mod &&
                                    entry.step_rate_0 == regs->vgt_instance_step_rate_0 &&
                                    entry.step_rate_1 == regs->vgt_instance_step_rate_1 &&
                                    entry.count == attr_count && entry.buffers_hash == b_hash &&
                                    (attr_count == 0 ||
                                     std::memcmp(entry.buffers.data(), cur_buffers.data(),
                                                 attr_count * sizeof(Gcn::Buffer)) == 0)) {
                                    draw.vertex = entry.vertex;
                                } else {
                                    PrepareVertexInputs(
                                        *vs, *sel.fetch_shader, *regs, draw.vertex, arena,
                                        std::span<const Gcn::Buffer>{cur_buffers.data(),
                                                                     attr_count},
                                        b_hash, true);
                                    if (draw.vertex.valid) {
                                        entry.submission_seq = target->seq;
                                        entry.vs_module = vs_mod;
                                        entry.step_rate_0 = regs->vgt_instance_step_rate_0;
                                        entry.step_rate_1 = regs->vgt_instance_step_rate_1;
                                        entry.count = attr_count;
                                        entry.buffers_hash = b_hash;
                                        if (attr_count > 0) {
                                            std::memcpy(entry.buffers.data(), cur_buffers.data(),
                                                        attr_count * sizeof(Gcn::Buffer));
                                        }
                                        entry.vertex = draw.vertex;
                                    }
                                }
                            } else {
                                PrepareVertexInputs(*vs, *sel.fetch_shader, *regs, draw.vertex,
                                                    arena);
                            }
                        }
                        draw.state.store(PreparedDraw::Ready, std::memory_order_release);
                    } else {
                        draw.state.store(PreparedDraw::Unavailable, std::memory_order_release);
                    }
                }
            }
            ++ordinal;
        }
        position = aborted ? NoPosition : (target->seq + 1);
    }
}

void DrawPreparation::Count(bool was_used, Miss why) {
    ++(was_used ? used : unused);
    if (!was_used) {
        ++misses[why];
    }
    static const bool stats = std::getenv("BB_FRAME_STATS") != nullptr;
    // The clock is read every 1024 draws: per draw it was 8% of the GPU thread.
    if (!stats || ((used + unused) & 1023) != 0) {
        return;
    }
    static auto window = std::chrono::steady_clock::now();
    const auto now = std::chrono::steady_clock::now();
    if (now - window < std::chrono::seconds(5)) {
        return;
    }
    window = now;
    std::printf("Draw preparation: %llu prepared pipelines used, %llu not (not ready %llu, "
                "unavailable %llu, other registers %llu, other programs %llu; %u workers, "
                "%llu scanner rebases)\n",
                static_cast<unsigned long long>(used), static_cast<unsigned long long>(unused),
                static_cast<unsigned long long>(misses[NotReady]),
                static_cast<unsigned long long>(misses[Unavailable]),
                static_cast<unsigned long long>(misses[OtherRegisters]),
                static_cast<unsigned long long>(misses[OtherPrograms]), worker_count,
                static_cast<unsigned long long>(rebases));
    used = unused = 0;
    misses = {};
}

} // namespace Vulkan
