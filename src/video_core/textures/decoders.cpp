// SPDX-FileCopyrightText: Copyright 2025 Eden Emulator Project
// SPDX-License-Identifier: GPL-3.0-or-later

// SPDX-FileCopyrightText: Copyright 2018 yuzu Emulator Project
// SPDX-License-Identifier: GPL-2.0-or-later

#include <array>
#include <algorithm>
#include <atomic>
#include <bit>
#include <cmath>
#include <condition_variable>
#include <cstring>
#include <cstdlib>
#include <functional>
#include <mutex>
#include <span>
#include <thread>
#include <vector>

#include "common/alignment.h"
#include "common/assert.h"
#include "common/bit_util.h"
#include "common/div_ceil.h"
#include "common/logging.h"
#include "common/cpu_features.h"
#include "common/thread.h"
#include "video_core/gpu.h"
#include "video_core/textures/decoders.h"

namespace Tegra::Texture {
namespace {

/// Large unswizzles (new textures while running through Ocarina of Time's Kokiri Forest: ~11% of
/// the split GPU back thread) are split by lines over helper threads plus the caller, which waits
/// for all of them: the result is the same, only sooner. A quarter of the host threads, at most 4
/// (more competed with the guest cores and made busy spots drop harder).
class LinePool {
public:
    static LinePool& Get() {
        static LinePool pool;
        return pool;
    }

    [[nodiscard]] bool Enabled() const {
        return !workers.empty();
    }

    /// Calls func(begin, end) over [0, count) in chunks; returns once every chunk is done.
    void Run(u32 count, const std::function<void(u32, u32)>& func) {
        std::unique_lock busy{run_mutex, std::try_to_lock};
        if (!busy || workers.empty()) {
            func(0, count);
            return;
        }
        {
            std::scoped_lock lock{mutex};
            job = &func;
            total = count;
            chunk = (std::max)(8U, count / static_cast<u32>((workers.size() + 1) * 4));
            next.store(0, std::memory_order_relaxed);
            pending = static_cast<u32>(workers.size());
            ++generation;
        }
        work_cv.notify_all();
        Work(func);
        std::unique_lock lock{mutex};
        done_cv.wait(lock, [this] { return pending == 0; });
        job = nullptr;
    }

private:
    /// At most 4 and a quarter of the host threads, and only the physical cores past the 6 the
    /// guest cores and the GPU threads keep busy: on a 6-core Ryzen 5 5500, 3 workers competed
    /// with them (no gain, slower movies). EDEN_NX2_UNSWIZZLE_THREADS sets the count (tests).
    static u32 WorkerCount() {
        if (const char* const text = std::getenv("EDEN_NX2_UNSWIZZLE_THREADS")) {
            return (std::min)(static_cast<u32>(std::max(0, std::atoi(text))), 8U);
        }
        const u32 logical = std::thread::hardware_concurrency();
        u32 physical = logical / 2;
        if (const auto cores = Common::GetProcessorCount(); cores && *cores > 0) {
            physical = static_cast<u32>(*cores);
        }
        const u32 spare = physical > 6 ? physical - 6 : 0;
        return (std::min)({4U, logical / 4, spare});
    }

    LinePool() {
        const u32 count = WorkerCount();
        for (u32 i = 0; i < count; ++i) {
            workers.emplace_back([this](std::stop_token stop) { Loop(stop); });
        }
        LOG_INFO(HW_GPU, "Unswizzle helper threads: {}", count);
    }

    ~LinePool() {
        {
            // Under the mutex: a worker between its predicate check and its wait would otherwise
            // miss the notification and never return to be joined.
            std::scoped_lock lock{mutex};
            for (auto& worker : workers) {
                worker.request_stop();
            }
        }
        work_cv.notify_all();
        workers.clear();
    }

    void Work(const std::function<void(u32, u32)>& func) {
        for (;;) {
            const u32 begin = next.fetch_add(chunk, std::memory_order_relaxed);
            if (begin >= total) {
                return;
            }
            func(begin, (std::min)(begin + chunk, total));
        }
    }

    void Loop(std::stop_token stop) {
        Common::SetCurrentThreadName("Unswizzle");
        u64 seen = 0;
        for (;;) {
            const std::function<void(u32, u32)>* func;
            {
                std::unique_lock lock{mutex};
                work_cv.wait(lock, [&] { return stop.stop_requested() || generation != seen; });
                if (stop.stop_requested()) {
                    return;
                }
                seen = generation;
                func = job;
            }
            Work(*func);
            {
                std::scoped_lock lock{mutex};
                --pending;
            }
            done_cv.notify_one();
        }
    }

