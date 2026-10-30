// MIT License. Copyright (c) 2026 João Alano and GT4Recomp contributors.
// Written from the TASK-026 specification (docs/hw-renderer-spec), clean room per decision 0070.
// Chapter 12.2/12.3 hookup on main's TASK-035 seam: GT4_RENDERER=hw feeds the GS stream hooks to the HWR backend
// in the game process (native/gs_stream/gs_stream_sink.hpp). Replaces the M0b gs.cpp splice of task/027-hw-renderer
// (native/hw_gs_frontend.inc and the paraLLEl-GS dispatch, dropped with paraLLEl-GS by decision 0070).
//
// The backend receives every GIF chunk, privileged write and VSYNC, draws through the GPU write-back renderer (M4/M5)
// and presents the composed display with the VBlank's field (M6: 13.3 field offset, 13.4 deinterlace). Local-to-host
// reads are answered from the shadow local memory after the open batch is flushed (10.2).

#include "gs_stream/gs_stream_sink.hpp"

#include "hw_cpu_sampler.hpp"
#include "hw_gs_backend.hpp"
#include "hw_gs_options.hpp"
#include "mtvu_ring.hpp"

#define WIN32_LEAN_AND_MEAN
#define NOMINMAX
#include <windows.h>
#include <intrin.h>

#include <algorithm>
#include <atomic>
#include <chrono>
#include <cstdio>
#include <cstdlib>
#include <cstring>
#include <mutex>
#include <string>
#include <thread>
#include <vector>

namespace gt4::hw {
namespace {

Backend *g_backend = nullptr;
bool g_odd_field = false;
std::uint64_t g_vsyncs = 0;
std::uint64_t g_unmirrored_privileged = 0;
// GT4_HW_PROFILE_EVERY state (see maybe_profile).
std::uint32_t g_profile_every = 0;
RenderCounters g_profile_last;
std::chrono::steady_clock::time_point g_profile_wall;

// M6 frame dumps (chapter 12.9 asks for them; the donor renderer cannot provide them in this mode).
// GT4_HW_DUMP_DIR=<folder> writes P6 PPM files, GT4_HW_DUMP_EVERY=<n> the interval in VBlanks (default
// 100). The image is the composed scanout of the GPU write-back path (Backend::scanout). The RAW VRAM
// buffer decode of chapter 12.9 stays with the CPU reference tool, which owns that oracle (IN-325).
std::string g_dump_dir;
std::uint32_t g_dump_every = 0;
std::uint64_t g_dump_from = 0;  // GT4_HW_DUMP_FROM=<vblank>: no dumps before it (consecutive frames of one scene)
std::uint64_t g_dumps = 0;
std::uint64_t g_dumps_without_image = 0;

void read_dump_options() {
  const char *dir = std::getenv("GT4_HW_DUMP_DIR");
  if (dir && *dir) {
    g_dump_dir = dir;
    g_dump_every = 100;
    if (const char *every = std::getenv("GT4_HW_DUMP_EVERY")) {
      const long value = std::strtol(every, nullptr, 10);
      g_dump_every = value > 0 ? static_cast<std::uint32_t>(value) : 100u;
    }
    if (const char *from = std::getenv("GT4_HW_DUMP_FROM")) g_dump_from = std::strtoull(from, nullptr, 10);
    std::fprintf(stderr, "[hw] frame dumps: %s every %u VBlanks from %llu (composed scanout image)\n",
                 g_dump_dir.c_str(), g_dump_every, static_cast<unsigned long long>(g_dump_from));
  }
}

// One P6 PPM of the composed scanout image. Returns false when there was no image this VBlank.
bool write_dump(Backend &hw, std::uint64_t index) {
  ScanoutRequest request;
  if (!hw.scanout(request) || request.width == 0 || request.height == 0) return false;
  char name[64];
  std::snprintf(name, sizeof(name), "frame_%05llu.ppm", static_cast<unsigned long long>(index));
  const std::string path = g_dump_dir + "\\" + name;
  std::FILE *file = std::fopen(path.c_str(), "wb");
  if (!file) return false;
  std::fprintf(file, "P6\n%u %u\n255\n", request.width, request.height);
  // One write per row (a 12x frame has 41 million pixels; a write per pixel took longer than the frame itself).
  std::vector<unsigned char> row(std::size_t{request.width} * 3u);
  for (std::size_t y = 0; y < request.height; ++y) {
    const std::uint32_t *pixels = request.pixels.data() + y * request.width;
    for (std::size_t x = 0; x < request.width; ++x) {
      row[3 * x] = static_cast<unsigned char>(pixels[x] & 0xFFu);
      row[3 * x + 1] = static_cast<unsigned char>((pixels[x] >> 8) & 0xFFu);
      row[3 * x + 2] = static_cast<unsigned char>((pixels[x] >> 16) & 0xFFu);
    }
    std::fwrite(row.data(), 1, row.size(), file);
  }
  std::fclose(file);
  return true;
}

void maybe_dump(Backend &hw) {
  if (g_dump_every == 0) return;
  if (g_vsyncs < g_dump_from || g_vsyncs % g_dump_every != 0) return;
  if (write_dump(hw, g_vsyncs)) {
    ++g_dumps;
  } else {
    ++g_dumps_without_image;
  }
}

void start_gs_worker();

// TASK-027 CPU survey: the cost of carrying the GS stream from the game (EE) thread to the GS worker, in TSC ticks
// (converted with the QPC rate between two profile lines). Each counter has one writer: the producer counters are
// written by the thread that calls the hooks (the EE thread), the worker counters by the GS worker. With the stream
// ring (IN-446) the hook's whole cost is the copy into the ring, so copy_ms equals gif_ms, and max_depth is in bytes.
struct TransportCounters {
  // Producer (EE thread).
  std::atomic<std::uint64_t> gif_commands{0}, gif_bytes{0}, privileged_commands{0}, vsync_commands{0};
  std::atomic<std::uint64_t> gif_ticks{0};         // inside gif(): buffer, copy and queue push
  std::atomic<std::uint64_t> copy_ticks{0};        // the byte copy alone
  std::atomic<std::uint64_t> privileged_ticks{0};  // inside privileged()
  std::atomic<std::uint64_t> vsync_wait_ticks{0}, vsync_waits{0};  // back-pressure (kFramesAhead)
  std::atomic<std::uint64_t> drain_wait_ticks{0}, drains{0};       // read_fifo / window calls waiting for the worker
  std::atomic<std::uint64_t> read_fifo_ticks{0}, read_fifos{0};    // read_fifo including its drain
  std::atomic<std::uint64_t> wake_pushes{0};       // pushes that found the worker waiting for work
  // Worker (GS worker thread).
  std::atomic<std::uint64_t> busy_ticks[5] = {};   // per GsCommand::Kind: Gif, Privileged, Vsync, GsReset, GifReset
  std::atomic<std::uint64_t> idle_ticks{0}, wakeups{0}, max_depth{0};
  // IN-461 (direct GS intake): VU1 jobs and records executed straight from the MTVU output ring, and the waits for them.
  std::atomic<std::uint64_t> mtvu_jobs{0}, mtvu_records{0}, mtvu_wait_ticks{0}, mtvu_sleeps{0};
};
TransportCounters g_transport;

void add(std::atomic<std::uint64_t> &counter, std::uint64_t value) {
  counter.store(counter.load(std::memory_order_relaxed) + value, std::memory_order_relaxed);  // single writer
}

bool start_backend(std::string &error) {
  Options options;
  try {
    options = parse_options([](const char *name) -> const char * { return std::getenv(name); });
  } catch (const OptionError &problem) {
    error = problem.what();
    return false;
  }
  read_dump_options();
  sampler::name_current_thread("ee");
  if (sampler::start_from_env()) std::fprintf(stderr, "[cpu-sampler] sampling the process (GT4_CPU_SAMPLER)\n");
  if (const char *every = std::getenv("GT4_HW_PROFILE_EVERY")) {
    const long value = std::strtol(every, nullptr, 10);
    g_profile_every = value > 0 ? static_cast<std::uint32_t>(value) : 0u;
    g_profile_wall = std::chrono::steady_clock::now();
  }
  // Created once and never destroyed: the Vulkan device must not be torn down during process exit.
  auto *created = new Backend;
  if (!created->init(options, error)) return false;
  g_backend = created;
  std::fprintf(stderr, "[hw] GT4_RENDERER=hw: HWR backend started in process, no GS process and no donor Vulkan renderer\n");
  start_gs_worker();
  for (const std::string &line : describe_options(options)) std::fprintf(stderr, "[hw] %s\n", line.c_str());
  return true;
}

Backend &backend() {
  if (!g_backend) {
    std::fprintf(stderr, "[hw] HWR backend used before start; stopping\n");
    std::exit(EXIT_FAILURE);
  }
  return *g_backend;
}

void gif_now(int path, const std::uint8_t *data, std::size_t bytes) { backend().gif_transfer(path, data, bytes); }

void privileged_now(std::uint32_t address, std::uint64_t value) {
  if (!backend().write_privileged(address, value)) ++g_unmirrored_privileged;
}

void read_fifo_now(std::uint8_t *data, std::uint32_t qwords) {
  const std::size_t filled = backend().read_transfer_fifo(data, qwords);
  if (filled < qwords) std::memset(data + filled * 16, 0, (static_cast<std::size_t>(qwords) - filled) * 16);
}

// Once per guest VBlank: submit the recorded work, then present (window) or close the frame (headless).
// GT4_HW_PROFILE_EVERY=<n>: every n VBlanks, one stderr line with the interval's per-frame averages (CPU ms per
// pass and work counts), so heavy scenes (3D cars, races) can be profiled from a headless run (M9 work).

// TASK-027 CPU survey: one [hw] transport line per profile interval (per-VBlank averages).
void print_transport(double n) {
  constexpr int kValues = 25;
  static std::uint64_t lastTsc = 0;
  static LARGE_INTEGER lastQpc{};
  static std::uint64_t last[kValues] = {};
  const std::uint64_t tsc = __rdtsc();
  LARGE_INTEGER qpc{}, frequency{};
  QueryPerformanceCounter(&qpc);
  QueryPerformanceFrequency(&frequency);
  const TransportCounters &t = g_transport;
  const std::uint64_t values[kValues] = {
      t.gif_commands.load(), t.gif_bytes.load(), t.privileged_commands.load(), t.vsync_commands.load(),
      t.gif_ticks.load(), t.copy_ticks.load(), t.privileged_ticks.load(), t.vsync_wait_ticks.load(),
      t.vsync_waits.load(), t.drain_wait_ticks.load(), t.drains.load(), t.read_fifo_ticks.load(),
      t.read_fifos.load(), t.wake_pushes.load(), t.busy_ticks[0].load(), t.busy_ticks[1].load(),
      t.busy_ticks[2].load(), t.busy_ticks[3].load() + t.busy_ticks[4].load(), t.idle_ticks.load(),
      t.wakeups.load(), t.max_depth.load(), t.mtvu_jobs.load(), t.mtvu_records.load(), t.mtvu_wait_ticks.load(),
      t.mtvu_sleeps.load()};
  if (lastTsc != 0 && tsc > lastTsc) {
    const double seconds = static_cast<double>(qpc.QuadPart - lastQpc.QuadPart) / static_cast<double>(frequency.QuadPart);
    const double msPerTick = seconds * 1000.0 / static_cast<double>(tsc - lastTsc);
    const auto d = [&](int i) { return static_cast<double>(values[i] - last[i]) / n; };
    const auto ms = [&](int i) { return d(i) * msPerTick; };
    std::fprintf(stderr,
                 "[hw] transport vsync=%llu ee: gif_cmds=%.1f gif_kib=%.0f priv_cmds=%.1f gif_ms=%.3f copy_ms=%.3f "
                 "priv_ms=%.3f vsync_wait_ms=%.3f (%.2f) drain_wait_ms=%.3f (%.2f) read_fifo_ms=%.3f (%.2f) "
                 "wake_pushes=%.1f | worker: gif_ms=%.3f priv_ms=%.3f vsync_ms=%.3f other_ms=%.3f idle_ms=%.3f "
                 "wakeups=%.1f max_depth=%llu mtvu_jobs=%.1f mtvu_records=%.1f mtvu_wait_ms=%.3f mtvu_sleeps=%.1f\n",
                 static_cast<unsigned long long>(g_vsyncs), d(0), d(1) / 1024.0, d(2), ms(4), ms(5), ms(6), ms(7), d(8),
                 ms(9), d(10), ms(11), d(12), d(13), ms(14), ms(15), ms(16), ms(17), ms(18), d(19),
                 static_cast<unsigned long long>(values[20]), d(21), d(22), ms(23), d(24));
  }
  std::copy(std::begin(values), std::end(values), std::begin(last));
  lastTsc = tsc;
  lastQpc = qpc;
}

void maybe_profile(Backend &hw) {
  if (g_profile_every == 0 || g_vsyncs % g_profile_every != 0) return;
  const RenderCounters now = hw.render_counters();
  const RenderCounters &was = g_profile_last;
  const double n = static_cast<double>(g_profile_every);
  const auto wall = std::chrono::steady_clock::now();
  const double wallMs = std::chrono::duration<double, std::milli>(wall - g_profile_wall).count() / n;
  std::fprintf(stderr,
               "[hw] profile vsync=%llu wall_ms=%.2f gif_ms=%.2f upload_ms=%.2f translate_ms=%.2f execute_ms=%.2f "
               "decode_ms=%.2f "
               "writeback_ms=%.2f load_ms=%.2f batches=%.1f prims=%.1f draws=%.1f chunks=%.1f textures=%.1f "
               "cached=%.1f texels=%.0f writebacks=%.2f loads=%.2f submissions=%.2f barriers=%.1f "
               "wb_other=%.2f wb_texture=%.2f wb_clut=%.2f wb_transfer=%.2f wb_display=%.2f wb_evict=%.2f "
               "wb_overlap=%.2f wb_fallback=%.2f wb_sprite=%.2f\n",
               static_cast<unsigned long long>(g_vsyncs), wallMs, (now.gif_us - was.gif_us) / n / 1000.0,
               (now.upload_us - was.upload_us) / n / 1000.0, (now.translate_us - was.translate_us) / n / 1000.0,
               (now.execute_us - was.execute_us) / n / 1000.0, (now.decode_us - was.decode_us) / n / 1000.0,
               (now.cache_writeback_us - was.cache_writeback_us) / n / 1000.0,
               (now.cache_load_us - was.cache_load_us) / n / 1000.0, static_cast<double>(now.batches - was.batches) / n,
               static_cast<double>(now.primitives - was.primitives) / n,
               static_cast<double>(now.gpu_draws - was.gpu_draws) / n, static_cast<double>(now.gpu_chunks - was.gpu_chunks) / n,
               static_cast<double>(now.textures - was.textures) / n,
               static_cast<double>(now.textures_cached - was.textures_cached) / n,
               static_cast<double>(now.texels - was.texels) / n,
               static_cast<double>(now.cache_writebacks - was.cache_writebacks) / n,
               static_cast<double>(now.cache_loads - was.cache_loads) / n,
               static_cast<double>(now.gpu_submissions - was.gpu_submissions) / n,
               static_cast<double>(now.gpu_barriers - was.gpu_barriers) / n,
               static_cast<double>(now.writeback_reasons[0] - was.writeback_reasons[0]) / n,
               static_cast<double>(now.writeback_reasons[1] - was.writeback_reasons[1]) / n,
               static_cast<double>(now.writeback_reasons[2] - was.writeback_reasons[2]) / n,
               static_cast<double>(now.writeback_reasons[3] - was.writeback_reasons[3]) / n,
               static_cast<double>(now.writeback_reasons[4] - was.writeback_reasons[4]) / n,
               static_cast<double>(now.writeback_reasons[5] - was.writeback_reasons[5]) / n,
               static_cast<double>(now.writeback_reasons[6] - was.writeback_reasons[6]) / n,
               static_cast<double>(now.writeback_reasons[7] - was.writeback_reasons[7]) / n,
               static_cast<double>(now.writeback_reasons[8] - was.writeback_reasons[8]) / n);
  if (now.gpu_busy_ns != was.gpu_busy_ns) {
    std::fprintf(stderr,
                 "[hw] gpu vsync=%llu busy_ms=%.2f pass_ms=%.2f decode_ms=%.2f clut_ms=%.2f swizzle_ms=%.2f "
                 "upload_ms=%.2f download_ms=%.2f scaled_ms=%.2f refresh_ms=%.2f early_submissions=%.2f\n",
                 static_cast<unsigned long long>(g_vsyncs), (now.gpu_busy_ns - was.gpu_busy_ns) / n / 1e6,
                 (now.gpu_ns[0] - was.gpu_ns[0]) / n / 1e6, (now.gpu_ns[1] - was.gpu_ns[1]) / n / 1e6,
                 (now.gpu_ns[2] - was.gpu_ns[2]) / n / 1e6, (now.gpu_ns[3] - was.gpu_ns[3]) / n / 1e6,
                 (now.gpu_ns[4] - was.gpu_ns[4]) / n / 1e6, (now.gpu_ns[5] - was.gpu_ns[5]) / n / 1e6,
                 (now.gpu_ns[6] - was.gpu_ns[6]) / n / 1e6, (now.gpu_ns[7] - was.gpu_ns[7]) / n / 1e6,
                 static_cast<double>(now.gpu_early_submissions - was.gpu_early_submissions) / n);
  }
  // IN-367 efficiency line (owner principle 2026-10-22: measure cost, not only FPS): CPU time of the thread that
  // runs the GS stream (the GS worker, or the EE thread with GT4_HW_GS_THREAD=0) and of the whole process (all
  // threads: EE, VU1 worker, GS worker, audio, driver), in ms per frame; render passes, barriers and bytes moved
  // between CPU and GPU per frame.
  {
    static double lastThreadMs = 0.0;
    static double lastProcessMs = 0.0;
    static bool primed = false;
    auto filetime_ms = [](const FILETIME &kernel, const FILETIME &user) {
      const auto ticks = [](const FILETIME &t) {
        return (static_cast<unsigned long long>(t.dwHighDateTime) << 32) | t.dwLowDateTime;
      };
      return static_cast<double>(ticks(kernel) + ticks(user)) / 10000.0;  // 100 ns units
    };
    FILETIME created{}, exited{}, kernel{}, user{};
    double threadMs = 0.0, processMs = 0.0;
    if (GetThreadTimes(GetCurrentThread(), &created, &exited, &kernel, &user)) threadMs = filetime_ms(kernel, user);
    if (GetProcessTimes(GetCurrentProcess(), &created, &exited, &kernel, &user)) processMs = filetime_ms(kernel, user);
    if (primed) {
      std::fprintf(stderr,
                   "[hw] cost vsync=%llu gs_thread_cpu_ms=%.2f process_cpu_core_ms=%.2f render_passes=%.1f "
                   "barriers=%.1f upload_mb=%.2f readback_mb=%.3f scaled_image_mb=%.1f\n",
                   static_cast<unsigned long long>(g_vsyncs), (threadMs - lastThreadMs) / n,
                   (processMs - lastProcessMs) / n,
                   static_cast<double>(now.gpu_render_passes - was.gpu_render_passes) / n,
                   static_cast<double>(now.gpu_barriers - was.gpu_barriers) / n,
                   static_cast<double>(now.gpu_upload_bytes - was.gpu_upload_bytes) / n / 1e6,
                   static_cast<double>(now.gpu_readback_bytes - was.gpu_readback_bytes) / n / 1e6,
                   static_cast<double>(now.gpu_scaled_image_bytes) / 1e6);
      // IN-384 follow-up (owner test 11, sporadic 1x frames): why a VBlank fell back to the CPU 1x presentation.
      // 0 GpuComposeApplies declined, 1 zero output size, 2 interlaced frame larger than the deinterlace images,
      // 3 the GPU compose or its flush failed.
      const unsigned long long skips[4] = {now.gpu_compose_skips[0] - was.gpu_compose_skips[0],
                                           now.gpu_compose_skips[1] - was.gpu_compose_skips[1],
                                           now.gpu_compose_skips[2] - was.gpu_compose_skips[2],
                                           now.gpu_compose_skips[3] - was.gpu_compose_skips[3]};
      if (skips[0] + skips[1] + skips[2] + skips[3] != 0) {
        std::fprintf(stderr, "[hw] compose_skips applies=%llu zero_size=%llu too_big=%llu failed=%llu\n", skips[0],
                     skips[1], skips[2], skips[3]);
      }
    }
    primed = true;
    lastThreadMs = threadMs;
    lastProcessMs = processMs;
  }
  print_transport(n);
  g_profile_last = now;
  g_profile_wall = wall;
}

void vsync_now(bool odd_field) {
  Backend &hw = backend();
  g_odd_field = odd_field;
  ++g_vsyncs;
  sampler::note_vblank(g_vsyncs);
  hw.set_display_field(odd_field);
  hw.flush();
  hw.next_frame();  // one guest frame per VBlank, windowed or headless (the session line's `frames`)
  if (hw.has_window()) hw.present(odd_field ? PresentPhase::field_odd : PresentPhase::field_even);
  maybe_dump(hw);
  maybe_profile(hw);
}

void gs_reset_now() {
  Backend &hw = backend();
  hw.reset_context();
  hw.reset_gif_paths();
  hw.clear_vram();
}

void gif_reset_now() { backend().reset_gif_paths(); }

// ---- GS worker thread (IN-363) ----
// The game's EE thread used to run the whole GS stream (parse, translate, record, submit, compose, present)
// synchronously. Now it queues the stream, in order, to one worker thread, which runs exactly the calls above in
// the same order, so results are unchanged; the EE continues while the GS work of the frame runs. The calls that
// return data or change the window (LOCAL->HOST FIFO reads, window attach and resize, the end of the session)
// first wait until the worker has executed everything queued before them, then run under the lock the worker
// holds for each command. At a VBlank the EE waits while kFramesAhead VBlanks are still queued (back-pressure).
// GT4_HW_GS_THREAD=0 keeps the synchronous path (diagnostic switch, not a 12.8 option).
//
// IN-446 (TASK-027 CPU survey, front T2): the stream travels through one single-producer/single-consumer byte ring
// instead of a deque of commands with a byte vector each, a mutex and a notify per command. The EE copies a GIF chunk
// once, into the ring, and takes no lock; the worker executes each record in place and then releases it. Records use
// the MTVU ring's framing (mtvu_ring.hpp: a 16-byte header, the payload padded to 16 bytes, a wrap filler before a
// record that would cross the end). Waking is conditional: the EE rings the work bell after a push, which wakes the
// worker only when it sleeps; the worker rings the progress bell only when what the EE waits for has happened (free
// space, a VBlank done, the ring empty).
enum class SinkRecord : std::uint16_t { Gif = 32, Privileged = 33, Vsync = 34, GsReset = 35, GifReset = 36, MtvuJob = 37 };

class StreamRing {
public:
  explicit StreamRing(std::size_t capacity) : capacity_(capacity), storage_(capacity) {}