    std::mutex run_mutex;
    std::mutex mutex;
    std::condition_variable work_cv;
    std::condition_variable done_cv;
    const std::function<void(u32, u32)>* job{};
    u32 total{};
    u32 chunk{1};
    std::atomic<u32> next{};
    u32 pending{};
    u64 generation{};
    std::vector<std::jthread> workers;
};

constexpr u32 NativeGobOffset(u32 offset, bool native_tiling) {
    if (!native_tiling) return offset;
    const u32 difference = ((offset >> 5) ^ (offset >> 6)) & 1;
    return offset ^ (difference << 5) ^ (difference << 6);
}
template <u32 mask>
constexpr u32 pdep(u32 value) {
    u32 result = 0;
    u32 m = mask;
    for (u32 bit = 1; m; bit += bit) {
        if (value & bit)
            result |= m & (~m + 1);
        m &= m - 1;
    }
    return result;
}

template <u32 mask, u32 incr_amount>
void incrpdep(u32& value) {
    static constexpr u32 swizzled_incr = pdep<mask>(incr_amount);
    value = ((value | ~mask) + swizzled_incr) & mask;
}

// Where each 16-byte unit of a GOB row lies within the GOB, by row (y & 7) and unit (x / 16 & 3).
// The 16 bytes of a unit are contiguous. A GOB's own offset is a multiple of GOB_SIZE, so the
// native tiling's swap of bits 5 and 6 only moves units within it.
std::array<u32, GOB_SIZE_Y * 4> GobUnitOffsets(bool native_tiling) {
    std::array<u32, GOB_SIZE_Y * 4> offsets;
    for (u32 row = 0; row < GOB_SIZE_Y; ++row) {
        for (u32 unit = 0; unit < 4; ++unit) {
            offsets[row * 4 + unit] = NativeGobOffset(
                pdep<SWIZZLE_X_BITS>(unit * 16) | pdep<SWIZZLE_Y_BITS>(row), native_tiling);
        }
    }
    return offsets;
}

template <bool TO_LINEAR, u32 BYTES_PER_PIXEL>
void SwizzleImpl(std::span<u8> output, std::span<const u8> input, u32 width, u32 height, u32 depth,
                 u32 block_height, u32 block_depth, u32 stride, bool native_tiling) {
    // The origin of the transformation can be configured here, leave it as zero as the current API
    // doesn't expose it.
    static constexpr u32 origin_x = 0;
    static constexpr u32 origin_y = 0;
    static constexpr u32 origin_z = 0;

    // We can configure here a custom pitch
    // As it's not exposed 'width * BYTES_PER_PIXEL' will be the expected pitch.
    const u32 pitch = width * BYTES_PER_PIXEL;

    const u32 gobs_in_x = Common::DivCeilLog2(stride, GOB_SIZE_X_SHIFT);
    const u32 block_size = gobs_in_x << (GOB_SIZE_SHIFT + block_height + block_depth);
    const u32 slice_size =
        Common::DivCeilLog2(height, block_height + GOB_SIZE_Y_SHIFT) * block_size;

    const u32 block_height_mask = (1U << block_height) - 1;
    const u32 block_depth_mask = (1U << block_depth) - 1;
    const u32 x_shift = GOB_SIZE_SHIFT + block_height + block_depth;

    // 16-byte units (UnswizzleTexture and SwizzleTexture widen to them when a row allows it):
    // their offsets in a GOB come from a table instead of being computed one by one.
    static constexpr bool unit_table =
        BYTES_PER_PIXEL == 16 && origin_x == 0 && origin_y == 0 && origin_z == 0;
    [[maybe_unused]] const auto unit_offsets = GobUnitOffsets(native_tiling);
    [[maybe_unused]] const u32 gobs_wide = Common::DivCeil(width, 4U);

    // Each (slice, line) writes its own bytes of the output: lines can go to other threads.
    const auto lines = [&](u32 first, u32 end) {
    for (u32 index = first; index < end; ++index) {
        const u32 slice = index / height;
        const u32 line = index % height;
        const u32 z = slice + origin_z;
        const u32 offset_z = (z >> block_depth) * slice_size +
                             ((z & block_depth_mask) << (GOB_SIZE_SHIFT + block_height));
        {
            const u32 y = line + origin_y;
            const u32 swizzled_y = pdep<SWIZZLE_Y_BITS>(y);

            const u32 block_y = y >> GOB_SIZE_Y_SHIFT;
            const u32 offset_y = (block_y >> block_height) * block_size +
                                 ((block_y & block_height_mask) << GOB_SIZE_SHIFT);

            if constexpr (unit_table) {
                const u32* const row_offsets = &unit_offsets[(y & (GOB_SIZE_Y - 1)) * 4];
                const u32 row_linear = slice * pitch * height + line * pitch;
                for (u32 gob_x = 0; gob_x < gobs_wide; ++gob_x) {
                    const u32 gob_offset = offset_z + offset_y + (gob_x << x_shift);
                    const u32 units = (std::min)(4U, width - gob_x * 4);
                    for (u32 unit = 0; unit < units; ++unit) {
                        const u32 swizzled_offset = gob_offset + row_offsets[unit];
                        const u32 unswizzled_offset = row_linear + (gob_x * 4 + unit) * 16;
                        u8* const dst = &output[TO_LINEAR ? swizzled_offset : unswizzled_offset];
                        const u8* const src =
                            &input[TO_LINEAR ? unswizzled_offset : swizzled_offset];
                        std::memcpy(dst, src, 16);
                    }
                }
                continue;
            }

            u32 swizzled_x = pdep<SWIZZLE_X_BITS>(origin_x * BYTES_PER_PIXEL);
            for (u32 column = 0; column < width;
                 ++column, incrpdep<SWIZZLE_X_BITS, BYTES_PER_PIXEL>(swizzled_x)) {
                const u32 x = (column + origin_x) * BYTES_PER_PIXEL;
                const u32 offset_x = (x >> GOB_SIZE_X_SHIFT) << x_shift;

                const u32 base_swizzled_offset = offset_z + offset_y + offset_x;
                const u32 swizzled_offset = NativeGobOffset(base_swizzled_offset + (swizzled_x | swizzled_y), native_tiling);

                const u32 unswizzled_offset =
                    slice * pitch * height + line * pitch + column * BYTES_PER_PIXEL;

                u8* const dst = &output[TO_LINEAR ? swizzled_offset : unswizzled_offset];
                const u8* const src = &input[TO_LINEAR ? unswizzled_offset : swizzled_offset];

                std::memcpy(dst, src, BYTES_PER_PIXEL);
            }
        }
    }
    };
    const u32 total_lines = depth * height;
    // From 1 MiB: splitting medium textures too (256 KiB) made busy spots drop harder.
    constexpr u64 min_bytes = u64{1} << 20;
    if (!TO_LINEAR && LinePool::Get().Enabled() && u64{pitch} * total_lines >= min_bytes) {
        LinePool::Get().Run(total_lines, lines);
    } else {
        lines(0, total_lines);
    }
}

template <bool TO_LINEAR, u32 BYTES_PER_PIXEL>
void SwizzleSubrectImpl(std::span<u8> output, std::span<const u8> input, u32 width, u32 height,
                        u32 depth, u32 origin_x, u32 origin_y, u32 extent_x, u32 num_lines,
                        u32 block_height, u32 block_depth, u32 pitch_linear, bool native_tiling) {
    // The origin of the transformation can be configured here, leave it as zero as the current API
    // doesn't expose it.
    static constexpr u32 origin_z = 0;

    // We can configure here a custom pitch
    // As it's not exposed 'width * BYTES_PER_PIXEL' will be the expected pitch.
    const u32 pitch = pitch_linear;
    const u32 stride = Common::AlignUpLog2(width * BYTES_PER_PIXEL, GOB_SIZE_X_SHIFT);

    const u32 gobs_in_x = Common::DivCeilLog2(stride, GOB_SIZE_X_SHIFT);
    const u32 block_size = gobs_in_x << (GOB_SIZE_SHIFT + block_height + block_depth);
    const u32 slice_size =
        Common::DivCeilLog2(height, block_height + GOB_SIZE_Y_SHIFT) * block_size;

    const u32 block_height_mask = (1U << block_height) - 1;
    const u32 block_depth_mask = (1U << block_depth) - 1;
    const u32 x_shift = GOB_SIZE_SHIFT + block_height + block_depth;

    u32 unprocessed_lines = num_lines;
    u32 extent_y = (std::min)(num_lines, height - origin_y);
    // Power of two pixels never straddle a 16-byte unit: copy each row in runs of whole units
    // (and the partial ones at its ends) from the unit table.
    constexpr bool unit_runs = std::has_single_bit(BYTES_PER_PIXEL);
    [[maybe_unused]] const auto unit_offsets = GobUnitOffsets(native_tiling);

    for (u32 slice = 0; slice < depth; ++slice) {
        const u32 z = slice + origin_z;
        const u32 offset_z = (z >> block_depth) * slice_size +
                             ((z & block_depth_mask) << (GOB_SIZE_SHIFT + block_height));
        const u32 lines_in_y = (std::min)(unprocessed_lines, extent_y);
        for (u32 line = 0; line < lines_in_y; ++line) {
            const u32 y = line + origin_y;
            const u32 swizzled_y = pdep<SWIZZLE_Y_BITS>(y);

            const u32 block_y = y >> GOB_SIZE_Y_SHIFT;
            const u32 offset_y = (block_y >> block_height) * block_size +
                                 ((block_y & block_height_mask) << GOB_SIZE_SHIFT);

            if constexpr (unit_runs) {
                const u32* const row_offsets = &unit_offsets[(y & (GOB_SIZE_Y - 1)) * 4];
                const u32 x_begin = origin_x * BYTES_PER_PIXEL;
                const u32 x_end = (origin_x + extent_x) * BYTES_PER_PIXEL;
                const u32 row_linear = slice * pitch * height + line * pitch;
                for (u32 x = x_begin; x < x_end;) {
                    const u32 run = (std::min)(16 - (x & 15), x_end - x);
                    const u32 swizzled_offset = offset_z + offset_y +
                                                ((x >> GOB_SIZE_X_SHIFT) << x_shift) +
                                                row_offsets[(x >> 4) & 3] + (x & 15);
                    const u32 unswizzled_offset = row_linear + (x - x_begin);
                    u8* const dst = &output[TO_LINEAR ? swizzled_offset : unswizzled_offset];
                    const u8* const src = &input[TO_LINEAR ? unswizzled_offset : swizzled_offset];
                    std::memcpy(dst, src, run);
                    x += run;
                }
                continue;
            }

            u32 swizzled_x = pdep<SWIZZLE_X_BITS>(origin_x * BYTES_PER_PIXEL);
            for (u32 column = 0; column < extent_x;
                 ++column, incrpdep<SWIZZLE_X_BITS, BYTES_PER_PIXEL>(swizzled_x)) {
                const u32 x = (column + origin_x) * BYTES_PER_PIXEL;
                const u32 offset_x = (x >> GOB_SIZE_X_SHIFT) << x_shift;

                const u32 base_swizzled_offset = offset_z + offset_y + offset_x;
                const u32 swizzled_offset = NativeGobOffset(base_swizzled_offset + (swizzled_x | swizzled_y), native_tiling);

                const u32 unswizzled_offset =
                    slice * pitch * height + line * pitch + column * BYTES_PER_PIXEL;

                u8* const dst = &output[TO_LINEAR ? swizzled_offset : unswizzled_offset];
                const u8* const src = &input[TO_LINEAR ? unswizzled_offset : swizzled_offset];

                std::memcpy(dst, src, BYTES_PER_PIXEL);
            }
        }
        unprocessed_lines -= lines_in_y;
        if (unprocessed_lines == 0) {
            return;
        }
    }
}

template <bool TO_LINEAR>
void Swizzle(std::span<u8> output, std::span<const u8> input, u32 bytes_per_pixel, u32 width,
             u32 height, u32 depth, u32 block_height, u32 block_depth, u32 stride_alignment, bool native_tiling) {
    switch (bytes_per_pixel) {
#define BPP_CASE(x)                                                                                \
    case x:                                                                                        \
        return SwizzleImpl<TO_LINEAR, x>(output, input, width, height, depth, block_height,        \
                                         block_depth, stride_alignment, native_tiling);
        BPP_CASE(1)
        BPP_CASE(2)
        BPP_CASE(3)
        BPP_CASE(4)
        BPP_CASE(6)
        BPP_CASE(8)
        BPP_CASE(12)
        BPP_CASE(16)
#undef BPP_CASE
    default:
        ASSERT_MSG(false, "Invalid bytes_per_pixel={}", bytes_per_pixel);
        break;
    }
}

} // Anonymous namespace

void PrepareUnswizzleThreads() {
    [[maybe_unused]] const bool enabled = LinePool::Get().Enabled();
}

void UnswizzleTexture(std::span<u8> output, std::span<const u8> input, u32 bytes_per_pixel,
                      u32 width, u32 height, u32 depth, u32 block_height, u32 block_depth,
                      u32 stride_alignment, bool native_tiling) {
    const u32 stride = Common::AlignUpLog2(width, stride_alignment) * bytes_per_pixel;
    const u32 new_bpp = (std::min)(4U, static_cast<u32>(std::countr_zero(width * bytes_per_pixel)));
    width = (width * bytes_per_pixel) >> new_bpp;
    bytes_per_pixel = 1U << new_bpp;
    Swizzle<false>(output, input, bytes_per_pixel, width, height, depth, block_height, block_depth,
                   stride, native_tiling);
}

void SwizzleTexture(std::span<u8> output, std::span<const u8> input, u32 bytes_per_pixel, u32 width,
                    u32 height, u32 depth, u32 block_height, u32 block_depth,
                    u32 stride_alignment, bool native_tiling) {
    const u32 stride = Common::AlignUpLog2(width, stride_alignment) * bytes_per_pixel;
    const u32 new_bpp = (std::min)(4U, static_cast<u32>(std::countr_zero(width * bytes_per_pixel)));
    width = (width * bytes_per_pixel) >> new_bpp;
    bytes_per_pixel = 1U << new_bpp;
    Swizzle<true>(output, input, bytes_per_pixel, width, height, depth, block_height, block_depth,
                  stride, native_tiling);
}

void SwizzleSubrect(std::span<u8> output, std::span<const u8> input, u32 bytes_per_pixel, u32 width,
                    u32 height, u32 depth, u32 origin_x, u32 origin_y, u32 extent_x, u32 extent_y,
                    u32 block_height, u32 block_depth, u32 pitch_linear, bool native_tiling) {
    switch (bytes_per_pixel) {
#define BPP_CASE(x)                                                                                \
    case x:                                                                                        \
        return SwizzleSubrectImpl<true, x>(output, input, width, height, depth, origin_x,          \
                                           origin_y, extent_x, extent_y, block_height,             \
                                           block_depth, pitch_linear, native_tiling);
        BPP_CASE(1)
        BPP_CASE(2)
        BPP_CASE(3)
        BPP_CASE(4)
        BPP_CASE(6)
        BPP_CASE(8)
        BPP_CASE(12)
        BPP_CASE(16)
#undef BPP_CASE
    default:
        ASSERT_MSG(false, "Invalid bytes_per_pixel={}", bytes_per_pixel);
        break;
    }
}

void UnswizzleSubrect(std::span<u8> output, std::span<const u8> input, u32 bytes_per_pixel,
                      u32 width, u32 height, u32 depth, u32 origin_x, u32 origin_y, u32 extent_x,
                      u32 extent_y, u32 block_height, u32 block_depth, u32 pitch_linear, bool native_tiling) {
    switch (bytes_per_pixel) {
#define BPP_CASE(x)                                                                                \
    case x:                                                                                        \
        return SwizzleSubrectImpl<false, x>(output, input, width, height, depth, origin_x,         \
                                            origin_y, extent_x, extent_y, block_height,            \
                                            block_depth, pitch_linear, native_tiling);
        BPP_CASE(1)
        BPP_CASE(2)
        BPP_CASE(3)
        BPP_CASE(4)
        BPP_CASE(6)
        BPP_CASE(8)
        BPP_CASE(12)
        BPP_CASE(16)
#undef BPP_CASE
    default:
        ASSERT_MSG(false, "Invalid bytes_per_pixel={}", bytes_per_pixel);
        break;
    }
}

std::size_t CalculateSize(bool tiled, u32 bytes_per_pixel, u32 width, u32 height, u32 depth,
                          u32 block_height, u32 block_depth) {
    if (tiled) {
        const u32 aligned_width = Common::AlignUpLog2(width * bytes_per_pixel, GOB_SIZE_X_SHIFT);
        const u32 aligned_height = Common::AlignUpLog2(height, GOB_SIZE_Y_SHIFT + block_height);
        const u32 aligned_depth = Common::AlignUpLog2(depth, GOB_SIZE_Z_SHIFT + block_depth);
        return aligned_width * aligned_height * aligned_depth;
    } else {
        return width * height * depth * bytes_per_pixel;
    }
}

u64 GetGOBOffset(u32 width, u32 height, u32 dst_x, u32 dst_y, u32 block_height,
                 u32 bytes_per_pixel) {
    auto div_ceil = [](const u32 x, const u32 y) { return ((x + y - 1) / y); };
    const u32 gobs_in_block = 1 << block_height;
    const u32 y_blocks = GOB_SIZE_Y << block_height;
    const u32 x_per_gob = GOB_SIZE_X / bytes_per_pixel;
    const u32 x_blocks = div_ceil(width, x_per_gob);
    const u32 block_size = GOB_SIZE * gobs_in_block;
    const u32 stride = block_size * x_blocks;
    const u32 base = (dst_y / y_blocks) * stride + (dst_x / x_per_gob) * block_size;
    const u32 relative_y = dst_y % y_blocks;
    return base + (relative_y / GOB_SIZE_Y) * GOB_SIZE;
}

} // namespace Tegra::Texture