  std::size_t capacity() const { return capacity_; }
  std::size_t max_payload() const { return capacity_ / 2 - mtvu::kRecordHeaderBytes; }
  std::uint64_t head() const { return head_.load(std::memory_order_seq_cst); }
  std::uint64_t tail() const { return tail_.load(std::memory_order_seq_cst); }

  // Producer only. False when the record does not fit now.
  bool try_push(const mtvu::RecordHeader &header, const std::uint8_t *payload) {
    const std::size_t total = mtvu::record_bytes(header.bytes);
    const std::uint64_t head = head_.load(std::memory_order_relaxed);
    const std::uint64_t tail = tail_.load(std::memory_order_seq_cst);  // pairs with the producer's want_ store
    const std::size_t offset = static_cast<std::size_t>(head % capacity_);
    const std::size_t filler = offset + total > capacity_ ? capacity_ - offset : 0;
    if (capacity_ - static_cast<std::size_t>(head - tail) < filler + total) return false;
    std::size_t at = offset;
    if (filler != 0) {
      mtvu::RecordHeader wrap;
      wrap.kind = static_cast<std::uint16_t>(mtvu::RecordKind::Wrap);
      wrap.bytes = static_cast<std::uint32_t>(filler - mtvu::kRecordHeaderBytes);
      std::memcpy(storage_.data() + offset, &wrap, mtvu::kRecordHeaderBytes);
      at = 0;
    }
    std::memcpy(storage_.data() + at, &header, mtvu::kRecordHeaderBytes);
    if (header.bytes != 0) std::memcpy(storage_.data() + at + mtvu::kRecordHeaderBytes, payload, header.bytes);
    head_.store(head + filler + total, std::memory_order_seq_cst);
    return true;
  }

  // Consumer only. Lends the next record (skipping wrap fillers) until release(). False when empty.
  bool try_peek(mtvu::RecordHeader &header, const std::uint8_t *&payload) {
    std::uint64_t tail = tail_.load(std::memory_order_relaxed);
    const std::uint64_t head = head_.load(std::memory_order_seq_cst);
    while (tail != head) {
      const std::size_t offset = static_cast<std::size_t>(tail % capacity_);
      std::memcpy(&header, storage_.data() + offset, mtvu::kRecordHeaderBytes);
      const std::size_t total = mtvu::record_bytes(header.bytes);
      if (header.kind == static_cast<std::uint16_t>(mtvu::RecordKind::Wrap)) {
        tail += total;
        continue;
      }
      peekedTail_ = tail + total;
      payload = storage_.data() + offset + mtvu::kRecordHeaderBytes;
      return true;
    }
    return false;
  }

  // Consumer only: frees the record lent by the last try_peek (and the fillers before it).
  void release() { tail_.store(peekedTail_, std::memory_order_seq_cst); }

private:
  std::size_t capacity_;
  std::vector<std::uint8_t> storage_;
  alignas(64) std::atomic<std::uint64_t> head_{0};
  alignas(64) std::atomic<std::uint64_t> tail_{0};
  std::uint64_t peekedTail_ = 0;  // consumer only
};

class GsWorker {
public:
  static constexpr std::size_t kFramesAhead = 2;
  // Two busy race VBlanks (about 6 MB of GIF data each) fit; a larger chunk is split into several records.
  static constexpr std::size_t kRingBytes = std::size_t{16} << 20;
  static constexpr std::uint64_t kWantNothing = 0;
  static constexpr std::uint64_t kWantEmpty = ~std::uint64_t{0};

  GsWorker() : ring_(kRingBytes) {}

  void start() {
    thread_ = std::thread([this] { run(); });
  }

  // Producer (EE thread): one record, in stream order. A GIF chunk larger than a record is split at qword boundaries
  // (the GIF parser keeps each path's state across transfers).
  void push(SinkRecord kind, std::uint8_t path, std::uint64_t value, const std::uint8_t *payload, std::size_t bytes) {
    if (kind == SinkRecord::Vsync) {
      if (queuedVsyncs_.load(std::memory_order_seq_cst) >= kFramesAhead) {
        const std::uint64_t start = __rdtsc();
        wait_for([this] { return queuedVsyncs_.load(std::memory_order_seq_cst) < kFramesAhead; }, kWantNothing);
        add(g_transport.vsync_wait_ticks, __rdtsc() - start);
        add(g_transport.vsync_waits, 1);
      }
      queuedVsyncs_.fetch_add(1, std::memory_order_seq_cst);
    }
    const std::size_t limit = ring_.max_payload() & ~std::size_t{15};
    do {
      const std::size_t part = bytes < limit ? bytes : limit;
      mtvu::RecordHeader header;
      header.kind = static_cast<std::uint16_t>(kind);
      header.path = path;
      header.bytes = static_cast<std::uint32_t>(part);
      header.job = value;
      if (!ring_.try_push(header, payload)) {
        const std::uint64_t need = mtvu::record_bytes(part) * 2;  // the record and a worst-case wrap filler
        wait_for([&] { return ring_.try_push(header, payload); }, need);
      }
      if (sleeping_.load(std::memory_order_relaxed)) add(g_transport.wake_pushes, 1);
      work_.ring();
      payload += part;
      bytes -= part;
    } while (bytes != 0);
    const std::uint64_t depth = ring_.head() - ring_.tail();
    if (depth > maxDepth_) {
      maxDepth_ = depth;
      g_transport.max_depth.store(depth, std::memory_order_relaxed);
    }
  }

  // IN-461 (CPU survey T3, direct GS intake; EE thread): VU1 job `job` at this point of the stream. The worker executes
  // the job's GIF records straight from the MTVU output ring when it reaches this record, so the EE neither copies nor
  // forwards them. The ring and its bell never change; they are stored before the first record that needs them.
  void post_mtvu_job(std::uint64_t job, mtvu::SpscByteRing &output, mtvu::Doorbell &bell) {
    if (mtvuOutput_ == nullptr) {
      mtvuOutput_ = &output;
      mtvuBell_ = &bell;
    }
    push(SinkRecord::MtvuJob, 0, job, nullptr, 0);
  }

  // Waits until every queued record has executed; the caller then runs with the backend lock held.
  std::unique_lock<std::mutex> drain() {
    const std::uint64_t start = __rdtsc();
    if (ring_.head() != ring_.tail()) wait_for([this] { return ring_.head() == ring_.tail(); }, kWantEmpty);
    std::unique_lock<std::mutex> backend(backendMutex_);
    add(g_transport.drain_wait_ticks, __rdtsc() - start);
    add(g_transport.drains, 1);
    return backend;
  }

private:
  // Producer side: sleeps on the progress bell until `ready()` holds. `want` tells the worker when to ring: the free
  // bytes needed, kWantEmpty, or kWantNothing (a VBlank done always rings). The want/snapshot/re-check/wait order
  // pairs with the worker's release/check/ring order (all sequentially consistent), so no wakeup is lost.
  // waitMutex_ keeps one waiter at a time (a window message may drain while the EE waits for space).
  template <typename Ready> void wait_for(Ready ready, std::uint64_t want) {
    std::lock_guard<std::mutex> waiting(waitMutex_);
    want_.store(want, std::memory_order_seq_cst);
    for (;;) {
      const std::uint32_t seen = progress_.snapshot();
      if (ready()) break;
      bool slept = false;
      progress_.wait_changed(seen, slept);
    }
    want_.store(kWantNothing, std::memory_order_seq_cst);
  }

  // Worker side, after a release: rings the progress bell when what the producer waits for has happened.
  void notify_progress(bool vsyncDone) {
    const std::uint64_t want = want_.load(std::memory_order_seq_cst);
    if (want == kWantNothing && !vsyncDone) return;
    const std::uint64_t used = ring_.head() - ring_.tail();
    const bool ready = vsyncDone || (want == kWantEmpty ? used == 0 : ring_.capacity() - used >= want);
    if (ready) progress_.ring();
  }

  void run() {
    sampler::name_current_thread("gs-worker");
    for (;;) {
      mtvu::RecordHeader header;
      const std::uint8_t *payload = nullptr;
      if (!ring_.try_peek(header, payload)) {
        const std::uint32_t seen = work_.snapshot();
        if (!ring_.try_peek(header, payload)) {
          const std::uint64_t start = __rdtsc();
          sleeping_.store(true, std::memory_order_relaxed);
          bool slept = false;
          work_.wait_changed(seen, slept);
          sleeping_.store(false, std::memory_order_relaxed);
          add(g_transport.idle_ticks, __rdtsc() - start);
          if (slept) add(g_transport.wakeups, 1);
          continue;
        }
      }
      const SinkRecord kind = static_cast<SinkRecord>(header.kind);
      const std::uint64_t busyStart = __rdtsc();
      if (kind == SinkRecord::MtvuJob) {
        // IN-461: the job's records, outside the backend lock while the worker waits for them.
        const std::uint64_t waited = execute_mtvu_job(header.job);
        add(g_transport.busy_ticks[0], __rdtsc() - busyStart - waited);
        add(g_transport.mtvu_wait_ticks, waited);
        ring_.release();
        notify_progress(false);
        continue;
      }
      {
        std::lock_guard<std::mutex> backendLock(backendMutex_);
        switch (kind) {
          case SinkRecord::Gif: gif_now(header.path, payload, header.bytes); break;
          case SinkRecord::Privileged: {
            std::uint32_t address = 0;
            std::memcpy(&address, payload, sizeof address);
            privileged_now(address, header.job);
            break;
          }
          case SinkRecord::Vsync: vsync_now(header.job != 0); break;
          case SinkRecord::GsReset: gs_reset_now(); break;
          case SinkRecord::GifReset: gif_reset_now(); break;
          case SinkRecord::MtvuJob: break;  // executed above, outside the lock
        }
      }
      const int slot = kind == SinkRecord::Gif ? 0 : kind == SinkRecord::Privileged ? 1 : kind == SinkRecord::Vsync ? 2 : 3;
      add(g_transport.busy_ticks[slot], __rdtsc() - busyStart);
      ring_.release();
      const bool vsyncDone = kind == SinkRecord::Vsync;
      if (vsyncDone) queuedVsyncs_.fetch_sub(1, std::memory_order_seq_cst);
      notify_progress(vsyncDone);
    }
  }

  // IN-461: executes VU1 job `job`'s GIF records from the MTVU output ring up to its JobDone, then frees them (the same
  // bytes the EE journal forwarded through gif() before; this thread is now the ring's one reader). Sleeps on the
  // ring's bell while the VU1 worker has not published the next record; the backend lock is taken per record, never
  // while sleeping. Returns the ticks spent waiting for the VU1 worker.
  std::uint64_t execute_mtvu_job(std::uint64_t job) {
    std::uint64_t waited = 0;
    for (;;) {
      mtvu::RecordHeader record;
      const std::uint8_t *bytes = nullptr;
      if (!mtvuOutput_->try_peek(record, bytes)) {
        const std::uint32_t seen = mtvuBell_->snapshot();
        if (!mtvuOutput_->try_peek(record, bytes)) {
          const std::uint64_t start = __rdtsc();
          bool slept = false;
          mtvuBell_->wait_changed(seen, slept);
          waited += __rdtsc() - start;
          if (slept) add(g_transport.mtvu_sleeps, 1);
          continue;
        }
      }
      const auto kind = static_cast<mtvu::RecordKind>(record.kind);
      if (record.job != job || (kind != mtvu::RecordKind::Gif && kind != mtvu::RecordKind::JobDone)) {
        std::fprintf(stderr, "[hw] IN-461: VU1 output record kind %u of job %llu while executing job %llu; stopping\n",
                     static_cast<unsigned>(record.kind), static_cast<unsigned long long>(record.job),
                     static_cast<unsigned long long>(job));
        std::exit(EXIT_FAILURE);
      }
      if (kind == mtvu::RecordKind::JobDone) {
        mtvuOutput_->release();
        add(g_transport.mtvu_jobs, 1);
        return waited;
      }
      {
        std::lock_guard<std::mutex> backendLock(backendMutex_);
        gif_now(record.path, bytes, record.bytes);
      }
      add(g_transport.mtvu_records, 1);
      mtvuOutput_->release();
    }
  }

  StreamRing ring_;
  mtvu::SpscByteRing *mtvuOutput_ = nullptr;  // IN-461: the VU1 worker's output ring (set by the EE, see post_mtvu_job)
  mtvu::Doorbell *mtvuBell_ = nullptr;
  mtvu::Doorbell work_;      // EE -> worker: records published (wakes the worker only when it sleeps)
  mtvu::Doorbell progress_;  // worker -> EE: space freed, a VBlank done, the ring empty (only when wanted)
  std::atomic<std::uint64_t> want_{kWantNothing};
  std::atomic<std::size_t> queuedVsyncs_{0};
  std::atomic<bool> sleeping_{false};  // the worker waits for work (TASK-027 CPU survey: pushes that wake it)
  std::uint64_t maxDepth_ = 0;         // producer only: deepest ring use, in bytes
  std::thread thread_;
  std::mutex backendMutex_;
  std::mutex waitMutex_;
};

GsWorker *g_worker = nullptr;  // null: synchronous (GT4_HW_GS_THREAD=0)

void start_gs_worker() {
  const char *thread = std::getenv("GT4_HW_GS_THREAD");
  if (!(thread && std::string(thread) == "0")) {
    g_worker = new GsWorker;  // never destroyed, like the backend
    g_worker->start();
    std::fprintf(stderr, "[hw] GS stream on its own worker thread (IN-363; GT4_HW_GS_THREAD=0 for the EE thread)\n");
  }
}

void gif(int path, const std::uint8_t *data, std::uint32_t qwc) {
  const std::size_t bytes = static_cast<std::size_t>(qwc) * 16;
  if (!g_worker) {
    gif_now(path, data, bytes);
    return;
  }
  const std::uint64_t start = __rdtsc();
  g_worker->push(SinkRecord::Gif, static_cast<std::uint8_t>(path), 0, data, bytes);
  const std::uint64_t ticks = __rdtsc() - start;
  add(g_transport.gif_ticks, ticks);
  add(g_transport.copy_ticks, ticks);  // the copy into the ring is the whole hook now
  add(g_transport.gif_commands, 1);
  add(g_transport.gif_bytes, bytes);
}

// IN-461 (direct GS intake): the VU1 job's place in the stream. Needs the worker thread: on the EE thread the job's
// output would be awaited before the job is even sent to the VU1 worker.
void mtvu_job(std::uint64_t job, mtvu::SpscByteRing &output, mtvu::Doorbell &bell) {
  if (!g_worker) {
    std::fprintf(stderr, "[hw] GT4_MTVU_DIRECT=1 needs the GS worker thread (GT4_HW_GS_THREAD is 0); stopping\n");
    std::exit(EXIT_FAILURE);
  }
  g_worker->post_mtvu_job(job, output, bell);
}

void privileged(std::uint32_t address, std::uint64_t value) {
  if (!g_worker) {
    privileged_now(address, value);
    return;
  }
  const std::uint64_t start = __rdtsc();
  std::uint8_t payload[sizeof address];
  std::memcpy(payload, &address, sizeof address);
  g_worker->push(SinkRecord::Privileged, 0, value, payload, sizeof payload);
  add(g_transport.privileged_ticks, __rdtsc() - start);
  add(g_transport.privileged_commands, 1);
}

void read_fifo(std::uint8_t *data, std::uint32_t qwords) {
  if (!g_worker) {
    read_fifo_now(data, qwords);
    return;
  }
  const std::uint64_t start = __rdtsc();
  {
    const std::unique_lock<std::mutex> lock = g_worker->drain();  // the read observes everything queued before it
    read_fifo_now(data, qwords);
  }
  add(g_transport.read_fifo_ticks, __rdtsc() - start);
  add(g_transport.read_fifos, 1);
}

void vsync(bool odd_field) {
  if (!g_worker) {
    vsync_now(odd_field);
    return;
  }
  g_worker->push(SinkRecord::Vsync, 0, odd_field ? 1 : 0, nullptr, 0);
  add(g_transport.vsync_commands, 1);
}

void gs_reset() {
  if (!g_worker) {
    gs_reset_now();
    return;
  }
  g_worker->push(SinkRecord::GsReset, 0, 0, nullptr, 0);
}

void gif_reset() {
  if (!g_worker) {
    gif_reset_now();
    return;
  }
  g_worker->push(SinkRecord::GifReset, 0, 0, nullptr, 0);
}

bool attach_window(std::uint64_t window, std::uint32_t width, std::uint32_t height) {
  std::unique_lock<std::mutex> lock;
  if (g_worker) lock = g_worker->drain();
  std::string error;
  if (!backend().attach_window(reinterpret_cast<void *>(window), error)) {
    std::fprintf(stderr, "[hw] window presentation refused: %s\n", error.c_str());
    return false;
  }
  backend().resize_window(width, height);
  std::fprintf(stderr, "[hw] window output through the HWR swapchain\n");
  return true;
}

// TASK-080: the race view's display-aspect fill (protocol 1.3 CONTROL display_aspect in pcsx2 mode). Called on the EE
// thread only when the request changes; the backend reads it atomically at its next present, so no drain is needed.
std::uint64_t g_display_aspect_changes = 0;
void display_aspect(bool fill, std::uint32_t ratio_millionths) {
  backend().set_display_aspect(fill, ratio_millionths);
  ++g_display_aspect_changes;
  if (!fill) {
    std::fprintf(stderr, "[hw] presentation: 16:9 pillarbox\n");
  } else if (ratio_millionths == 0) {
    std::fprintf(stderr, "[hw] presentation: fill the whole window\n");
  } else {
    std::fprintf(stderr, "[hw] presentation: fill at ratio %.4f\n", ratio_millionths / 1e6);
  }
}

void resize_window(std::uint32_t width, std::uint32_t height) {
  std::unique_lock<std::mutex> lock;
  if (g_worker) lock = g_worker->drain();
  backend().resize_window(width, height);
}

RenderCounters stats_counters() { return g_backend ? g_backend->render_counters() : RenderCounters{}; }

void finish(std::FILE *output) {
  if (!g_backend) return;
  sampler::finish(output);
  std::unique_lock<std::mutex> lock;
  if (g_worker) lock = g_worker->drain();
  g_backend->wait_idle();
  const Stats stats = g_backend->stats();
  std::fprintf(output,
               "[hw] session: vsyncs=%llu frames=%llu presents=%llu black_presents=%llu gif_bytes=%llu "
               "privileged=%llu unmirrored_privileged=%llu faults=%llu\n",
               static_cast<unsigned long long>(g_vsyncs), static_cast<unsigned long long>(stats.frames),
               static_cast<unsigned long long>(stats.presents), static_cast<unsigned long long>(stats.black_presents),
               static_cast<unsigned long long>(stats.gif_bytes),
               static_cast<unsigned long long>(stats.privileged_writes),
               static_cast<unsigned long long>(g_unmirrored_privileged), static_cast<unsigned long long>(stats.faults));
  std::fprintf(output,
               "[hw] m6: flushes=%llu held_presents=%llu dropped_frames=%llu auxiliary_frames=%llu translate_us=%.1f "
               "execute_us=%.1f compose_us=%.1f upload_us=%.1f present_us=%.1f\n",
               static_cast<unsigned long long>(stats.flushes),
               static_cast<unsigned long long>(stats.held_presents),
               static_cast<unsigned long long>(stats.dropped_frames),
               static_cast<unsigned long long>(stats.auxiliary_frames), stats.translate_us, stats.execute_us,
               stats.compose_us, stats.upload_us, stats.present_us);
  // TASK-080: fill requests received and the rectangle of the last present (window only).
  std::fprintf(output, "[hw] presentation: aspect_changes=%llu last_rect=%u,%u %ux%u fill=%u\n",
               static_cast<unsigned long long>(g_display_aspect_changes), stats.present_left, stats.present_top,
               stats.present_width, stats.present_height, stats.present_fill);
  const RenderCounters counters = stats_counters();
  std::fprintf(output,
               "[hw] counters: batches=%llu primitives=%llu primitives_skipped_texture=%llu batches_empty=%llu "
               "textures=%llu texels=%llu gpu_draws=%llu writeback_pixels=%llu flat_deindexed=%llu sprites=%llu\n",
               static_cast<unsigned long long>(counters.batches),
               static_cast<unsigned long long>(counters.primitives),
               static_cast<unsigned long long>(counters.primitives_skipped_texture),
               static_cast<unsigned long long>(counters.batches_empty),
               static_cast<unsigned long long>(counters.textures),
               static_cast<unsigned long long>(counters.texels),
               static_cast<unsigned long long>(counters.gpu_draws),
               static_cast<unsigned long long>(counters.writeback_pixels),
               static_cast<unsigned long long>(counters.flat_deindexed),
               static_cast<unsigned long long>(counters.sprites));
  {
    const RenderCounters &video = counters;
    std::fprintf(output, "[hw] video: vblanks_480i=%llu vblanks_480p=%llu (SMODE2.INT; menus are 480i, races 480p with "
                         "GT4_FORCE_480P=1)\n",
                 static_cast<unsigned long long>(video.vblanks_interlaced),
                 static_cast<unsigned long long>(video.vblanks_progressive));
  }
  std::fprintf(output,
               "[hw] output: presentation_frames=%llu blank_frames=%llu deinterlaced_frames=%llu "
               "interlace_offset_frames=%llu merge_alpha_from_texel=%llu writeback_depth_words=%llu "
               "fifo_overruns=%llu\n",
               static_cast<unsigned long long>(counters.presentation_frames),
               static_cast<unsigned long long>(counters.blank_frames),
               static_cast<unsigned long long>(counters.deinterlaced_frames),
               static_cast<unsigned long long>(counters.interlace_offset_frames),
               static_cast<unsigned long long>(counters.merge_alpha_from_texel),
               static_cast<unsigned long long>(counters.writeback_depth_words),
               static_cast<unsigned long long>(counters.fifo_overruns));
  std::fprintf(output, "[hw] tone: strip_pages=%llu strip_batches=%llu verify_mismatch_bytes=%llu (IN-383)\n",
               static_cast<unsigned long long>(counters.tone_strip_pages),
               static_cast<unsigned long long>(counters.tone_strip_batches),
               static_cast<unsigned long long>(counters.tone_verify_mismatch_bytes));
  if (counters.scale > 1) {
    std::fprintf(output,
                 "[hw] scale: x%u draws=%llu passes=%llu refreshes=%llu refresh_pixels=%llu composes=%llu "
                 "circuits_from_slots=%llu circuits_from_glm=%llu circuits_from_shadows=%llu shadow_saves=%llu "
                 "tone_runs=%llu tone_carries=%llu\n",
                 counters.scale, static_cast<unsigned long long>(counters.scaled_draws),
                 static_cast<unsigned long long>(counters.scaled_passes),
                 static_cast<unsigned long long>(counters.scaled_refreshes),
                 static_cast<unsigned long long>(counters.scaled_refresh_pixels),
                 static_cast<unsigned long long>(counters.scaled_composes),
                 static_cast<unsigned long long>(counters.scaled_circuits_from_slots),
                 static_cast<unsigned long long>(counters.scaled_circuits_from_glm),
                 static_cast<unsigned long long>(counters.scaled_circuits_from_shadows),
                 static_cast<unsigned long long>(counters.scaled_shadow_saves),
                 static_cast<unsigned long long>(counters.tone_runs),
                 static_cast<unsigned long long>(counters.tone_carries));
  }
  if (g_dump_every != 0) {
    std::fprintf(output, "[hw] dumps: written=%llu without_image=%llu every=%u dir=%s\n",
                 static_cast<unsigned long long>(g_dumps), static_cast<unsigned long long>(g_dumps_without_image),
                 g_dump_every, g_dump_dir.c_str());
  }
  std::fflush(output);
}

}  // namespace
}  // namespace gt4::hw

namespace gt4::gs_stream {

const InProcessSink &hw_in_process_sink() {
  static const InProcessSink sink = [] {
    InProcessSink s;
    s.start = &gt4::hw::start_backend;
    s.gif = &gt4::hw::gif;
    s.privileged = &gt4::hw::privileged;
    s.read_fifo = &gt4::hw::read_fifo;
    s.vsync = &gt4::hw::vsync;
    s.gs_reset = &gt4::hw::gs_reset;
    s.gif_reset = &gt4::hw::gif_reset;
    s.attach_window = &gt4::hw::attach_window;
    s.resize_window = &gt4::hw::resize_window;
    s.display_aspect = &gt4::hw::display_aspect;
    s.finish = &gt4::hw::finish;
    s.mtvu_job = &gt4::hw::mtvu_job;
    return s;
  }();
  return sink;
}

}  // namespace gt4::gs_stream
