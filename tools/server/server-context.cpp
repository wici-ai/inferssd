
#include "server-context.h"
#include "server-expert-guard.h"
#include "server-sampler-struct-top1.h"
#include "server-k3-protocol.h"
#include "src/llama-kimi-runtime.h"
#include "server-chat.h"
#include "server-common.h"
#include "server-http.h"
#include "server-task.h"
#include "server-queue.h"

#include "build-info.h"
#include "common.h"
#include "llama.h"
#include "log.h"
#include "sampling.h"
#include "speculative.h"
#include "mtmd.h"
#include "mtmd-helper.h"

#include <algorithm>
#include <chrono>
#include <cstddef>
#include <cinttypes>
#include <deque>
#include <cstdio>
#include <cstdlib>
#include <exception>
#include <fstream>
#include <iterator>
#include <memory>
#include <filesystem>
#include <mutex>
#include <unordered_map>
#include <utility>

#if defined(__linux__)
#include <sys/resource.h>
#endif

#if defined(__GNUC__) || defined(__clang__)
#if defined(LLAMA_SERVER_CUDA_MOE)
extern "C" void ggml_cuda_moe_ram_tier_request_begin(uint64_t request_id) __attribute__((weak));
extern "C" void ggml_cuda_moe_stream_batch_phase_report(const char * label) __attribute__((weak));
extern "C" void ggml_cuda_moe_prefill_request_phase(int active) __attribute__((weak));
#endif
extern "C" void ggml_cpu_kimi_a2_request_phase(int active) __attribute__((weak));
extern "C" bool llama_moe_prefill_phase_workspace(
    llama_context * ctx, int active) __attribute__((weak));
extern "C" bool llama_moe_prefill_phase_workspace_sized(
    llama_context * ctx, int active, uint32_t requested_tokens) __attribute__((weak));
extern "C" bool llama_moe_prefill_phase_workspace_sized_ex(
    llama_context * ctx, int active, uint32_t prompt_tokens, uint32_t prefill_tokens) __attribute__((weak));
#endif

// fix problem with std::min and std::max
#if defined(_WIN32)
#define WIN32_LEAN_AND_MEAN
#ifndef NOMINMAX
#   define NOMINMAX
#endif
#include <windows.h>
#endif

using json = nlohmann::ordered_json;

constexpr int HTTP_POLLING_SECONDS = 1;

static bool server_prompt_last_token_single_enabled() {
    static const bool enabled = []() {
        const char * env = std::getenv("LLAMA_SERVER_PROMPT_LAST_TOKEN_SINGLE");
        return env && env[0] && env[0] != '0';
    }();
    return enabled;
}

static bool server_prefill_new_tokens_enabled() {
    static const bool enabled = []() {
        const char * env = std::getenv("LLAMA_SERVER_PREFILL_NEW_TOKENS");
        return !env || std::strcmp(env, "0") != 0;
    }();
    return enabled;
}

// The number of tokens of the shared prompt prefix the chat template reported ("shared_prefix_chars", see
// oaicompat_chat_params_parse), if that prefix tokenizes to a prefix of the prompt's tokens; 0 otherwise.
static int64_t server_shared_prefix_tokens(const llama_vocab * vocab, const json & data, const llama_tokens & tokens) {
    const size_t n_chars = json_value(data, "shared_prefix_chars", (size_t) 0);
    const std::string prompt = json_value(data, "prompt", std::string());
    if (n_chars == 0 || n_chars >= prompt.size()) {
        return 0;
    }

    json prefix = json::object();
    prefix["prompt"]           = prompt.substr(0, n_chars);
    prefix["chat_input_spans"] = json::array();
    for (const auto & span : data.at("chat_input_spans")) {
        const int64_t offset = span.at(0).get<int64_t>();
        const int64_t length = span.at(1).get<int64_t>();
        if (offset < (int64_t) n_chars) {
            prefix["chat_input_spans"].push_back({offset, std::min<int64_t>(length, (int64_t) n_chars - offset)});
        }
    }

    try {
        const llama_tokens prefix_tokens = tokenize_chat_prompt(vocab, prefix);
        if (prefix_tokens.size() < tokens.size() && std::equal(prefix_tokens.begin(), prefix_tokens.end(), tokens.begin())) {
            return (int64_t) prefix_tokens.size();
        }
    } catch (const std::exception &) {
        // not a token boundary of the prompt
    }

    return 0;
}

static bool server_raw_io_log_enabled() {
    static const bool enabled = []() {
        const char * env = std::getenv("LLAMA_RAW_IO_LOG");
        return env && env[0] && env[0] != '0';
    }();
    return enabled;
}

static bool server_kimi_dense_phase_gate_enabled() {
    static const bool enabled = []() {
        for (const char * name : { "GGML_KIMI_DENSE_PREFETCH_LAYERS", "GGML_KIMI_KDA_GPU_LAYERS", "GGML_KIMI_CPU_SINK" }) {
            const char * env = std::getenv(name);
            if (env && env[0] && std::strcmp(env, "0") != 0) {
                return true;
            }
        }
        return false;
    }();
    return enabled;
}

static bool server_moe_phase01_telemetry_enabled() {
    const char * phase0 = std::getenv("GGML_MOE_PREFILL_PHASE0");
    const char * phase1 = std::getenv("GGML_MOE_PREFILL_PHASE1");
    const char * a2 = std::getenv("GGML_MOE_A2_CPU_GROUPED_PREFILL");
    return (phase0 && phase0[0] && phase0[0] != '0') ||
        (phase1 && phase1[0] && phase1[0] != '0') ||
        (a2 && a2[0] && a2[0] != '0');
}

struct server_moe_memory_events {
    uint64_t monotonic_ns = 0;
    uint64_t low = 0;
    uint64_t high = 0;
    uint64_t max = 0;
    uint64_t oom = 0;
    uint64_t oom_kill = 0;
    uint64_t oom_group_kill = 0;
    uint64_t current = 0;
    uint64_t anon = 0;
    uint64_t file = 0;
    uint64_t kernel = 0;
    uint64_t shmem = 0;
    uint64_t file_mapped = 0;
    uint64_t file_dirty = 0;
    uint64_t file_writeback = 0;
    uint64_t pgfault = 0;
    uint64_t pgmajfault = 0;
    uint64_t pgscan = 0;
    uint64_t pgsteal = 0;
    uint64_t workingset_refault_file = 0;
    uint64_t workingset_activate_file = 0;
    uint64_t minor_faults = 0;
    uint64_t major_faults = 0;
    uint64_t cpu_usage_usec = 0;
    uint64_t cpu_user_usec = 0;
    uint64_t cpu_system_usec = 0;
    uint64_t cpu_nr_throttled = 0;
    uint64_t cpu_throttled_usec = 0;
    uint64_t io_read_bytes = 0;
    uint64_t io_write_bytes = 0;
};

struct server_moe_memory_event_task_state {
    server_moe_memory_events begin;
    server_moe_memory_events last;
};

static bool server_moe_phase_memory_events_enabled() {
    const char * env = std::getenv("GGML_MOE_PHASE_MEMORY_EVENTS");
    return env && env[0] && env[0] != '0';
}

static const std::filesystem::path & server_moe_cgroup_path() {
    static const std::filesystem::path path = []() {
#if defined(__linux__)
        std::ifstream cgroup("/proc/self/cgroup");
        std::string line;
        while (std::getline(cgroup, line)) {
            if (line.rfind("0::", 0) != 0) {
                continue;
            }
            std::string relative = line.substr(3);
            while (!relative.empty() && relative.front() == '/') {
                relative.erase(relative.begin());
            }
            return std::filesystem::path("/sys/fs/cgroup") / relative;
        }
#endif
        return std::filesystem::path();
    }();
    return path;
}

static bool server_moe_read_memory_events(server_moe_memory_events & events) {
#if defined(__linux__)
    events.monotonic_ns = (uint64_t) std::chrono::duration_cast<std::chrono::nanoseconds>(
        std::chrono::steady_clock::now().time_since_epoch()).count();
    struct rusage usage = {};
    if (getrusage(RUSAGE_SELF, &usage) == 0) {
        events.minor_faults = (uint64_t) usage.ru_minflt;
        events.major_faults = (uint64_t) usage.ru_majflt;
    }

    const std::filesystem::path & cgroup_path = server_moe_cgroup_path();
    if (cgroup_path.empty()) {
        return false;
    }

    std::ifstream input(cgroup_path / "memory.events");
    std::string key;
    uint64_t value = 0;
    bool saw_max = false;
    while (input >> key >> value) {
        if (key == "low") {
            events.low = value;
        } else if (key == "high") {
            events.high = value;
        } else if (key == "max") {
            events.max = value;
            saw_max = true;
        } else if (key == "oom") {
            events.oom = value;
        } else if (key == "oom_kill") {
            events.oom_kill = value;
        } else if (key == "oom_group_kill") {
            events.oom_group_kill = value;
        }
    }

    std::ifstream current_input(cgroup_path / "memory.current");
    current_input >> events.current;
    std::ifstream stat_input(cgroup_path / "memory.stat");
    while (stat_input >> key >> value) {
        if (key == "anon") {
            events.anon = value;
        } else if (key == "file") {
            events.file = value;
        } else if (key == "kernel") {
            events.kernel = value;
        } else if (key == "shmem") {
            events.shmem = value;
        } else if (key == "file_mapped") {
            events.file_mapped = value;
        } else if (key == "file_dirty") {
            events.file_dirty = value;
        } else if (key == "file_writeback") {
            events.file_writeback = value;
        } else if (key == "pgfault") {
            events.pgfault = value;
        } else if (key == "pgmajfault") {
            events.pgmajfault = value;
        } else if (key == "pgscan") {
            events.pgscan = value;
        } else if (key == "pgsteal") {
            events.pgsteal = value;
        } else if (key == "workingset_refault_file") {
            events.workingset_refault_file = value;
        } else if (key == "workingset_activate_file") {
            events.workingset_activate_file = value;
        }
    }

    std::ifstream cpu_input(cgroup_path / "cpu.stat");
    while (cpu_input >> key >> value) {
        if (key == "usage_usec") {
            events.cpu_usage_usec = value;
        } else if (key == "user_usec") {
            events.cpu_user_usec = value;
        } else if (key == "system_usec") {
            events.cpu_system_usec = value;
        } else if (key == "nr_throttled") {
            events.cpu_nr_throttled = value;
        } else if (key == "throttled_usec") {
            events.cpu_throttled_usec = value;
        }
    }

    std::ifstream io_input("/proc/self/io");
    while (io_input >> key >> value) {
        if (key == "read_bytes:") {
            events.io_read_bytes = value;
        } else if (key == "write_bytes:") {
            events.io_write_bytes = value;
        }
    }
    return saw_max;
#else
    (void) events;
    return false;
#endif
}

static uint64_t server_moe_memory_event_delta(uint64_t current, uint64_t previous) {
    return current >= previous ? current - previous : 0;
}

static void server_moe_phase_memory_events_report(const char * label, int64_t task_id) {
    if (!server_moe_phase_memory_events_enabled()) {
        return;
    }

    server_moe_memory_events current;
    if (!server_moe_read_memory_events(current)) {
        SRV_WRN("[moe_phase_memory_events] label=%s task=%lld status=unavailable\n",
                label ? label : "unknown", (long long) task_id);
        return;
    }

    static std::mutex mutex;
    static std::unordered_map<int64_t, server_moe_memory_event_task_state> tasks;
    std::lock_guard<std::mutex> lock(mutex);
    auto it = tasks.find(task_id);
    if (!label || std::strcmp(label, "request_begin") == 0 || it == tasks.end()) {
        it = tasks.insert_or_assign(task_id, server_moe_memory_event_task_state{current, current}).first;
    }
    const server_moe_memory_events & begin = it->second.begin;
    const server_moe_memory_events & last = it->second.last;

    SRV_INF("[moe_phase_memory_events] label=%s task=%lld "
            "monotonic_ns=%llu minor_faults=%llu major_faults=%llu "
            "max=%llu oom=%llu oom_kill=%llu oom_group_kill=%llu "
            "current=%llu anon=%llu file=%llu kernel=%llu shmem=%llu "
            "file_mapped=%llu file_dirty=%llu file_writeback=%llu "
            "pgfault=%llu pgmajfault=%llu pgscan=%llu pgsteal=%llu "
            "workingset_refault_file=%llu workingset_activate_file=%llu "
            "delta_phase_minor_faults=%llu delta_phase_major_faults=%llu "
            "delta_phase_pgfault=%llu delta_phase_pgmajfault=%llu "
            "delta_phase_pgscan=%llu delta_phase_pgsteal=%llu "
            "delta_phase_workingset_refault_file=%llu "
            "delta_phase_max=%llu delta_phase_oom=%llu delta_phase_oom_kill=%llu "
            "delta_phase_oom_group_kill=%llu delta_total_max=%llu delta_total_oom=%llu "
            "delta_total_oom_kill=%llu delta_total_oom_group_kill=%llu\n",
            label ? label : "unknown",
            (long long) task_id,
            (unsigned long long) current.monotonic_ns,
            (unsigned long long) current.minor_faults,
            (unsigned long long) current.major_faults,
            (unsigned long long) current.max,
            (unsigned long long) current.oom,
            (unsigned long long) current.oom_kill,
            (unsigned long long) current.oom_group_kill,
            (unsigned long long) current.current,
            (unsigned long long) current.anon,
            (unsigned long long) current.file,
            (unsigned long long) current.kernel,
            (unsigned long long) current.shmem,
            (unsigned long long) current.file_mapped,
            (unsigned long long) current.file_dirty,
            (unsigned long long) current.file_writeback,
            (unsigned long long) current.pgfault,
            (unsigned long long) current.pgmajfault,
            (unsigned long long) current.pgscan,
            (unsigned long long) current.pgsteal,
            (unsigned long long) current.workingset_refault_file,
            (unsigned long long) current.workingset_activate_file,
            (unsigned long long) server_moe_memory_event_delta(current.minor_faults, last.minor_faults),
            (unsigned long long) server_moe_memory_event_delta(current.major_faults, last.major_faults),
            (unsigned long long) server_moe_memory_event_delta(current.pgfault, last.pgfault),
            (unsigned long long) server_moe_memory_event_delta(current.pgmajfault, last.pgmajfault),
            (unsigned long long) server_moe_memory_event_delta(current.pgscan, last.pgscan),
            (unsigned long long) server_moe_memory_event_delta(current.pgsteal, last.pgsteal),
            (unsigned long long) server_moe_memory_event_delta(
                current.workingset_refault_file, last.workingset_refault_file),
            (unsigned long long) server_moe_memory_event_delta(current.max, last.max),
            (unsigned long long) server_moe_memory_event_delta(current.oom, last.oom),
            (unsigned long long) server_moe_memory_event_delta(current.oom_kill, last.oom_kill),
            (unsigned long long) server_moe_memory_event_delta(current.oom_group_kill, last.oom_group_kill),
            (unsigned long long) server_moe_memory_event_delta(current.max, begin.max),
            (unsigned long long) server_moe_memory_event_delta(current.oom, begin.oom),
            (unsigned long long) server_moe_memory_event_delta(current.oom_kill, begin.oom_kill),
            (unsigned long long) server_moe_memory_event_delta(current.oom_group_kill, begin.oom_group_kill));

    SRV_INF("[moe_phase_resource] label=%s task=%lld monotonic_ns=%llu "
            "cpu_usage_usec=%llu cpu_user_usec=%llu cpu_system_usec=%llu "
            "cpu_nr_throttled=%llu cpu_throttled_usec=%llu "
            "io_read_bytes=%llu io_write_bytes=%llu "
            "delta_phase_cpu_usage_usec=%llu delta_phase_cpu_user_usec=%llu "
            "delta_phase_cpu_system_usec=%llu delta_phase_cpu_nr_throttled=%llu "
            "delta_phase_cpu_throttled_usec=%llu delta_phase_io_read_bytes=%llu "
            "delta_phase_io_write_bytes=%llu\n",
            label ? label : "unknown",
            (long long) task_id,
            (unsigned long long) current.monotonic_ns,
            (unsigned long long) current.cpu_usage_usec,
            (unsigned long long) current.cpu_user_usec,
            (unsigned long long) current.cpu_system_usec,
            (unsigned long long) current.cpu_nr_throttled,
            (unsigned long long) current.cpu_throttled_usec,
            (unsigned long long) current.io_read_bytes,
            (unsigned long long) current.io_write_bytes,
            (unsigned long long) server_moe_memory_event_delta(current.cpu_usage_usec, last.cpu_usage_usec),
            (unsigned long long) server_moe_memory_event_delta(current.cpu_user_usec, last.cpu_user_usec),
            (unsigned long long) server_moe_memory_event_delta(current.cpu_system_usec, last.cpu_system_usec),
            (unsigned long long) server_moe_memory_event_delta(current.cpu_nr_throttled, last.cpu_nr_throttled),
            (unsigned long long) server_moe_memory_event_delta(current.cpu_throttled_usec, last.cpu_throttled_usec),
            (unsigned long long) server_moe_memory_event_delta(current.io_read_bytes, last.io_read_bytes),
            (unsigned long long) server_moe_memory_event_delta(current.io_write_bytes, last.io_write_bytes));

    if (label && std::strcmp(label, "request_end") == 0) {
        tasks.erase(it);
    } else {
        it->second.last = current;
    }
}

static void server_moe_phase_smaps_snapshot(const char * label, int64_t task_id) {
#if defined(__linux__)
    const char * directory = std::getenv("GGML_MOE_PHASE_SMAPS_DIR");
    if (!directory || !directory[0] || !label || !label[0]) {
        return;
    }

    char stem[128];
    const int written = std::snprintf(
        stem, sizeof(stem), "task-%lld-%s", (long long) task_id, label);
    if (written < 0 || (size_t) written >= sizeof(stem)) {
        return;
    }
    const std::filesystem::path base = std::filesystem::path(directory) / stem;
    for (const char * source : { "/proc/self/maps", "/proc/self/smaps" }) {
        std::ifstream input(source, std::ios::binary);
        std::ofstream output(base.string() + (source[11] == 's' ? ".smaps" : ".maps"),
            std::ios::binary | std::ios::trunc);
        if (input && output) {
            output << input.rdbuf();
        }
    }
#else
    (void) label;
    (void) task_id;
#endif
}

static bool server_moe_workspace_transition(
        llama_context * ctx,
        const char * label,
        int64_t task_id,
        uint32_t prompt_tokens,
        uint32_t prefill_tokens) {
#if defined(__GNUC__) || defined(__clang__)
    const bool phase01_telemetry = server_moe_phase01_telemetry_enabled();
    const bool phase_memory_events = server_moe_phase_memory_events_enabled();
    const bool dense_phase_gate = server_kimi_dense_phase_gate_enabled();
    const char * elastic_value = std::getenv("GGML_KIMI_CPU_SINK_VRAM_ELASTIC");
    const bool elastic_lifecycle = elastic_value && !std::strcmp(elastic_value, "1");
    const char * prompt_pack_source_value =
        std::getenv("GGML_SCHED_MOE_COPY_EXPERT_PACK_SOURCE");
    const bool prompt_pack_source_lifecycle = prompt_pack_source_value &&
        prompt_pack_source_value[0] && std::strcmp(prompt_pack_source_value, "0") != 0;
    // Memory lifecycle is a correctness transition, not telemetry.
    if ((phase01_telemetry || phase_memory_events || dense_phase_gate || elastic_lifecycle ||
            prompt_pack_source_lifecycle) &&
            (llama_moe_prefill_phase_workspace_sized_ex ||
             llama_moe_prefill_phase_workspace_sized || llama_moe_prefill_phase_workspace) && ctx) {
        bool transition_ok = true;
        if (label && std::strcmp(label, "request_begin") == 0) {
            transition_ok = llama_moe_prefill_phase_workspace_sized_ex ?
                llama_moe_prefill_phase_workspace_sized_ex(ctx, 1, prompt_tokens, prefill_tokens) :
                llama_moe_prefill_phase_workspace_sized ?
                llama_moe_prefill_phase_workspace_sized(ctx, 1, prompt_tokens) :
                llama_moe_prefill_phase_workspace(ctx, 1);
        } else if (label &&
                (std::strcmp(label, "prefill_done") == 0 ||
                 std::strcmp(label, "request_end") == 0)) {
            transition_ok = llama_moe_prefill_phase_workspace_sized_ex ?
                llama_moe_prefill_phase_workspace_sized_ex(ctx, 0, 0, 0) :
                llama_moe_prefill_phase_workspace_sized ?
                llama_moe_prefill_phase_workspace_sized(ctx, 0, 0) :
                llama_moe_prefill_phase_workspace(ctx, 0);
        }
        if (!transition_ok) {
            SRV_WRN(
                "[moe_prefill_phase_workspace] label=%s task=%lld transition=failed\n",
                label ? label : "unknown", (long long) task_id);
            return false;
        }
    }
#else
    (void) ctx;
    (void) label;
    (void) task_id;
    (void) prompt_tokens;
    (void) prefill_tokens;
#endif
    return true;
}

static bool server_moe_phase_report(
        llama_context * ctx,
        const char * label,
        int64_t task_id,
        uint32_t prompt_tokens = 0,
        bool transition_workspace = true) {
#if defined(__GNUC__) || defined(__clang__)
    const bool phase01_telemetry = server_moe_phase01_telemetry_enabled();
    const bool phase_memory_events = server_moe_phase_memory_events_enabled();
    const bool dense_phase_gate = server_kimi_dense_phase_gate_enabled();
    if (transition_workspace &&
            !server_moe_workspace_transition(ctx, label, task_id, prompt_tokens, prompt_tokens)) {
        return false;
    }
    if (!phase01_telemetry && !phase_memory_events && !dense_phase_gate) {
        return true;
    }
    server_moe_phase_memory_events_report(label, task_id);
    server_moe_phase_smaps_snapshot(label, task_id);
    if (!phase01_telemetry && !dense_phase_gate) {
        return true;
    }
    if (phase01_telemetry && ggml_cpu_kimi_a2_request_phase) {
        if (label && std::strcmp(label, "request_begin") == 0) {
            ggml_cpu_kimi_a2_request_phase(1);
        } else if (label &&
                (std::strcmp(label, "prefill_done") == 0 ||
                 std::strcmp(label, "request_end") == 0)) {
            ggml_cpu_kimi_a2_request_phase(0);
        }
    }
#if defined(LLAMA_SERVER_CUDA_MOE)
    if (phase01_telemetry && ggml_cuda_moe_prefill_request_phase) {
        if (label && std::strcmp(label, "request_begin") == 0) {
            ggml_cuda_moe_prefill_request_phase(1);
        } else if (label &&
                (std::strcmp(label, "prefill_done") == 0 ||
                 std::strcmp(label, "request_end") == 0)) {
            ggml_cuda_moe_prefill_request_phase(0);
        }
    }
#endif
    if (!phase01_telemetry) {
        return true;
    }
#if defined(LLAMA_SERVER_CUDA_MOE)
    if (!ggml_cuda_moe_stream_batch_phase_report) {
        return true;
    }
    char scoped_label[96];
    std::snprintf(scoped_label, sizeof(scoped_label), "%s_task_%lld",
        label ? label : "unknown", (long long)task_id);
    ggml_cuda_moe_stream_batch_phase_report(scoped_label);
#endif
#else
    (void) ctx;
    (void) label;
    (void) task_id;
#endif
    return true;
}


static server_prompt_checkpoint server_get_checkpoint(llama_context * ctx, int id, int64_t n_tokens, llama_pos pos_min = -1, llama_pos pos_max = -1) {
    if (pos_min == -1) {
        pos_min = llama_memory_seq_pos_min(llama_get_memory(ctx), id);
    }
    if (pos_max == -1) {
        pos_max = llama_memory_seq_pos_max(llama_get_memory(ctx), id);
    }

    const size_t checkpoint_size = llama_state_seq_get_size_ext(ctx, id, LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY);

    auto cur = server_prompt_checkpoint {
        /*.pos_min  = */ pos_min,
        /*.pos_max  = */ pos_max,
        /*.n_tokens = */ n_tokens,
        /*.data     = */ std::vector<uint8_t>(checkpoint_size),
    };

    const size_t n = llama_state_seq_get_data_ext(ctx, cur.data.data(), checkpoint_size, id, LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY);
    if (n != checkpoint_size) {
        GGML_ABORT("checkpoint size mismatch: expected %zu, got %zu\n", checkpoint_size, n);
    }

    return cur;
}

// The partial state of the sequence after its first n_tokens tokens, taken after the batch that went past them by a
// memory that can save an earlier state (llama_state_seq_at_align). It holds the positions from pos_min to the one
// before n_tokens: a memory that cannot be rolled back resumes exactly after that position (pos_min = pos_max), a
// sliding-window cache holds the window that position attends to and is truncated after loading like an ordinary
// checkpoint.
static server_prompt_checkpoint server_get_checkpoint_at(llama_context * ctx, int id, int64_t n_tokens, llama_pos pos_min) {
    const size_t checkpoint_size = llama_state_seq_get_size_at(ctx, id, LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY, n_tokens);

    auto cur = server_prompt_checkpoint {
        /*.pos_min  = */ pos_min,
        /*.pos_max  = */ (llama_pos) n_tokens - 1,
        /*.n_tokens = */ n_tokens,
        /*.data     = */ std::vector<uint8_t>(checkpoint_size),
    };

    const size_t n = llama_state_seq_get_data_at(ctx, cur.data.data(), checkpoint_size, id, LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY, n_tokens);
    if (checkpoint_size == 0 || n != checkpoint_size) {
        GGML_ABORT("checkpoint size mismatch: expected %zu, got %zu\n", checkpoint_size, n);
    }

    return cur;
}

// state diagram: https://github.com/ggml-org/llama.cpp/pull/9283
enum slot_state {
    SLOT_STATE_IDLE,
    SLOT_STATE_WAIT_OTHER, // after assigning a task, but waiting for parent slot to process prompt
    SLOT_STATE_STARTED,    // after assigning a task and about to process prompt
    SLOT_STATE_PROCESSING_PROMPT,
    SLOT_STATE_DONE_PROMPT,
    SLOT_STATE_GENERATING,
};

enum server_state {
    SERVER_STATE_LOADING_MODEL,  // Server is starting up, model not fully loaded yet
    SERVER_STATE_READY,          // Server is ready and model is loaded
};

static json server_runtime_policy_json(const llama_k3_decode_expert_policy & p) {
    return {{"mode", llama_k3_decode_expert_mode_name(p.mode)}, {"top_k", p.top_k},
        {"mass", p.mass}, {"min_k", p.min_k}, {"max_k", p.max_k},
        {"layer_start", p.layer_start}, {"layer_end", p.layer_end}, {"small_batch", p.small_batch}};
}

static json server_runtime_config_json(const llama_k3_runtime_config & config) {
    json table = json::array();
    for (const auto & row : config.table) {
        table.push_back({{"layer", row.layer}, {"mass", row.mass}, {"min_k", row.min_k}, {"max_k", row.max_k}});
    }
    return {{"primary", server_runtime_policy_json(config.primary)},
        {"guard_tokens", config.guard_tokens}, {"guard_policy", server_runtime_policy_json(config.guard)},
        {"guard_start_tokens", config.guard_start_tokens},
        {"guard_control_tokens", config.guard_control_tokens},
        {"layer_table", table}};
}

static llama_tokens server_guard_control_token_ids(const llama_vocab * vocab) {
    const auto open = common_tokenize(vocab, "<|open|>", false, true);
    const auto close = common_tokenize(vocab, "<|close|>", false, true);
    if (open.size() != 1 || close.size() != 1 || open[0] < 0 || close[0] < 0 || open[0] == close[0] ||
            !llama_vocab_is_control(vocab, open[0]) || !llama_vocab_is_control(vocab, close[0])) {
        throw std::invalid_argument("K3 control guard requires distinct single control-token IDs for <|open|> and <|close|>");
    }
    return {open[0], close[0]};
}

struct server_slot {
    int id;

    llama_context * ctx = nullptr;

    common_context_seq_rm_type ctx_seq_rm_type = COMMON_CONTEXT_SEQ_RM_TYPE_NO;

    // multimodal
    mtmd_context * mctx = nullptr;

    // speculative decoding
    llama_tokens spec_draft;
    std::vector<int32_t> spec_i_batch;
    server_prompt_checkpoint spec_ckpt;
    common_speculative_ptr spec;

    // TODO: move members that belong to the task (such as `generated_text`, `has_new_line`) to task_results_state
    //       see https://github.com/ggml-org/llama.cpp/pull/18283#issuecomment-3710175837
    std::unique_ptr<const server_task> task;
    std::unique_ptr<const server_task> task_prev; // used for debugging

    // used to determine the slot that has been used the longest
    int64_t t_last_used = -1;

    // the task whose request_begin has been reported and whose request_end has not (see end_request())
    bool    request_open = false;
    int64_t request_task_id = -1;

    // Prompt tokens [n0, n1) of the slot went into the batch being decoded, ending at batch row `row_end`. A memory
    // that can save an earlier state (llama_state_seq_at_align) is checkpointed inside them once they are decoded,
    // instead of stopping the batch at each checkpoint (see checkpoint_decoded_prompt()).
    struct {
        int64_t n0 = 0;
        int64_t n1 = 0;
        int32_t row_end = -1;
    } prompt_batch;

    // generation props
    int32_t n_ctx       = 0;  // context size per slot
    int32_t n_keep      = 0;
    int32_t n_decoded   = 0;
    int32_t n_remaining = -1;
    int32_t i_batch     = -1;

    int32_t n_prompt_tokens_cache     = 0;
    int32_t n_prompt_tokens_processed = 0;

    size_t last_nl_pos = 0;

    common_chat_output_source output_source;
    std::string  generated_text;
    std::string  debug_generated_text;
    llama_tokens generated_tokens;

    // Last min_len sampled tokens are held back from SSE. If loop_stop fires,
    // the matched suffix is removed here before any client can observe it.
    std::deque<completion_token_output> loop_output_hold;
    int64_t loop_removed_tokens = 0;

    std::vector<completion_token_output> generated_token_probs;

    bool has_next_token = true;
    bool has_new_line   = false;
    bool truncated      = false;

    stop_type stop;

    std::string stopping_word;

    // state
    slot_state state = SLOT_STATE_IDLE;

    server_prompt prompt;
    server_expert_guard expert_guard;
    server_k3_protocol k3_protocol;
    uint64_t guard_predictions = 0, guard_failed_decodes = 0;
    uint64_t guard_start_predictions = 0, guard_opener_predictions = 0, guard_overlap_predictions = 0;
    uint64_t guard_control_predictions = 0, guard_control_only_predictions = 0;
    int64_t guard_opened_after_token = -1;
    bool guard_prompt_primed = false, guard_last_selected = false;
    bool guard_last_start_selected = false, guard_last_opener_selected = false;
    bool guard_last_control_selected = false;

    void reset_guard() {
        expert_guard.reset(0, {});
        guard_predictions = guard_failed_decodes = 0;
        guard_start_predictions = guard_opener_predictions = guard_overlap_predictions = 0;
        guard_control_predictions = guard_control_only_predictions = 0;
        guard_opened_after_token = -1;
        guard_prompt_primed = guard_last_selected = false;
        guard_last_start_selected = guard_last_opener_selected = false;
        guard_last_control_selected = false;
    }

    void prompt_save(server_prompt_cache & prompt_cache) const {
        GGML_ASSERT(prompt.data.size() == 0);

        prompt_cache.save(prompt, true, ctx, id, ctx_seq_rm_type);
    }

    // how many tokens of `tokens` the slot's own state lets it skip (a state that cannot be rolled back is reused up
    // to its end or one of its checkpoints)
    int64_t prompt_reuse(const server_tokens & tokens) const {
        if (ctx_seq_rm_type != COMMON_CONTEXT_SEQ_RM_TYPE_FULL) {
            return prompt.tokens.get_common_prefix(tokens);
        }
        const server_prompt_checkpoint * checkpoint = nullptr;
        return std::max<int64_t>(0, server_prompt_reuse_full(prompt, tokens, &checkpoint));
    }

    bool prompt_load(server_prompt_cache & prompt_cache, const server_tokens & tokens) {
        bool res = prompt_cache.load(prompt, tokens, prompt_reuse(tokens), ctx, id, ctx_seq_rm_type);
        if (!res) {
            SLT_WRN(*this, "%s", "failed to load prompt from cache\n");
        }

        return res;
    }

    void prompt_clear(bool allow_processing) {
        if (!allow_processing) {
            GGML_ASSERT(!is_processing());
        }

        SLT_INF(*this, "clearing prompt with %zu tokens\n", prompt.tokens.size());

        llama_memory_seq_rm(llama_get_memory(ctx), id, -1, -1);
        prompt.tokens.clear();
    }

    std::vector<common_adapter_lora_info> lora;
    int32_t alora_invocation_start = -1;

    // sampling
    json json_schema;

    common_sampler_ptr smpl;

    llama_token sampled; // in speculative mode, this is the last accepted token

    // stats
    size_t n_sent_text = 0; // number of sent text character

    int64_t t_start_process_prompt;
    int64_t t_start_generation;

    double t_prompt_processing = 0.0; // ms
    double t_token_generation = 0.0;  // ms

    std::function<void(int /* id_slot */)> callback_on_release;

    // Speculative decoding stats
    int32_t n_draft_total = 0;      // Total draft tokens generated
    int32_t n_draft_accepted = 0;   // Draft tokens actually accepted
    uint64_t n_spec_blocks = 0;
    int64_t  t_spec_step_start_us = 0;
    double   t_spec_draft_ms = 0.0;

    void reset() {
        SLT_DBG(*this, "%s", "\n");

        n_prompt_tokens_cache = 0;
        reset_guard();
        k3_protocol = {};

        last_nl_pos    = 0;
        generated_text = "";
        output_source = {};
        output_source.valid = true;
        has_new_line   = false;
        truncated      = false;
        stop           = STOP_TYPE_NONE;
        stopping_word  = "";
        n_sent_text    = 0;

        if (can_speculate()) {
            spec_draft.clear();
            spec_i_batch.clear();
            spec_ckpt.clear();
        }
        generated_tokens.clear();
        loop_output_hold.clear();
        loop_removed_tokens = 0;
        generated_token_probs.clear();
        json_schema = json();

        // clear speculative decoding stats
        n_draft_total = 0;
        n_draft_accepted = 0;
        n_spec_blocks = 0;
        t_spec_step_start_us = 0;
        t_spec_draft_ms = 0.0;

        task_prev = std::move(task);
        task.reset();

        llama_set_sampler(ctx, id, nullptr);

        // clear alora start
        alora_invocation_start = -1;
    }

    void init_sampler() const {
        common_sampler_set_log_context(smpl.get(), id, task->id);
        common_sampler_reset(smpl.get());

        if (!task->need_sampling()) {
            return;
        }

        const int64_t t_start = ggml_time_us();

        int n_text = 0;

        for (int i = 0; i < (int) prompt.tokens.size(); i++) {
            const llama_token id = prompt.tokens[i];

            if (id != LLAMA_TOKEN_NULL) {
                common_sampler_accept(smpl.get(), id, false);
                n_text++;
            }
        }

        SLT_INF(*this, "init sampler, took %0.2f ms, tokens: text = %d, total = %d\n",
                (ggml_time_us() - t_start) / 1000.0, n_text, (int) prompt.tokens.size());
    }

    // if the context does not have a memory module then all embeddings have to be computed within a single ubatch
    // also we cannot split if the pooling would require any past tokens
    bool can_split() const {
        GGML_ASSERT(task);

        return
            !task->need_embd() ||
            (llama_get_memory(ctx) && llama_pooling_type(ctx) == LLAMA_POOLING_TYPE_LAST);
    }

    bool can_batch_with(server_slot & other_slot) const {
        GGML_ASSERT(task);

        return task->type == other_slot.task->type && are_lora_equal(lora, other_slot.lora);
    }

    bool has_budget(const common_params & global_params) {
        GGML_ASSERT(task);

        if (task->params.n_predict == -1 && global_params.n_predict == -1) {
            return true; // limitless
        }

        n_remaining = -1;

        if (task->params.n_predict != -1) {
            n_remaining = task->params.n_predict - n_decoded;
        } else if (global_params.n_predict != -1) {
            n_remaining = global_params.n_predict - n_decoded;
        }

        return n_remaining > 0; // no budget
    }

    bool is_processing() const {
        return state != SLOT_STATE_IDLE;
    }

    bool can_speculate() const {
        return !!spec;
    }

    void add_token(const completion_token_output & token) {
        if (!is_processing()) {
            SLT_WRN(*this, "%s", "slot is not processing\n");
            return;
        }

        generated_token_probs.push_back(token);
    }

    int get_n_draft_max() const {
        GGML_ASSERT(task);

        if (!can_speculate()) {
            return 0;
        }

        const int n_draft_min = common_speculative_n_min(spec.get(), task->params.speculative);

        // determine the max draft that fits the current slot state
        int n_draft_max = common_speculative_n_max(spec.get(), task->params.speculative);

        // note: slot.prompt is not yet expanded with the `id` token sampled above
        //       also, need to leave space for 1 extra token to allow context shifts
        n_draft_max = std::min(n_draft_max, n_ctx - prompt.n_tokens() - 2);

        if (n_remaining > 0) {
            n_draft_max = std::min(n_draft_max, n_remaining - 1);
        }

        SLT_DBG(*this, "max possible draft: %d\n", n_draft_max);

        if (n_draft_max < n_draft_min) {
            SLT_DBG(*this, "the max possible draft is too small: %d < %d - skipping speculative decoding\n", n_draft_max, n_draft_min);
            n_draft_max = 0;
        }

        return n_draft_max;
    }

    void update_batch(llama_batch & batch) {
        const int n_draft_max = get_n_draft_max();
        if (n_draft_max > 0) {
            GGML_ASSERT(can_speculate());

            // generate draft tokens in speculative decoding mode
            // TODO: rework to have a single draft llama_context shared across all slots [TAG_SERVER_SPEC_REWORK]
            //       perform the speculative drafting for all sequences at the same time in a single batch
            const llama_tokens & tokens = prompt.tokens.get_text_tokens();

            const auto & params_spec = task->params.speculative;

            if (!spec_draft.empty()) {
                // we have a previous (partial) draft to reuse
                if (ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL) {
                    GGML_ASSERT(!spec_ckpt.empty());
                }
            } else {
                GGML_ASSERT(spec_i_batch.empty());

                // generate a new draft
                t_spec_step_start_us = ggml_time_us();
                spec_draft = common_speculative_draft(spec.get(), params_spec, tokens, sampled);
                t_spec_draft_ms = (ggml_time_us() - t_spec_step_start_us) / 1e3;

                if (spec_draft.size() > (size_t) n_draft_max) {
                    SLT_WRN(*this, "draft size %d exceeds max %d, truncating\n", (int) spec_draft.size(), n_draft_max);
                    spec_draft.resize(n_draft_max);
                }

                if (!spec_draft.empty() && ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL) {
                    const auto n_tokens = prompt.tokens.size();

                    spec_ckpt = server_get_checkpoint(ctx, this->id, n_tokens);

                    SLT_DBG(*this, "created speculative checkpoint (pos_min = %d, pos_max = %d, n_tokens = %zu, size = %.3f MiB)\n",
                            spec_ckpt.pos_min, spec_ckpt.pos_max, n_tokens, (float) spec_ckpt.data.size() / 1024 / 1024);
                }

                if (spec_draft.empty()) {
                    t_spec_step_start_us = 0;
                    t_spec_draft_ms = 0.0;
                }
            }

            GGML_ASSERT(spec_draft.size() <= (size_t) n_draft_max);
        }

        if (spec_draft.empty()) {
            // no speculative decoding
            i_batch = batch.n_tokens;

            common_batch_add(batch, sampled, prompt.tokens.pos_next(), { this->id }, true);

            SLT_DBG(*this, "slot decode token, id=%d, n_ctx = %d, n_tokens = %d, truncated = %d\n",
                    sampled, n_ctx, prompt.n_tokens(), truncated);
        } else {
            SLT_DBG(*this, "generate_draft: id=%d, #tokens=%zu, #draft=%zu, pos_next=%d\n",
                    sampled, prompt.tokens.size(), spec_draft.size(), prompt.tokens.pos_next());

            GGML_ASSERT(spec_i_batch.empty());

            spec_i_batch.push_back(batch.n_tokens);
            for (size_t i = 0; i < spec_draft.size(); i++) {
                spec_i_batch.push_back(batch.n_tokens + i + 1);
            }

            auto pos0 = prompt.tokens.pos_next();

            common_batch_add(batch, sampled, pos0++, { this->id }, true);
            for (auto token : spec_draft) {
                common_batch_add(batch, token, pos0++, { this->id }, true);
            }
        }

        prompt.tokens.push_back(sampled);
        prompt.tokens.insert(spec_draft);
    }

    // Report request_end for the request opened at launch, exactly once, whatever ends it: completion, an error, a
    // cancellation or a rejected launch. A request left open keeps the backend in its prefill phase.
    void end_request() {
        if (!request_open) {
            return;
        }
        request_open = false;
        server_moe_phase_report(ctx, "request_end", request_task_id);
    }

    void release() {
        end_request();
        prompt_batch.row_end = -1;

        if (is_processing()) {
            GGML_ASSERT(task);

            SLT_INF(*this, "stop processing: n_tokens = %d, truncated = %d\n", prompt.n_tokens(), truncated);

            t_last_used        =  ggml_time_us();
            t_token_generation = (ggml_time_us() - t_start_generation) / 1e3;

            state = SLOT_STATE_IDLE;

            // do not keep context of the child slots - the parent's context is enough
            if (task->is_child()) {
                prompt_clear(false);
            }

            reset();

            callback_on_release(id);
        }
    }

    result_timings get_timings() const {
        result_timings timings;
        timings.cache_n = n_prompt_tokens_cache;

        timings.prompt_n            = n_prompt_tokens_processed;
        timings.prompt_ms           = t_prompt_processing;
        timings.prompt_per_token_ms = t_prompt_processing / n_prompt_tokens_processed;
        timings.prompt_per_second   = 1e3 / t_prompt_processing * n_prompt_tokens_processed;

        timings.predicted_n            = n_decoded;
        timings.predicted_ms           = t_token_generation;
        timings.predicted_per_token_ms = t_token_generation / n_decoded;
        timings.predicted_per_second   = 1e3 / t_token_generation * n_decoded;

        // Add speculative metrics
        if (n_draft_total > 0) {
            timings.draft_n          = n_draft_total;
            timings.draft_n_accepted = n_draft_accepted;
        }

        return timings;
    }

    size_t find_stopping_strings(const std::string & text, const size_t last_token_size, bool is_full_stop) {
        GGML_ASSERT(task);

        size_t stop_pos = std::string::npos;

        for (const std::string & word : task->params.antiprompt) {
            size_t pos;

            if (is_full_stop) {
                const size_t tmp      = word.size() + last_token_size;
                const size_t from_pos = text.size() > tmp ? text.size() - tmp : 0;

                pos = text.find(word, from_pos);
            } else {
                // otherwise, partial stop
                pos = string_find_partial_stop(text, word);
            }

            if (pos != std::string::npos && (stop_pos == std::string::npos || pos < stop_pos)) {
                if (is_full_stop) {
                    stop           = STOP_TYPE_WORD;
                    stopping_word  = word;
                    has_next_token = false;
                }
                stop_pos = pos;
            }
        }

        return stop_pos;
    }

    void print_timings() const {
        const double t_prompt        =       t_prompt_processing / n_prompt_tokens_processed;
        const double n_prompt_second = 1e3 / t_prompt_processing * n_prompt_tokens_processed;

        const double t_gen        =       t_token_generation / n_decoded;
        const double n_gen_second = 1e3 / t_token_generation * n_decoded;

        SLT_INF(*this,
                "\n"
                "prompt eval time = %10.2f ms / %5d tokens (%8.2f ms per token, %8.2f tokens per second)\n"
                "       eval time = %10.2f ms / %5d tokens (%8.2f ms per token, %8.2f tokens per second)\n"
                "      total time = %10.2f ms / %5d tokens\n",
                t_prompt_processing, n_prompt_tokens_processed, t_prompt, n_prompt_second,
                t_token_generation, n_decoded, t_gen, n_gen_second,
                t_prompt_processing + t_token_generation, n_prompt_tokens_processed + n_decoded);

        if (n_draft_total > 0) {
            const float draft_ratio = (float) n_draft_accepted / n_draft_total;
            SLT_CNT(*this,
                    "draft acceptance rate = %0.5f (%5d accepted / %5d generated)\n",
                    draft_ratio, n_draft_accepted, n_draft_total
            );
        }

        common_speculative_print_stats(spec.get());
    }

    json to_json(bool only_metrics = false) const {
        json res;

        res = {
            {"id",            id},
            {"n_ctx",         n_ctx},
            {"speculative",   can_speculate()},
            {"is_processing", is_processing()},
        };

        const auto & ptask = task ? task : task_prev;

        if (ptask) {
            res["id_task"] = ptask->id;
            res["params"] = ptask->params.to_json(only_metrics);
            res["next_token"] = {
                {
                    {"has_next_token", has_next_token},
                    {"has_new_line",   has_new_line},
                    {"n_remain",       n_remaining},
                    {"n_decoded",      n_decoded},
                }
            };

            if (!only_metrics) {
                res["prompt"] = ptask->tokens.detokenize(ctx, true);
                res["generated"] = generated_text.empty() ? debug_generated_text : generated_text;
            }
        }

        return res;
    }

    void copy_state_to(server_slot & other) const {
        GGML_ASSERT(state == SLOT_STATE_DONE_PROMPT);

        llama_memory_seq_rm(llama_get_memory(ctx), other.id,     -1, -1);
        llama_memory_seq_cp(llama_get_memory(ctx), id, other.id, -1, -1);

        other.n_decoded   = n_decoded;
        other.n_remaining = n_remaining;
        other.i_batch     = i_batch;

        other.t_start_process_prompt    = t_start_process_prompt;
        other.t_prompt_processing       = t_prompt_processing;
        other.n_prompt_tokens_cache     = n_prompt_tokens_cache;
        other.n_prompt_tokens_processed = n_prompt_tokens_processed;

        other.prompt = prompt.clone();
        other.init_sampler();
    }
};



//
// server_metrics
//

struct server_metrics {
    int64_t t_start = 0;

    uint64_t n_prompt_tokens_processed_total = 0;
    uint64_t t_prompt_processing_total       = 0;
    uint64_t n_tokens_predicted_total        = 0;
    uint64_t n_sampler_struct_top1_replacements_total = 0;
    uint64_t n_sampler_struct_mixed_samples_total = 0;
    uint64_t n_k3_constraint_conflicts_total = 0;
    uint64_t n_k3_protocol_forced_tokens_total = 0;
    uint64_t t_tokens_generation_total       = 0;

    uint64_t n_tokens_max = 0;

    uint64_t n_prompt_tokens_processed = 0;
    uint64_t t_prompt_processing       = 0;

    uint64_t n_tokens_predicted  = 0;
    uint64_t t_tokens_generation = 0;

    uint64_t n_decode_total     = 0;
    uint64_t n_busy_slots_total = 0;

    void init() {
        t_start = ggml_time_us();
    }

    void on_prompt_eval(const server_slot & slot) {
        n_prompt_tokens_processed_total += slot.n_prompt_tokens_processed;
        n_prompt_tokens_processed       += slot.n_prompt_tokens_processed;
        t_prompt_processing             += slot.t_prompt_processing;
        t_prompt_processing_total       += slot.t_prompt_processing;

        n_tokens_max = std::max(n_tokens_max, (uint64_t) slot.prompt.n_tokens());
    }

    void on_prediction(const server_slot & slot) {
        n_tokens_predicted_total   += slot.n_decoded;
        n_tokens_predicted         += slot.n_decoded;
        t_tokens_generation        += slot.t_token_generation;
        t_tokens_generation_total  += slot.t_token_generation;
    }

    void on_decoded(const std::vector<server_slot> & slots) {
        n_decode_total++;
        for (const auto & slot : slots) {
            if (slot.is_processing()) {
                n_busy_slots_total++;
            }
            n_tokens_max = std::max(n_tokens_max, (uint64_t) slot.prompt.n_tokens());
        }
    }

    void reset_bucket() {
        n_prompt_tokens_processed = 0;
        t_prompt_processing       = 0;
        n_tokens_predicted        = 0;
        t_tokens_generation       = 0;
    }
};


//
// server_context_impl (private implementation)
//

struct server_context_impl {
    friend struct server_context;

public:
    // only use these pointers outside of this class:
    //  - when not in sleeping state
    //  - and, with thread-safe APIs (e.g., tokenizer calls)
    llama_model * model = nullptr;
    mtmd_context * mctx = nullptr;
    const llama_vocab * vocab = nullptr;

    server_queue    queue_tasks;
    server_response queue_results;

    // note: chat_params must not be refreshed upon existing sleeping state
    server_chat_params chat_params;

    ~server_context_impl() {
        if (!sleeping) {
            // destroy() is already called when entering sleeping state
            // we don't call it again here to avoid double free
            destroy();
        }
    }

private:
    // note: accessing these fields outside of this class is not thread-safe
    // use server_context methods instead

    common_params params_base;

    // note: keep these alive - they determine the lifetime of the model, context, etc.
    common_init_result_ptr llama_init;

    llama_context * ctx = nullptr;

    llama_batch batch {};

    llama_model_ptr model_dft;

    bool add_bos_token = true;

    int32_t n_ctx; // total context for all clients / slots

    // set to llama_model_n_swa(model)
    // if swa_full is enabled, this is set to 0 to simulate a non-SWA model
    int32_t n_swa;

    // slots / clients
    std::vector<server_slot> slots;

    int slots_debug = 0;
    int n_empty_consecutive = 0;

    // Opt-in bounded prefill sizing on Mac. The context's physical ubatch
    // remains the hard ceiling; the server submits smaller physical work.
    int32_t mac_prefill_task = -1;
    int32_t mac_prefill_size = 0;
    int32_t mac_prefill_previous_size = 0;
    double mac_prefill_previous_ms_per_token = 0;
    bool mac_prefill_settled = false;

    std::unique_ptr<server_prompt_cache> prompt_cache;

    // positions at which the memory can save a state it has gone past (llama_state_seq_at_align), 0 if it cannot
    int64_t checkpoint_at_align = 0;

    bool guard_enabled() const {
        const auto * config = llama_k3_runtime_config_get(ctx);
        return config && (config->guard_tokens > 0 || config->guard_start_tokens > 0 || config->guard_control_tokens > 0);
    }

    server_metrics metrics;
    server_sampler_struct_top1 sampler_struct_top1;
    server_k3_protocol_ids k3_protocol_ids;

    json json_webui_settings = json::object();

    // Necessary similarity of prompt for slot selection
    float slot_prompt_similarity = 0.0f;

    std::string model_name; // name of the loaded model, to be used by API
    std::set<std::string> model_aliases; // additional names for the model
    std::set<std::string> model_tags;    // informational tags

    bool sleeping = false;

    void destroy() {
        llama_init.reset();

        ctx = nullptr;
        model = nullptr;

        mtmd_free(mctx);
        mctx = nullptr;

        for (server_slot & slot : slots) {
            if (slot.can_speculate()) {
                slot.spec.reset();
            }
        }

        llama_batch_free(batch);
    }

    // What a cached state on disk depends on besides its tokens: the model file and the build that computed it.
    std::string prompt_cache_fingerprint() const {
        std::string fp = std::string(llama_build_info()) + "|" + params_base.model.path;
        std::error_code ec;
        const auto size  = std::filesystem::file_size(params_base.model.path, ec);
        const auto mtime = std::filesystem::last_write_time(params_base.model.path, ec);
        fp += "|" + std::to_string(ec ? 0 : size) + "|" + std::to_string(ec ? 0 : (long long) mtime.time_since_epoch().count());
        char desc[256];
        llama_model_desc(model, desc, sizeof(desc));
        return fp + "|" + desc;
    }

    void slot_save_and_clear(server_slot & slot) {
        // Guard trajectories have no persisted prefix/schedule identity.
        if (guard_enabled()) { return; }
        if (slot.prompt.n_tokens() == 0) {
            return;
        }
        SLT_INF(slot, "%s", "saving idle slot to prompt cache\n");
        SLT_DBG(slot, "%s", "__TEST_TAG_CACHE_IDLE_SLOT__\n");
        slot.prompt_save(*prompt_cache);
        slot.prompt_clear(false);
        prompt_cache->update();
    }

    void handle_sleeping_state(bool new_state) {
        GGML_ASSERT(sleeping != new_state);
        if (new_state) {
            SRV_INF("%s", "server is entering sleeping state\n");
            destroy();
        } else {
            SRV_INF("%s", "server is exiting sleeping state\n");
            if (!load_model(params_base)) {
                GGML_ABORT("failed to reload model after sleeping");
            }
        }
        sleeping = new_state;
    }

    // load the model and initialize llama_context
    // this may also be called to resume from sleeping state
    bool load_model(common_params & params) {
        bool is_resume = sleeping;

        SRV_INF("loading model '%s'\n", params.model.path.c_str());

        params_base = params;

        try {
            sampler_struct_top1.config = server_sampler_struct_top1_config::from_env();
        } catch (const std::exception & e) {
            SRV_ERR("%s\n", e.what());
            return false;
        }
        if (sampler_struct_top1.config.active() && params_base.speculative.type != COMMON_SPECULATIVE_TYPE_NONE) {
            SRV_ERR("%s", "K3 sampler structural top-1 requires non-speculative sampling\n");
            return false;
        }

        if (sampler_struct_top1.config.active()) { params_base.sampling.backend_sampling = false; }

        llama_init = common_init_from_params(params_base);

        model = llama_init->model();
        ctx   = llama_init->context();

        if (model == nullptr) {
            SRV_ERR("failed to load model, '%s'\n", params_base.model.path.c_str());
            return false;
        }

        if (ctx == nullptr) {
            SRV_ERR("failed to create_context with model '%s'\n", params_base.model.path.c_str());
            return false;
        }

        vocab = llama_model_get_vocab(model);
        sampler_struct_top1.tokens.clear();
        if (sampler_struct_top1.config.active()) {
            const int32_t n_vocab = llama_vocab_n_tokens(vocab);
            sampler_struct_top1.tokens.reserve(n_vocab);
            size_t n_struct = 0, n_mixed = 0;
            for (int32_t token = 0; token < n_vocab; ++token) {
                sampler_struct_top1.tokens.push_back(server_struct_classify(
                    common_token_to_piece(vocab, token, true),
                    (llama_vocab_get_attr(vocab, token) & LLAMA_TOKEN_ATTR_CONTROL) != 0,
                    llama_vocab_is_eog(vocab, token)));
                n_struct += sampler_struct_top1.is_struct(token);
                n_mixed += sampler_struct_top1.tokens.back().mixed;
            }
            k3_protocol_ids = server_k3_protocol_ids::find(sampler_struct_top1.tokens);
            const auto & config = sampler_struct_top1.config;
            SRV_INF("K3 sampler: struct_top1=%d, protocol_tags=%d, force_response=%d, vocab=%d, structural=%zu, mixed=%zu, classes=%u, min_top1_p=%.9g, basis=effective_q, grammar_first=1, backend_sampling=0\n",
                config.enabled, config.protocol_tags, config.force_response, n_vocab, n_struct, n_mixed,
                unsigned(config.classes), config.min_top1_p);
        }
        if (const auto * config = llama_k3_runtime_config_get(ctx)) {
            if (config->guard_control_tokens > 0) {
                try {
                    const auto control = server_guard_control_token_ids(vocab);
                    SRV_INF("control guard tokens: open=%d, close=%d\n", control[0], control[1]);
                }
                catch (const std::exception & e) { SRV_ERR("%s\n", e.what()); return false; }
            }
            if (guard_enabled() && (params_base.n_parallel != 1 ||
                    params_base.speculative.type != COMMON_SPECULATIVE_TYPE_NONE || !params_base.mmproj.path.empty())) {
                SRV_ERR("%s", "K3 opener guard requires one slot, no speculation and a text-only context\n");
                return false;
            }
            if (guard_enabled() || !config->table.empty()) {
                SRV_INF("runtime routing launch: %s\n", server_runtime_config_json(*config).dump().c_str());
            }
        }

        n_ctx = llama_n_ctx(ctx);

        add_bos_token = llama_vocab_get_add_bos(vocab);

        if (params_base.speculative.has_dft()) {
            // TODO speculative: move to common/speculative.cpp?
            const auto & params_spec = params_base.speculative.draft;

            SRV_INF("loading draft model '%s'\n", params_spec.mparams.path.c_str());

            auto params_dft = params_base;

            params_dft.n_parallel   = 1;
            params_dft.n_ctx        = params_spec.n_ctx == 0 ? llama_n_ctx_seq(ctx) : params_spec.n_ctx;
            params_dft.n_batch      = llama_n_ctx_seq(ctx);
            params_dft.devices      = params_spec.devices;
            params_dft.model        = params_spec.mparams;
            params_dft.n_gpu_layers = params_spec.n_gpu_layers;
            params_dft.cache_type_k = params_spec.cache_type_k;
            params_dft.cache_type_v = params_spec.cache_type_v;

            if (params_spec.cpuparams.n_threads > 0) {
                params_dft.cpuparams.n_threads       = params_spec.cpuparams.n_threads;
                params_dft.cpuparams_batch.n_threads = params_spec.cpuparams_batch.n_threads;
            }

            params_dft.tensor_buft_overrides = params_spec.tensor_buft_overrides;

            auto mparams_dft = common_model_params_to_llama(params_dft);

            model_dft.reset(llama_model_load_from_file(params_dft.model.path.c_str(), mparams_dft));
            if (model_dft == nullptr) {
                SRV_ERR("failed to load draft model, '%s'\n", params_dft.model.path.c_str());
                return false;
            }

            params_base.speculative.draft.model = model_dft.get();
            params_base.speculative.draft.cparams = common_context_params_to_llama(params_dft);
        }

        std::string & mmproj_path = params_base.mmproj.path;
        if (!mmproj_path.empty()) {
            if (!is_resume) {
                mtmd_helper_log_set(common_log_default_callback, nullptr);
            }

            mtmd_context_params mparams = mtmd_context_params_default();

            mparams.use_gpu          = params_base.mmproj_use_gpu;
            mparams.print_timings    = false;
            mparams.n_threads        = params_base.cpuparams.n_threads;
            mparams.flash_attn_type  = params_base.flash_attn_type;
            mparams.warmup           = params_base.warmup;
            mparams.image_min_tokens = params_base.image_min_tokens;
            mparams.image_max_tokens = params_base.image_max_tokens;
            mparams.media_marker     = get_media_marker();

            mctx = mtmd_init_from_file(mmproj_path.c_str(), model, mparams);
            if (mctx == nullptr) {
                SRV_ERR("failed to load multimodal model, '%s'\n", mmproj_path.c_str());
                return false;
            }
            SRV_INF("loaded multimodal model, '%s'\n", mmproj_path.c_str());

            if (params_base.ctx_shift) {
                params_base.ctx_shift = false;
                SRV_WRN("%s\n", "ctx_shift is not supported by multimodal, it will be disabled");
            }

            if (params_base.n_cache_reuse) {
                params_base.n_cache_reuse = 0;
                SRV_WRN("%s\n", "cache_reuse is not supported by multimodal, it will be disabled");
            }
        }

        if (!llama_memory_can_shift(llama_get_memory(ctx))) {
            if (params_base.ctx_shift) {
                params_base.ctx_shift = false;
                SRV_WRN("%s\n", "ctx_shift is not supported by this context, it will be disabled");
            }

            if (params_base.n_cache_reuse) {
                params_base.n_cache_reuse = 0;
                SRV_WRN("%s\n", "cache_reuse is not supported by this context, it will be disabled");
            }
        }

        if (llama_model_n_swa(model) == 0) {
            if (params_base.swa_full) {
                params_base.swa_full = false;
                SRV_WRN("%s\n", "swa_full is not supported by this model, it will be disabled");
            }
        }

        n_swa = params_base.swa_full ? 0 : llama_model_n_swa(model);

        // Necessary similarity of prompt for slot selection
        slot_prompt_similarity = params_base.slot_prompt_similarity;

        // setup slots
        SRV_INF("initializing slots, n_slots = %d\n", params_base.n_parallel);

        const int n_ctx_train = llama_model_n_ctx_train(model);

        int n_ctx_slot = llama_n_ctx_seq(ctx);
        if (n_ctx_slot > n_ctx_train) {
            SRV_WRN("the slot context (%d) exceeds the training context of the model (%d) - capping\n", n_ctx_slot, n_ctx_train);
            n_ctx_slot = n_ctx_train;
        }

        slots.clear();

        const auto ctx_seq_rm_type = common_context_can_seq_rm(ctx);
        if (ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_NO) {
            SRV_WRN("%s", "speculative decoding not supported by this context\n");
        }

        if (ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL) {
            SRV_WRN("%s", "speculative decoding will use checkpoints\n");
        }

        // initialize slots
        for (int i = 0; i < params_base.n_parallel; i++) {
            slots.emplace_back();
        }

        for (int i = 0; i < params_base.n_parallel; i++) {
            server_slot & slot = slots[i];

            slot.id    = i;
            slot.ctx   = ctx;
            slot.n_ctx = n_ctx_slot;

            slot.ctx_seq_rm_type = ctx_seq_rm_type;

            slot.mctx                   = mctx;
            slot.prompt.tokens.has_mtmd = mctx != nullptr;

            // try speculative decoding
            if (ctx_seq_rm_type != COMMON_CONTEXT_SEQ_RM_TYPE_NO) {
                slot.spec.reset(common_speculative_init(params_base.speculative, slot.ctx));

                if (slot.spec) {
                    SLT_INF(slot, "%s", "speculative decoding context initialized\n");
                }
            }

            SLT_INF(slot, "new slot, n_ctx = %d\n", slot.n_ctx);

            slot.callback_on_release = [this](int id_slot) {
                queue_tasks.pop_deferred_task(id_slot);
            };

            slot.reset();
        }

        {
            const char * LLAMA_SERVER_SLOTS_DEBUG = getenv("LLAMA_SERVER_SLOTS_DEBUG");
            slots_debug = LLAMA_SERVER_SLOTS_DEBUG ? atoi(LLAMA_SERVER_SLOTS_DEBUG) : 0;

            if (slots_debug) {
                SRV_WRN("slots debug = %d\n", slots_debug);
            }
        }

        // the update_slots() logic will always submit a maximum of n_batch or n_parallel tokens
        // note that n_batch can be > n_ctx (e.g. for non-causal attention models such as BERT where the KV cache is not used)
        {
            const int32_t n_batch = llama_n_batch(ctx);
            batch = llama_batch_init(std::max(n_batch, params_base.n_parallel), 0, 1);
        }

        checkpoint_at_align = llama_state_seq_at_align(ctx);
        // A state saved after the batch serves only a memory that cannot be rolled back to it: one that cannot be
        // rolled back at all, or a sliding-window cache that gives the window's cells to later positions, not one
        // with a full-size window (--swa-full, n_swa = 0 here).  The same condition as checkpoints that stop the
        // batch (do_checkpoint).
        if (ctx_seq_rm_type != COMMON_CONTEXT_SEQ_RM_TYPE_FULL && n_swa == 0) {
            checkpoint_at_align = 0;
        }
        if (checkpoint_at_align > 0) {
            SRV_INF("context checkpoints are taken after each prompt batch, at multiples of %" PRId64 " tokens\n", checkpoint_at_align);
        }

        if (!params_base.cache_disk.empty()) {
            SRV_WRN("prompt cache is on disk in %s, size limit: %d MiB\n", params_base.cache_disk.c_str(), params_base.cache_disk_mib);

            prompt_cache = std::make_unique<server_prompt_cache>(params_base.cache_disk_mib, 0);
            prompt_cache->use_dir(params_base.cache_disk, prompt_cache_fingerprint());
        } else if (params_base.cache_ram_mib != 0) {
            if (params_base.cache_ram_mib < 0) {
                SRV_WRN("prompt cache is enabled, size limit: %s\n", "no limit");
            } else {
                SRV_WRN("prompt cache is enabled, size limit: %d MiB\n", params_base.cache_ram_mib);
            }
            SRV_WRN("%s", "use `--cache-ram 0` to disable the prompt cache\n");

            prompt_cache = std::make_unique<server_prompt_cache>(params_base.cache_ram_mib, n_ctx);
        } else {
            SRV_WRN("%s", "prompt cache is disabled - use `--cache-ram N` to enable it\n");
        }
        SRV_WRN("%s", "for more info see https://github.com/ggml-org/llama.cpp/pull/16391\n");

        if (!params_base.model_alias.empty()) {
            // backward compat: use first alias as model name
            model_name = *params_base.model_alias.begin();
        } else if (!params_base.model.name.empty()) {
            model_name = params_base.model.name;
        } else {
            // fallback: derive model name from file name
            auto model_path = std::filesystem::path(params_base.model.path);
            model_name = model_path.filename().string();
        }

        model_aliases = params_base.model_alias;
        model_tags    = params_base.model_tags;

        // propagate new defaults back to caller
        params = params_base;

        if (!is_resume) {
            return init();
        }

        return true;
    }

    // unlike load_model(), this is only called once during initialization
    bool init() {
        GGML_ASSERT(ctx != nullptr);
        GGML_ASSERT(model != nullptr);
        GGML_ASSERT(!sleeping);

        // wiring up server queues
        queue_tasks.on_new_task([this](server_task && task) {
            process_single_task(std::move(task));
        });
        queue_tasks.on_update_slots([this]() {
            update_slots();
        });
        queue_tasks.on_sleeping_state([this](bool sleeping) {
            handle_sleeping_state(sleeping);
        });

        metrics.init();

        if (params_base.cache_idle_slots) {
            if (!params_base.kv_unified) {
                SRV_WRN("%s: --cache-idle-slots requires --kv-unified, disabling\n", __func__);
                params_base.cache_idle_slots = false;
            } else if (params_base.cache_ram_mib == 0) {
                SRV_WRN("%s: --cache-idle-slots requires --cache-ram, disabling\n", __func__);
                params_base.cache_idle_slots = false;
            } else {
                SRV_INF("%s: idle slots will be saved to prompt cache and cleared upon starting a new task\n", __func__);
                SRV_DBG("%s", "__TEST_TAG_CACHE_IDLE_SLOTS_ENABLED__\n");
            }
        }

        // populate webui settings
        {
            if (!params_base.webui_config_json.empty()) {
                try {
                    json_webui_settings = json::parse(params_base.webui_config_json);
                } catch (const std::exception & e) {
                    SRV_ERR("%s: failed to parse webui config: %s\n", __func__, e.what());
                    return false;
                }
            }
        }

        // populate chat template params
        {
            common_chat_templates_ptr chat_templates;

            try {
                chat_templates = common_chat_templates_init(model, params_base.chat_template);

                LOG_INF("%s: chat template, example_format: '%s'\n", __func__,
                    common_chat_format_example(chat_templates.get(), params_base.use_jinja, params_base.default_template_kwargs).c_str());

            } catch (const std::exception & e) {
                SRV_ERR("%s: chat template parsing error: %s\n", __func__, e.what());
                SRV_ERR("%s: please consider disabling jinja via --no-jinja, or use a custom chat template via --chat-template\n", __func__);
                SRV_ERR("%s: for example: --no-jinja --chat-template chatml\n", __func__);
                return false;
            }

            // thinking is enabled if:
            // 1. It's not explicitly disabled via --reasoning off
            // 2. The chat template supports it
            const bool template_supports_thinking = params_base.use_jinja && common_chat_templates_support_enable_thinking(chat_templates.get());
            const bool enable_thinking = params_base.enable_reasoning != 0 && template_supports_thinking;
            SRV_INF("%s: chat template, thinking = %d\n", __func__, enable_thinking);

            chat_params = {
                /* use_jinja             */ params_base.use_jinja,
                /* prefill_assistant     */ params_base.prefill_assistant,
                /* reasoning_format      */ params_base.reasoning_format,
                /* chat_template_kwargs  */ params_base.default_template_kwargs,
                /* tmpls                 */ std::move(chat_templates),
                /* allow_image           */ mctx ? mtmd_support_vision(mctx) : false,
                /* allow_audio           */ mctx ? mtmd_support_audio (mctx) : false,
                /* enable_thinking       */ enable_thinking,
                /* reasoning_budget      */ params_base.sampling.reasoning_budget_tokens,
                /* reasoning_budget_msg  */ params_base.sampling.reasoning_budget_message,
                /* reasoning_budget_sfx  */ params_base.sampling.reasoning_budget_suffix,
                /* media_path            */ params_base.media_path,
                /* force_pure_content    */ params_base.force_pure_content_parser
            };
        }

        return true;
    }

    server_slot * get_slot_by_id(int id_slot) {
        // note: allow id_slot to be out of bounds (wrap around)
        id_slot = id_slot % slots.size();

        for (server_slot & slot : slots) {
            if (slot.id == id_slot) {
                return &slot;
            }
        }

        return nullptr;
    }

    // The prompt takes the slot's cached token ids where its text continues them (server_tokens_reuse_text): a
    // follow-up whose history renders the previous reply back into other tokens then extends the slot's prompt
    // instead of parting from it inside the reply and prefilling the reply again.
    void reuse_cached_text(const server_slot & slot, server_task & task) {
        if (task.type != SERVER_TASK_TYPE_COMPLETION || !task.params.cache_prompt || task.tokens.has_mtmd ||
                slot.prompt.tokens.has_mtmd || slot.prompt.tokens.empty()) {
            return;
        }
        const size_t n_before = slot.prompt.tokens.get_common_prefix(task.tokens);
        if (n_before == slot.prompt.tokens.size()) {
            return;
        }
        llama_tokens tokens = task.tokens.get_tokens();
        // text for normal and byte tokens only: the chat prompt keeps a control token's spelling in content literal
        const size_t n_after = server_tokens_reuse_text(slot.prompt.tokens.get_tokens(), tokens, [&](llama_token t) {
            const auto attr = llama_vocab_get_attr(vocab, t);
            const bool text = (attr & (LLAMA_TOKEN_ATTR_NORMAL | LLAMA_TOKEN_ATTR_BYTE)) &&
                !(attr & (LLAMA_TOKEN_ATTR_CONTROL | LLAMA_TOKEN_ATTR_USER_DEFINED | LLAMA_TOKEN_ATTR_UNKNOWN |
                          LLAMA_TOKEN_ATTR_UNUSED));
            return text ? common_token_to_piece(ctx, t, false) : std::string();
        });
        if (n_after == n_before) {
            return;
        }
        // the prompt's tokens [n_before, end of the replaced text) became the cached [n_before, n_after)
        const int64_t delta = int64_t(tokens.size()) - int64_t(task.tokens.size());
        const int64_t replaced_end = int64_t(n_after) - delta;
        if (task.n_shared_prefix >= replaced_end) {
            task.n_shared_prefix += delta;
        } else if (task.n_shared_prefix > int64_t(n_before)) {
            task.n_shared_prefix = int64_t(n_before);
        }
        SLT_INF(slot, "prompt text continues the cached tokens: shared %zu -> %zu of %zu cached tokens, prompt %zu -> %zu tokens\n",
                n_before, n_after, slot.prompt.tokens.size(), task.tokens.size(), tokens.size());
        task.tokens = server_tokens(tokens, false);
    }

    server_slot * get_available_slot(server_task & task) {
        server_slot * ret = nullptr;

        bool update_cache = false;

        // find the slot that has at least n% prompt similarity
        if (ret == nullptr && slot_prompt_similarity != 0.0f) {
            float sim_best = 0;

            for (server_slot & slot : slots) {
                // skip the slot if it is not available
                if (slot.is_processing()) {
                    continue;
                }

                const auto & tokens = slot.prompt.tokens;

                // skip the slot if it does not contains cached tokens
                if (tokens.empty()) {
                    continue;
                }

                // fraction of the Longest Common Prefix length with respect to the input prompt length
                const float sim_cur = float(tokens.get_common_prefix(task.tokens)) / task.tokens.size();

                // select the current slot if the criteria match
                if (sim_cur > sim_best && sim_cur > slot_prompt_similarity) {
                    sim_best = sim_cur;

                    ret = &slot;
                }
            }

            if (ret != nullptr) {
                const float f_keep = (sim_best*task.tokens.size()) / ret->prompt.tokens.size();

                SLT_INF(*ret, "selected slot by LCP similarity, sim_best = %.3f (> %.3f thold), f_keep = %.3f\n",
                        sim_best, slot_prompt_similarity, f_keep);

                // if we are about to lose a large portion of the existing context - save it in the prompt cache
                if (f_keep < 0.5f) {
                    update_cache = true;
                }
            }
        }

        // find the slot that has been least recently used
        if (ret == nullptr) {
            int64_t t_last = -1;

            for (server_slot & slot : slots) {
                // skip the slot if it is not available
                if (slot.is_processing()) {
                    continue;
                }

                // select the current slot if the criteria match
                if (!ret || slot.t_last_used <= t_last) {
                    t_last = slot.t_last_used;
                    ret = &slot;
                }
            }

            if (ret != nullptr) {
                SLT_INF(*ret, "selected slot by LRU, t_last = %" PRId64 "\n", t_last);

                update_cache = true;
            }
        }

        if (ret) {
            reuse_cached_text(*ret, task);

            const auto & tokens = ret->prompt.tokens;

            // cache prompts only for completion tasks
            const bool cache_task = prompt_cache && !guard_enabled() && task.type == SERVER_TASK_TYPE_COMPLETION;

            update_cache = update_cache && cache_task;

            // A state that cannot be rolled back reuses the slot's prompt only up to its end or one of its
            // checkpoints, so a cached prompt (a shared prefix, an earlier conversation) may do better even when
            // the slot's prompt is similar: look whenever the new prompt does not just extend the slot's.
            const bool look = cache_task && ret->ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL &&
                tokens.get_common_prefix(task.tokens) < tokens.size();

            if (update_cache || look) {
                SRV_WRN("%s", "updating prompt cache\n");

                const int64_t t_start = ggml_time_us();

                // don't save the slot's state if its context is empty
                if (update_cache && tokens.size() > 0) {
                    ret->prompt_save(*prompt_cache);
                }

                if (!ret->prompt_load(*prompt_cache, task.tokens)) {
                    ret->prompt_clear(false);
                }

                prompt_cache->update();

                SRV_WRN("prompt cache update took %.2f ms\n", (ggml_time_us() - t_start) / 1000.0);
            }
        }

        return ret;
    }

    // return true if at least one slot has been cleared
    // TODO: improve logic
    //       - smarter decision which slot to clear (LRU or longest prompt?)
    //       - move slot to level 2 cache instead of removing?
    //       - instead of purging, try to store and resume later?
    bool try_clear_idle_slots() {
        bool res = false;

        if (!params_base.kv_unified) {
            return res;
        }

        for (auto & slot : slots) {
            if (slot.is_processing()) {
                continue;
            }

            if (slot.prompt.n_tokens() > 0) {
                SRV_WRN("purging slot %d with %zu tokens\n", slot.id, slot.prompt.tokens.size());

                slot.prompt_clear(false);

                res = true;

                // clear slots one by one
                break;
            }
        }

        return res;
    }

    std::vector<common_adapter_lora_info> construct_lora_list(const std::map<int, float> & config) const {
        std::vector<common_adapter_lora_info> output = params_base.lora_adapters; // copy
        for (size_t i = 0; i < output.size(); ++i) {
            auto it = config.find(i);
            if (it != config.end()) {
                output[i].scale = it->second;
            } else {
                output[i].scale = 0.0f;
            }
        }
        return output;
    }

    bool launch_slot_with_task(server_slot & slot, server_task && task) {
        // Rejected launches need not pass through release()/reset().
        slot.reset_guard();
        slot.k3_protocol = {};

        // process per-request lora adapters
        if (!task.params.lora.empty()) {
            auto task_loras = construct_lora_list(task.params.lora);
            if (!are_lora_equal(task_loras, slot.lora)) {
                // if lora has changed, check to see if the cache should be cleared
                if (lora_should_clear_cache(slot.lora, task_loras)) {
                    SLT_INF(slot, "clearing cache for lora change. %zu loras -> %zu loras\n", slot.lora.size(), task.params.lora.size());
                    slot.prompt.tokens.clear();
                } else {
                    SLT_INF(slot, "keeping cache for alora. %zu target loras\n", task_loras.size());
                }
                slot.lora = task_loras;
            }
        } else {
            slot.lora = params_base.lora_adapters;
        }

        // if using alora, make sure it's only a single one requested and active
        size_t alora_invocation_start = task.tokens.size();
        if (lora_all_alora(slot.lora)) {
            const auto & enabled_ids = lora_get_enabled_ids(slot.lora);
            // TODO: This will error out if a user requests two aloras, but only
            // provides the activation string for one. We could, instead search
            // for all requested alora activation strings and then either keep
            // only the last one, or reject if multiple are found.
            if (enabled_ids.size() != 1) {
                send_error(task, "Cannot run multiple aLoRAs in a single request", ERROR_TYPE_INVALID_REQUEST);
                return false;
            }
            const auto & lora = slot.lora[enabled_ids[0]].ptr;

            // get the pointer and count for the invocation tokens
            const uint64_t      n_invocation_tokens = llama_adapter_get_alora_n_invocation_tokens(lora);
            const llama_token * invocation_tokens   = llama_adapter_get_alora_invocation_tokens  (lora);

            // scan backwards through the prompt tokens to find the last
            // occurrence of the invocation sequence
            int match_idx = static_cast<int>(n_invocation_tokens) - 1;
            for (int i = task.tokens.size() - 1; i >= 0; --i) {
                // the token in this position matches the next token to find in
                // the invocation sequence
                if (task.tokens[i] == invocation_tokens[match_idx]) {
                    // if it's a full match, we've found the start
                    if (match_idx == 0) {
                        alora_invocation_start = i;
                        break;
                    }
                    // otherwise, check the next token in the sequence
                    --match_idx;
                } else {
                    // no match in this position, so start looking over again
                    match_idx = static_cast<int>(n_invocation_tokens) - 1;
                }
            }

            // if the activation string is not found, disable the alora
            if (alora_invocation_start == task.tokens.size()) {
                SLT_DBG(slot, "alora %zu requested, but not found. deactivating\n", enabled_ids[0]);
                slot.lora[enabled_ids[0]].scale = 0.0f;
            } else {
                SLT_DBG(slot, "alora %zu activated starting at %zu\n", enabled_ids[0], alora_invocation_start);
                slot.alora_invocation_start = alora_invocation_start;
            }
        }

        if (!task.tokens.validate(ctx)) {
            send_error(task, "Prompt contains invalid tokens", ERROR_TYPE_INVALID_REQUEST);
            return false;
        }

        if (sampler_struct_top1.config.active() && task.need_sampling()) {
            try {
                const auto & config = sampler_struct_top1.config;
                if ((config.protocol_tags || config.force_response) && common_grammar_needs_prefill(task.params.sampling.grammar)) {
                    throw std::invalid_argument("K3 protocol tags currently support ordinary chat, not tool/schema generation profiles");
                }
                // Declared tools (tool_choice other than none) admit the template's tool section;
                // tool_choice=required makes it mandatory, as the tool-call grammar does elsewhere.
                slot.k3_protocol.reset(task.params.sampling.generation_prompt, sampler_struct_top1.tokens,
                    k3_protocol_ids, config.protocol_tags, config.force_response,
                    task.params.chat_parser_params.parse_tool_calls, task.params.tool_call_required);
                if (slot.k3_protocol.observing()) {
                    if (task.tokens.has_mtmd) { throw std::invalid_argument("K3 protocol requires a text-only prompt"); }
                    const auto prefix = common_tokenize(vocab, task.params.sampling.generation_prompt, false, true);
                    server_expert_guard_verify_prefix(task.params.sampling.generation_prompt, prefix, task.tokens.get_text_tokens());
                }
                task.params.sampling.backend_sampling = false;
            } catch (const std::exception & e) {
                send_error(task, e.what(), ERROR_TYPE_INVALID_REQUEST);
                return false;
            }
        }

        if (guard_enabled()) {
            try {
                const auto * config = llama_k3_runtime_config_get(ctx);
                if (mctx || task.tokens.has_mtmd) { throw std::invalid_argument("K3 opener guard requires a text-only prompt"); }
                const auto prefix = common_tokenize(vocab, task.params.sampling.generation_prompt, false, true);
                server_expert_guard_verify_prefix(task.params.sampling.generation_prompt, prefix, task.tokens.get_text_tokens());
                const auto control = config->guard_control_tokens > 0
                    ? server_guard_control_token_ids(vocab) : llama_tokens{LLAMA_TOKEN_NULL, LLAMA_TOKEN_NULL};
                slot.expert_guard.reset(config->guard_tokens,
                    common_tokenize(vocab, "<|open|>response<|sep|>", false, true), config->guard_start_tokens,
                    config->guard_control_tokens, control[0], control[1]);
                slot.expert_guard.prime_current_prefix(prefix);
                slot.guard_prompt_primed = slot.expert_guard.opened();
                if (slot.guard_prompt_primed) { slot.guard_opened_after_token = 0; }
            } catch (const std::exception & e) { send_error(task, e.what(), ERROR_TYPE_INVALID_REQUEST); return false; }
        }

#if defined(LLAMA_SERVER_CUDA_MOE) && (defined(__GNUC__) || defined(__clang__))
        if (!task.is_child() && ggml_cuda_moe_ram_tier_request_begin) {
            ggml_cuda_moe_ram_tier_request_begin(
                    task.id >= 0 ? static_cast<uint64_t>(task.id) : 0);
        }
#endif
        if (!task.is_child()) {
            const bool defer_workspace = server_prefill_new_tokens_enabled() && task.need_sampling();
            if (!server_moe_phase_report(slot.ctx, "request_begin", task.id,
                    static_cast<uint32_t>(task.n_tokens()), !defer_workspace)) {
                send_error(task, "failed to prepare GPU memory for prompt processing", ERROR_TYPE_SERVER);
                return false;
            }
            slot.request_open    = true;
            slot.request_task_id = task.id;
        }

        SLT_DBG(slot, "launching slot : %s\n", safe_json_to_str(slot.to_json()).c_str());

        // initialize samplers
        if (task.need_sampling()) {
            try {
                slot.smpl.reset(common_sampler_init(model, task.params.sampling));
            } catch (std::exception & e) {
                std::string err_msg = std::string("Failed to initialize samplers: ") + e.what();
                slot.end_request();
                send_error(task, err_msg, ERROR_TYPE_INVALID_REQUEST);
                return false;
            }

            const bool need_logits = task.params.sampling.n_probs > 0;

            bool backend_sampling = true;

            backend_sampling &= task.params.sampling.backend_sampling;

            // TODO: speculative decoding requires multiple samples per batch - not supported yet
            backend_sampling &= !(slot.can_speculate() && common_speculative_n_max(slot.spec.get(), task.params.speculative) > 0);

            // TODO: getting post/pre sampling logits is not yet supported with backend sampling
            backend_sampling &= !need_logits;
            backend_sampling &= !sampler_struct_top1.config.active();

            // TODO: tmp until backend sampling is fully implemented
            if (backend_sampling) {
                llama_set_sampler(ctx, slot.id, common_sampler_get(slot.smpl.get()));
            } else {
                llama_set_sampler(ctx, slot.id, nullptr);
            }

            SLT_INF(slot, "sampler chain: %s\n", common_sampler_print(slot.smpl.get()).c_str());
        } else {
            slot.smpl.reset();
        }

        if (guard_enabled()) {
            // Only B requires a cold cross-request state. Inside one response,
            // switching the frozen policy preserves KV/recurrent continuity.
            llama_synchronize(ctx);
            if (!llama_memory_seq_rm(llama_get_memory(ctx), slot.id, -1, -1)) {
                llama_memory_clear(llama_get_memory(ctx), true);
            }
            slot.prompt.tokens.clear();
            slot.prompt.data.clear();
            slot.prompt.checkpoints.clear();
            slot.spec_ckpt.clear();
            slot.n_prompt_tokens_cache = 0;
            if (prompt_cache) { prompt_cache->states.clear(); }
            if (!llama_k3_runtime_guard_set(ctx, false)) {
                slot.end_request();
                send_error(task, "cannot restore K3 primary routing", ERROR_TYPE_SERVER);
                return false;
            }
            SLT_INF(slot, "opener guard cold start: tokens=%u, prompt_primed=%d, start_tokens=%u, control_tokens=%u\n",
                llama_k3_runtime_config_get(ctx)->guard_tokens, int(slot.guard_prompt_primed),
                llama_k3_runtime_config_get(ctx)->guard_start_tokens, llama_k3_runtime_config_get(ctx)->guard_control_tokens);
        }

        slot.task = std::make_unique<const server_task>(std::move(task));

        slot.state = slot.task->is_child()
            ? SLOT_STATE_WAIT_OTHER // wait for the parent to process prompt
            : SLOT_STATE_STARTED;

        // reset server kill-switch counter
        n_empty_consecutive = 0;

        SLT_INF(slot, "processing task, is_child = %d\n", slot.task->is_child());
        return true;
    }

    void emit_output_token(completion_token_output result, server_slot & slot) {
        const std::string token_str = result.text_to_send;

        // Optional per-token audit: preserve chat request/sampling semantics and
        // measure completion-to-completion latency without per-layer profiling.
        static const bool token_audit = [] {
            const char * value = std::getenv("LLAMA_KIMI_TOKEN_AUDIT");
            return value && std::strcmp(value, "1") == 0;
        }();
        if (token_audit) {
            std::fprintf(stderr, "[kimi_token_audit] {\"task\":%d,\"n\":%d,\"id\":%d,\"us\":%lld}\n",
                slot.task->id, slot.n_decoded, result.tok, (long long) ggml_time_us());
        }

        if (!token_str.empty() && llama_vocab_is_control(vocab, result.tok)) {
            slot.output_source.controls.push_back({slot.generated_text.size(),
                slot.generated_text.size() + token_str.size(), result.tok});
        }
        slot.generated_text += token_str;
        if (slot.task->params.return_tokens) {
            slot.generated_tokens.push_back(result.tok);
        }

        // check if there is incomplete UTF-8 character at the end
        bool incomplete = validate_utf8(slot.generated_text) < slot.generated_text.size();

        // search stop word and delete it
        if (!incomplete) {
            size_t pos = std::min(slot.n_sent_text, slot.generated_text.size());

            const std::string str_test = slot.generated_text.substr(pos);
            bool send_text = true;

            size_t stop_pos = slot.find_stopping_strings(str_test, token_str.size(), true);
            if (stop_pos != std::string::npos) {
                slot.generated_text.erase(
                    slot.generated_text.begin() + pos + stop_pos,
                    slot.generated_text.end());
                pos = std::min(slot.n_sent_text, slot.generated_text.size());
            } else if (slot.has_next_token && !llama_vocab_is_eog(vocab, result.tok)) {
                stop_pos = slot.find_stopping_strings(str_test, token_str.size(), false);
                send_text = stop_pos == std::string::npos;
            }

            if (send_text) {
                result.text_to_send = slot.generated_text.substr(pos, std::string::npos);
                slot.n_sent_text += result.text_to_send.size();
            } else {
                result.text_to_send = "";
            }

            slot.add_token(result);
            if (slot.task->params.stream) {
                send_partial_response(slot, result, false);
            }
        }

        if (result.text_to_send.find('\n') != std::string::npos) {
            slot.has_new_line = true;

            if (slot.task->params.t_max_predict_ms > 0 &&
                    (ggml_time_us() - slot.t_start_generation > 1000.0f*slot.task->params.t_max_predict_ms)) {
                slot.stop           = STOP_TYPE_LIMIT;
                slot.has_next_token = false;

                SLT_DBG(slot, "stopped by time limit, n_decoded = %d, t_max_predict_ms = %d ms\n",
                        slot.n_decoded, (int) slot.task->params.t_max_predict_ms);
            }
        }
    }

    void flush_loop_output_hold(server_slot & slot) {
        if (slot.stop == STOP_TYPE_WORD) {
            slot.loop_output_hold.clear();
            return;
        }

        while (!slot.loop_output_hold.empty()) {
            completion_token_output output = std::move(slot.loop_output_hold.front());
            slot.loop_output_hold.pop_front();

            // EOG controls generation but is never user-visible.
            if (llama_vocab_is_eog(vocab, output.tok)) {
                continue;
            }

            emit_output_token(std::move(output), slot);
            if (slot.stop == STOP_TYPE_WORD) {
                slot.loop_output_hold.clear();
                break;
            }
        }
    }

    bool process_token(completion_token_output & result, server_slot & slot) {
        const completion_token_output sampled_result = result;
        const std::string sampled_token_str = sampled_result.text_to_send;

        // The sampled token must immediately become the next model input even
        // while its user-visible representation remains in the rolling hold.
        slot.sampled = sampled_result.tok;
        slot.has_next_token = true;
        slot.loop_output_hold.push_back(sampled_result);

        int32_t matched_len = 0;
        const bool loop_triggered = common_sampler_loop_stop_triggered(slot.smpl.get(), &matched_len);
        if (loop_triggered && matched_len > 0) {
            const size_t removable = std::min<size_t>((size_t) matched_len, slot.loop_output_hold.size());
            for (size_t i = 0; i < removable; ++i) {
                slot.loop_output_hold.pop_back();
            }
            slot.loop_removed_tokens += removable;

            if (removable != (size_t) matched_len) {
                SLT_WRN(slot,
                        "loop_stop triggered for %d tokens, but only %zu unsent tokens remained; visible output may be incomplete\n",
                        matched_len, removable);
            } else {
                SLT_WRN(slot, "loop_stop suppressed repeated output block before streaming: %d tokens\n", matched_len);
            }
        }

        const int32_t hold_limit = std::max(0, common_sampler_loop_stop_min_len(slot.smpl.get()));
        if ((int32_t) slot.loop_output_hold.size() > hold_limit) {
            completion_token_output output = std::move(slot.loop_output_hold.front());
            slot.loop_output_hold.pop_front();
            emit_output_token(std::move(output), slot);
        }

        // if context shifting is disabled, make sure that we don't run out of context
        if (!params_base.ctx_shift && slot.prompt.n_tokens() + 1 >= slot.n_ctx) {
            slot.truncated      = true;
            slot.stop           = STOP_TYPE_LIMIT;
            slot.has_next_token = false;

            SLT_DBG(slot, "stopped due to running out of context capacity, prompt.n_tokens() = %d, task.n_tokens = %d, n_decoded = %d, n_ctx = %d\n",
                    slot.prompt.n_tokens(), slot.task->n_tokens(), slot.n_decoded, slot.n_ctx);
        }

        // check the limits
        if (slot.n_decoded > 0 && slot.has_next_token && !slot.has_budget(params_base)) {
            slot.stop           = STOP_TYPE_LIMIT;
            slot.has_next_token = false;

            SLT_DBG(slot, "stopped by limit, n_decoded = %d, n_predict = %d\n", slot.n_decoded, slot.task->params.n_predict);
        }

        if (slot.has_new_line) {
            // require that each new line has a whitespace prefix (i.e. indentation) of at least slot.params.n_indent
            if (slot.task->params.n_indent > 0) {
                if (slot.last_nl_pos > 0) {
                    size_t pos = slot.last_nl_pos;

                    int n_indent = 0;
                    while (pos < slot.generated_text.size() && (slot.generated_text[pos] == ' ' || slot.generated_text[pos] == '\t')) {
                        n_indent++;
                        pos++;
                    }

                    if (pos < slot.generated_text.size() && n_indent < slot.task->params.n_indent) {
                        slot.stop           = STOP_TYPE_LIMIT;
                        slot.has_next_token = false;
                        slot.generated_text.erase(pos, std::string::npos);

                        SLT_DBG(slot, "stopped by indentation limit, n_decoded = %d, n_indent = %d\n", slot.n_decoded, n_indent);
                    }
                }

                const size_t pos = slot.generated_text.find('\n', slot.last_nl_pos);
                if (pos != std::string::npos) {
                    slot.last_nl_pos = pos + 1;
                }
            }
        }

        if (llama_vocab_is_eog(vocab, sampled_result.tok)) {
            slot.stop           = STOP_TYPE_EOS;
            slot.has_next_token = false;

            SLT_DBG(slot, "%s", "stopped by EOS\n");
        }

        SLT_DBG(slot, "n_decoded = %d, n_remaining = %d, next token: %5d '%s'\n",
                slot.n_decoded, slot.n_remaining, sampled_result.tok, sampled_token_str.c_str());

        return slot.has_next_token;
    }

    void populate_token_probs(const server_slot & slot, completion_token_output & result, bool post_sampling, bool special, int idx) const {
        const size_t n_probs_request = slot.task->params.sampling.n_probs;

        if (post_sampling) {
            const auto * cur_p = common_sampler_get_candidates(slot.smpl.get(), true);
            const size_t max_probs = cur_p->size;
            const size_t n_probs = std::min(max_probs, n_probs_request);

            // set probability for sampled token
            for (size_t i = 0; i < max_probs; i++) {
                if (cur_p->data[i].id == result.tok) {
                    result.prob = cur_p->data[i].p;
                    break;
                }
            }

            // set probability for top n_probs tokens
            result.probs.reserve(n_probs);
            for (size_t i = 0; i < n_probs; i++) {
                result.probs.push_back({
                    cur_p->data[i].id,
                    common_token_to_piece(ctx, cur_p->data[i].id, special),
                    cur_p->data[i].p
                });
            }
        } else {
            // TODO: optimize this with min-p optimization
            std::vector<llama_token_data> cur = get_token_probabilities(ctx, idx);
            const size_t max_probs = cur.size();
            const size_t n_probs = std::min(max_probs, n_probs_request);

            // set probability for sampled token
            for (size_t i = 0; i < max_probs; i++) {
                // set probability for sampled token
                if (cur[i].id == result.tok) {
                    result.prob = cur[i].p;
                    break;
                }
            }

            // set probability for top n_probs tokens
            result.probs.reserve(n_probs);
            for (size_t i = 0; i < n_probs; i++) {
                result.probs.push_back({
                    cur[i].id,
                    common_token_to_piece(ctx, cur[i].id, special),
                    cur[i].p
                });
            }
        }
    }

    void send_error(const server_task & task, const std::string & error, const enum error_type type = ERROR_TYPE_SERVER) {
        send_error(task.id, error, type);
    }

    void send_error(const server_slot & slot, const std::string & error, const enum error_type type = ERROR_TYPE_SERVER) {
        send_error(slot.task->id, error, type, slot.task->n_tokens(), slot.n_ctx);
    }

    void send_error(const int id_task, const std::string & error, const enum error_type type = ERROR_TYPE_SERVER, const int32_t n_prompt_tokens = 0, const int32_t n_ctx = 0) {
        SRV_ERR("task id = %d, error: %s\n", id_task, error.c_str());

        if (type == ERROR_TYPE_EXCEED_CONTEXT_SIZE) {
            GGML_ASSERT(n_ctx > 0 && n_prompt_tokens > 0);
        }

        auto res = std::make_unique<server_task_result_error>();
        res->id              = id_task;
        res->err_type        = type;
        res->err_msg         = error;
        res->n_prompt_tokens = n_prompt_tokens;
        res->n_ctx           = n_ctx;

        queue_results.send(std::move(res));
    }

    // if multimodal is enabled, send an error and return false
    bool check_no_mtmd(const int id_task) {
        if (mctx) {
            send_error(id_task, "This feature is not supported by multimodal", ERROR_TYPE_NOT_SUPPORTED);
            return false;
        }
        return true;
    }

    void send_partial_response(server_slot & slot, const completion_token_output & tkn, bool is_progress) {
        auto res = std::make_unique<server_task_result_cmpl_partial>();

        res->id    = slot.task->id;
        res->index = slot.task->index;

        if (is_progress) {
            res->is_progress        = true;
            res->progress.total     = slot.task->n_tokens();
            res->progress.cache     = slot.n_prompt_tokens_cache;
            res->progress.processed = slot.prompt.tokens.size();
            res->progress.time_ms   = (ggml_time_us() - slot.t_start_process_prompt) / 1000;
        } else {
            res->content = tkn.text_to_send;
            res->tokens  = { tkn.tok };
            res->output_source = slot.output_source;
        }

        res->n_decoded             = slot.n_decoded;
        res->n_prompt_tokens       = slot.task->n_tokens();
        res->n_prompt_tokens_cache = slot.n_prompt_tokens_cache;
        res->post_sampling_probs   = slot.task->params.post_sampling_probs;

        res->verbose           = slot.task->params.verbose;
        res->res_type          = slot.task->params.res_type;
        res->oaicompat_model   = slot.task->params.oaicompat_model;
        res->oaicompat_cmpl_id = slot.task->params.oaicompat_cmpl_id;

        // populate res.probs_output
        if (slot.task->params.sampling.n_probs > 0) {
            res->prob_output = tkn; // copy the token probs
        }

        // populate timings if this is final response or timings_per_token is enabled
        if (slot.stop != STOP_TYPE_NONE || slot.task->params.timings_per_token) {
            res->timings = slot.get_timings();
        }

        queue_results.send(std::move(res));
    }

    void send_final_response(server_slot & slot) {
        if (guard_enabled()) {
            SLT_INF(slot, "opener guard summary: predictions=%" PRIu64 ", remaining=%u, opened_after_token=%" PRId64
                ", prompt_primed=%d, failed_decodes=%" PRIu64 ", start_predictions=%" PRIu64
                ", opener_predictions=%" PRIu64 ", overlap_predictions=%" PRIu64 ", start_remaining=%u"
                ", control_predictions=%" PRIu64 ", control_only_predictions=%" PRIu64 ", control_remaining=%u"
                ", control_triggers=%" PRIu64 "\n",
                slot.guard_predictions, slot.expert_guard.remaining(), slot.guard_opened_after_token,
                int(slot.guard_prompt_primed), slot.guard_failed_decodes, slot.guard_start_predictions,
                slot.guard_opener_predictions, slot.guard_overlap_predictions, slot.expert_guard.start_remaining(),
                slot.guard_control_predictions, slot.guard_control_only_predictions, slot.expert_guard.control_remaining(),
                slot.expert_guard.control_triggers());
        }
        slot.end_request();
        auto res = std::make_unique<server_task_result_cmpl_final>();

        res->id      = slot.task->id;
        res->id_slot = slot.id;

        res->index = slot.task->index;

        // Log the exact decoded generation before chat protocol parsing splits it
        // into reasoning/content/tool-call fields. JSON encoding keeps one record per line.
        if (server_raw_io_log_enabled()) {
            SLT_INF(slot, "raw_io id=%s output_pre_parser=%s\n",
                slot.task->params.oaicompat_cmpl_id.c_str(), json(slot.generated_text).dump().c_str());
        }

        // keep copy of last generated text for debugging purposes
        if (slots_debug) {
            slot.debug_generated_text = slot.generated_text;
        }

        res->output_source = slot.output_source;

        // in stream mode, content and tokens are already in last partial chunk
        if (slot.task->params.stream) {
            res->content     = "";
            res->tokens      = llama_tokens{};
        } else {
            res->content     = std::move(slot.generated_text);
            res->tokens      = std::move(slot.generated_tokens);
        }
        res->timings         = slot.get_timings();
        res->prompt          = slot.task->tokens.detokenize(ctx, true);
        res->response_fields = std::move(slot.task->params.response_fields);

        res->truncated             = slot.truncated;
        res->n_decoded             = slot.n_decoded;
        res->n_prompt_tokens       = slot.task->n_tokens();
        res->n_prompt_tokens_cache = slot.n_prompt_tokens_cache;
        res->n_tokens_cached       = slot.prompt.n_tokens();
        res->has_new_line          = slot.has_new_line;
        res->stopping_word         = slot.stopping_word;
        res->stop                  = slot.stop;
        res->post_sampling_probs   = slot.task->params.post_sampling_probs;

        res->verbose           = slot.task->params.verbose;
        res->stream            = slot.task->params.stream;
        res->include_usage     = slot.task->params.include_usage;
        res->res_type          = slot.task->params.res_type;
        res->oaicompat_model   = slot.task->params.oaicompat_model;
        res->oaicompat_cmpl_id = slot.task->params.oaicompat_cmpl_id;

        // populate res.probs_output
        if (slot.task->params.sampling.n_probs > 0) {
            if (!slot.task->params.stream && slot.stop == STOP_TYPE_WORD) {
                const llama_tokens stop_word_toks = common_tokenize(ctx, slot.stopping_word, false);

                size_t safe_offset = std::min(slot.generated_token_probs.size(), stop_word_toks.size());
                res->probs_output = std::vector<completion_token_output>(
                        slot.generated_token_probs.begin(),
                        slot.generated_token_probs.end() - safe_offset);
            } else {
                res->probs_output = std::vector<completion_token_output>(
                        slot.generated_token_probs.begin(),
                        slot.generated_token_probs.end());
            }
        }

        res->generation_params = slot.task->params; // copy the parameters

        queue_results.send(std::move(res));
    }

    void send_embedding(const server_slot & slot, const llama_batch & batch) {
        auto res = std::make_unique<server_task_result_embd>();
        res->id        = slot.task->id;
        res->index     = slot.task->index;
        res->n_tokens  = slot.task->n_tokens();
        res->res_type  = slot.task->params.res_type;

        const int n_embd_out = llama_model_n_embd_out(model);

        std::vector<float> embd_res(n_embd_out, 0.0f);

        for (int i = 0; i < batch.n_tokens; ++i) {
            if (!batch.logits[i] || batch.seq_id[i][0] != slot.id) {
                continue;
            }

            const float * embd = nullptr;
            if (llama_pooling_type(slot.ctx) == LLAMA_POOLING_TYPE_NONE) {
                embd = llama_get_embeddings_ith(ctx, i);
            } else {
                embd = llama_get_embeddings_seq(ctx, batch.seq_id[i][0]);
            }

            if (embd == nullptr) {
                SLT_ERR(slot, "failed to get embeddings, token = %d, seq_id = %d\n", batch.token[i], batch.seq_id[i][0]);

                res->embedding.push_back(std::vector<float>(n_embd_out, 0.0f));
                continue;
            }

            // normalize only when there is pooling
            if (llama_pooling_type(slot.ctx) != LLAMA_POOLING_TYPE_NONE) {
                common_embd_normalize(embd, embd_res.data(), n_embd_out, slot.task->params.embd_normalize);
                res->embedding.push_back(embd_res);
                break;
            }

            res->embedding.emplace_back(embd, embd + n_embd_out);
        }

        SLT_DBG(slot, "%s", "sending embeddings\n");

        queue_results.send(std::move(res));
    }

    void send_rerank(const server_slot & slot, const llama_batch & batch) {
        auto res = std::make_unique<server_task_result_rerank>();
        res->id       = slot.task->id;
        res->index    = slot.task->index;
        res->n_tokens = slot.task->n_tokens();

        for (int i = 0; i < batch.n_tokens; ++i) {
            if (!batch.logits[i] || batch.seq_id[i][0] != slot.id) {
                continue;
            }

            const float * embd = llama_get_embeddings_seq(ctx, batch.seq_id[i][0]);
            if (embd == NULL) {
                embd = llama_get_embeddings_ith(ctx, i);
            }

            if (embd == NULL) {
                SLT_ERR(slot, "failed to get embeddings, token = %d, seq_id = %d\n", batch.token[i], batch.seq_id[i][0]);

                res->score = -1e6;
                continue;
            }

            res->score = embd[0];
        }

        SLT_DBG(slot, "sending rerank result, res.score = %f\n", res->score);

        queue_results.send(std::move(res));
    }

    //
    // Functions to process the task
    //

    // tokenize the input if it's set by CLI, return false on error
    bool tokenize_cli_input(server_task & task) {
        try {
            auto & prompt = task.cli_prompt;
            if (mctx != nullptr) {
                task.tokens = process_mtmd_prompt(mctx, prompt, task.cli_files);
            } else {
                task.tokens = std::move(tokenize_input_prompts(vocab, mctx, prompt, true, true)[0]);
            }
            task.cli_prompt.clear();
            task.cli_files.clear();
        } catch (const std::exception & e) {
            send_error(task, std::string("Failed to format input: ") + e.what(), ERROR_TYPE_INVALID_REQUEST);
            return false;
        }
        return true;
    }

    std::vector<server_slot *> get_free_slots(size_t n_slots_needed, int exclude_id_slot) {
        std::vector<server_slot *> free_slots;
        for (auto & slot : slots) {
            if (!slot.is_processing() && slot.id != exclude_id_slot) {
                free_slots.push_back(&slot);
            }
            if (free_slots.size() >= n_slots_needed) {
                break;
            }
        }
        return free_slots;
    }

    // launch multiple slots for parent + child tasks
    bool launch_slots_with_parent_task(server_slot & parent_slot, std::vector<server_slot *> & child_slots, server_task && parent_task) {
        GGML_ASSERT(!parent_slot.is_processing());
        GGML_ASSERT(parent_task.is_parent());
        GGML_ASSERT(child_slots.size() == parent_task.child_tasks.size());

        int id_parent = parent_task.id;

        SRV_INF("launching slots for parent task id_task = %d with %zu child tasks\n", id_parent, parent_task.child_tasks.size());

        // to be called in case of failure to release all launched slots
        auto release_slots = [this, id_parent]() {
            for (auto & slot : slots) {
                if (slot.is_processing() && (
                        slot.task->id == id_parent ||
                        slot.task->id_parent == id_parent
                )) {
                    slot.release();
                }
            }
        };

        // launch all child tasks first
        size_t idx = 0;
        GGML_ASSERT(child_slots.size() == parent_task.child_tasks.size());
        for (auto * slot : child_slots) {
            int id_child = parent_task.child_tasks[idx].id;
            if (!launch_slot_with_task(*slot, std::move(parent_task.child_tasks[idx]))) {
                SRV_ERR("failed to launch slot with child task, id_task = %d\n", id_child);
                release_slots();
                return false;
            }
            idx++;
        }

        // finally, launch the parent task
        if (!launch_slot_with_task(parent_slot, std::move(parent_task))) {
            SRV_ERR("failed to launch slot with task, id_task = %d\n", id_parent);
            release_slots();
            return false;
        }

        return true;
    }

    // n_tokens_cur: the number of tokens added to the batch for the current slot
    void create_checkpoint(server_slot & slot, const int64_t n_tokens_cur, llama_pos pos_min, llama_pos pos_max) {
        if (checkpoint_room(slot, llama_state_seq_get_size_ext(ctx, slot.id, LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY))) {
            add_checkpoint(slot, server_get_checkpoint(ctx, slot.id, slot.prompt.n_tokens() - n_tokens_cur, pos_min, pos_max));
        }
    }

    // Checkpoints inside the prompt tokens of the slot that the last batch decoded, for a memory that can save an
    // earlier state (llama_state_seq_at_align), at the positions where a later prompt is likely to branch off: the
    // end of the prompt part other conversations share (the leading system messages and tools,
    // task->n_shared_prefix), a few tokens before the end of the prompt (the generation prompt may be rendered
    // differently in the next turn) and every checkpoint_every_nt tokens, each rounded down to a position the memory
    // can save. The shared prefix also goes to the prompt cache, where a conversation started later, or after a
    // restart, finds it.
    void checkpoint_decoded_prompt(server_slot & slot) {
        const int64_t n0 = slot.prompt_batch.n0;
        const int64_t n1 = slot.prompt_batch.n1;
        slot.prompt_batch.row_end = -1;

        const int64_t align    = checkpoint_at_align;
        const int64_t n_shared = slot.task->n_shared_prefix - slot.task->n_shared_prefix % align;

        std::vector<int64_t> at;
        const auto want = [&](int64_t n) {
            n -= n % align;
            if (n > n0 && n <= n1 && n >= 64) {
                at.push_back(n);
            }
        };
        if (n_shared > 0) {
            want(n_shared);
        }
        if (n1 == slot.task->n_tokens()) {
            want(n1 - 4);
        }
        if (params_base.checkpoint_every_nt > 0) {
            const int64_t every = params_base.checkpoint_every_nt;
            for (int64_t n = (n0/every + 1)*every; n <= n1; n += every) {
                want(n);
            }
        }
        std::sort(at.begin(), at.end());
        at.erase(std::unique(at.begin(), at.end()), at.end());

        for (const int64_t n : at) {
            const bool shared = n == n_shared;
            // no need to create checkpoints that are too close together
            if (!shared && !slot.prompt.checkpoints.empty() && n <= slot.prompt.checkpoints.back().n_tokens + 64) {
                continue;
            }
            if (!llama_state_seq_can_save_at(ctx, slot.id, n)) {
                SLT_WRN(slot, "cannot save the state after %" PRId64 " tokens\n", n);
                continue;
            }
            if (params_base.n_ctx_checkpoints > 0 &&
                    checkpoint_room(slot, llama_state_seq_get_size_at(ctx, slot.id, LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY, n))) {
                const llama_pos pos_min = slot.ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL ? n - 1 :
                    llama_state_seq_pos_min_at(ctx, slot.id, n);
                add_checkpoint(slot, server_get_checkpoint_at(ctx, slot.id, n, pos_min));
            }
            if (shared && prompt_cache) {
                server_prompt prefix;
                prefix.tokens = slot.prompt.tokens.clone();
                prefix.tokens.keep_first(n);
                SLT_INF(slot, "keeping the shared prompt prefix of %" PRId64 " tokens\n", n);
                prompt_cache->save(prefix, false, ctx, slot.id, slot.ctx_seq_rm_type);
                prompt_cache->update();
            }
        }
    }

    // Room for a new checkpoint of `bytes`, made before it is allocated: the oldest checkpoint goes when the slot
    // holds n_ctx_checkpoints, the RAM expert cache gives back what the memory limit requires, and failing that the
    // oldest checkpoints go too. False (the checkpoint is skipped) when even no checkpoints leave no room.
    bool checkpoint_room(server_slot & slot, size_t bytes) {
        auto erase_oldest = [&](const char * why) {
            const auto & cur = slot.prompt.checkpoints.front();
            SLT_WRN(slot, "erasing old context checkpoint (%s; pos_min = %d, pos_max = %d, n_tokens = %" PRId64 ", size = %.3f MiB)\n",
                    why, cur.pos_min, cur.pos_max, cur.n_tokens, (float) cur.data.size() / 1024 / 1024);
            slot.prompt.checkpoints.erase(slot.prompt.checkpoints.begin());
        };
        while (!slot.prompt.checkpoints.empty() && slot.prompt.checkpoints.size() >= (size_t) params_base.n_ctx_checkpoints) {
            erase_oldest("count");
        }
        while (!llama_host_reserve(ctx, bytes)) {
            if (slot.prompt.checkpoints.empty()) {
                SLT_WRN(slot, "skipping a context checkpoint of %.3f MiB: no room in the memory limit\n", (float) bytes / 1024 / 1024);
                return false;
            }
            erase_oldest("memory");
        }
        return true;
    }

    void add_checkpoint(server_slot & slot, server_prompt_checkpoint && checkpoint) {
        const auto & cur = slot.prompt.checkpoints.emplace_back(std::move(checkpoint));

        SLT_WRN(slot,
                "created context checkpoint %d of %d (pos_min = %d, pos_max = %d, n_tokens = %" PRId64 ", size = %.3f MiB)\n",
                (int) slot.prompt.checkpoints.size(), params_base.n_ctx_checkpoints, cur.pos_min,
                cur.pos_max, cur.n_tokens, (float) cur.data.size() / 1024 / 1024);
    }

    // Recurrent targets cannot commit a verifier batch directly: evaluating
    // several rows together can leave a different recurrent state than hard1
    // token-by-token decoding. Restore the one checkpoint taken before the
    // verifier block, discard its dirty tail, and rebuild only the prefix that
    // will actually remain in the target context. The final sampled token is
    // intentionally not decoded here; it remains slot.sampled for the next
    // generation step, matching the ordinary server path.
    bool recompute_speculative_prefix(server_slot & slot, const llama_tokens & accepted) {
        GGML_ASSERT(slot.ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL);
        GGML_ASSERT(!slot.spec_ckpt.empty());
        GGML_ASSERT(!accepted.empty());

        const auto & ckpt = slot.spec_ckpt;
        const size_t restored = llama_state_seq_set_data_ext(
            slot.ctx, ckpt.data.data(), ckpt.size(), slot.id,
            LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY);
        if (restored != ckpt.size()) {
            SLT_ERR(slot,
                    "failed to restore speculative checkpoint for sequential recompute "
                    "(pos_min = %d, pos_max = %d, size = %zu, restored = %zu)\n",
                    ckpt.pos_min, ckpt.pos_max, ckpt.size(), restored);
            return false;
        }

        const llama_pos pos0 = ckpt.pos_max + 1;
        if (!llama_memory_seq_rm(llama_get_memory(slot.ctx), slot.id, pos0, -1)) {
            SLT_ERR(slot, "failed to discard dirty verifier state from position %d\n", (int) pos0);
            return false;
        }

        slot.prompt.tokens.keep_first(ckpt.n_tokens);
        if (slot.prompt.tokens.pos_next() != pos0) {
            SLT_ERR(slot,
                    "speculative checkpoint token/position mismatch: n_tokens = %zu, "
                    "prompt pos_next = %d, checkpoint pos_next = %d\n",
                    ckpt.n_tokens, (int) slot.prompt.tokens.pos_next(), (int) pos0);
            return false;
        }

        llama_tokens replay;
        replay.reserve(accepted.size());
        replay.push_back(slot.sampled);
        replay.insert(replay.end(), accepted.begin(), accepted.end() - 1);

        llama_batch replay_batch = llama_batch_init(1, 0, 1);
        bool ok = true;
        for (size_t i = 0; i < replay.size(); ++i) {
            common_batch_clear(replay_batch);
            common_batch_add(
                replay_batch, replay[i], pos0 + (llama_pos) i, { slot.id }, false);

            const int ret = llama_decode(slot.ctx, replay_batch);
            metrics.on_decoded(slots);
            if (ret != 0) {
                SLT_ERR(slot,
                        "sequential speculative recompute failed at row %zu/%zu, ret = %d\n",
                        i + 1, replay.size(), ret);
                ok = false;
                break;
            }
            if (!common_speculative_process(slot.spec.get(), replay_batch, slot.id)) {
                SLT_ERR(slot,
                        "failed to inject target features during sequential speculative "
                        "recompute at row %zu/%zu\n",
                        i + 1, replay.size());
                ok = false;
                break;
            }
        }
        llama_batch_free(replay_batch);

        if (!ok) {
            return false;
        }

        slot.prompt.tokens.insert(replay);
        SLT_DBG(slot,
                "sequentially recomputed speculative prefix: rows = %zu, pos = [%d, %d]\n",
                replay.size(), (int) pos0, (int) (pos0 + replay.size() - 1));
        return true;
    }

    void process_single_task(server_task && task) {
        switch (task.type) {
            case SERVER_TASK_TYPE_COMPLETION:
            case SERVER_TASK_TYPE_INFILL:
            case SERVER_TASK_TYPE_EMBEDDING:
            case SERVER_TASK_TYPE_RERANK:
                {
                    if (guard_enabled() && (task.type != SERVER_TASK_TYPE_COMPLETION || task.params.n_cmpl != 1 ||
                            task.is_parent() || task.is_child() || task.params.speculative.type != COMMON_SPECULATIVE_TYPE_NONE ||
                            (task.params.res_type != TASK_RESPONSE_TYPE_NONE && task.params.res_type != TASK_RESPONSE_TYPE_OAI_CHAT &&
                             task.params.res_type != TASK_RESPONSE_TYPE_OAI_CMPL))) {
                        send_error(task, "K3 opener guard requires one native/OAI completion without speculation", ERROR_TYPE_INVALID_REQUEST);
                        break;
                    }
                    if (sampler_struct_top1.config.active() && task.params.speculative.type != COMMON_SPECULATIVE_TYPE_NONE) {
                        send_error(task, "K3 sampler structural top-1 requires non-speculative sampling", ERROR_TYPE_INVALID_REQUEST);
                        break;
                    }
                    // special case: if input is provided via CLI, tokenize it first
                    // otherwise, no need to tokenize as it's already done inside the HTTP thread
                    if (task.cli) {
                        if (!tokenize_cli_input(task)) {
                            break;
                        }
                    }

                    const int id_slot = task.id_slot;
                    const int id_task = task.id;

                    server_slot * slot = id_slot != -1 ? get_slot_by_id(id_slot) : get_available_slot(task);
                    if (slot != nullptr && id_slot != -1 && !slot->is_processing()) {
                        reuse_cached_text(*slot, task);
                    }

                    //
                    // slot scheduling logic
                    //

                    if (slot == nullptr) {
                        // if no slot is available, we defer this task for processing later
                        SRV_DBG("no slot is available, defer task, id_task = %d\n", id_task);
                        queue_tasks.defer(std::move(task));
                        break;
                    }

                    if (slot->is_processing()) {
                        // if requested slot is unavailable, we defer this task for processing later
                        SRV_DBG("requested slot is unavailable, defer task, id_task = %d\n", id_task);
                        queue_tasks.defer(std::move(task));
                        break;
                    }

                    if (task.is_parent()) {
                        // try getting free slots for all child tasks
                        size_t n_child_tasks = task.child_tasks.size();
                        std::vector<server_slot *> child_slots = get_free_slots(n_child_tasks, slot->id);
                        if (child_slots.size() < n_child_tasks) {
                            SRV_DBG("not enough free slots for child tasks, n_free = %zu, n_children = %zu, defer task, id_task = %d\n", child_slots.size(), n_child_tasks, id_task);
                            queue_tasks.defer(std::move(task));
                            break;
                        }
                        if (!launch_slots_with_parent_task(*slot, child_slots, std::move(task))) {
                            SRV_ERR("failed to launch slot with parent task, id_task = %d\n", id_task);
                            break; // drop the task
                        }
                    } else if (!launch_slot_with_task(*slot, std::move(task))) {
                        SRV_ERR("failed to launch slot with task, id_task = %d\n", id_task);
                        break; // drop the task
                    }

                    if (params_base.cache_idle_slots) {
                        for (auto & s : slots) {
                            if (!s.is_processing()) {
                                slot_save_and_clear(s);
                            }
                        }
                    }
                } break;
            case SERVER_TASK_TYPE_CANCEL:
                {
                    // release slot linked with the task id
                    for (auto & slot : slots) {
                        if (slot.task && slot.task->id == task.id_target) {
                            slot.release();
                            break;
                        }
                    }
                } break;
            case SERVER_TASK_TYPE_NEXT_RESPONSE:
                {
                    // do nothing
                } break;
            case SERVER_TASK_TYPE_METRICS:
                {
                    json slots_data = json::array();

                    int n_idle_slots       = 0;
                    int n_processing_slots = 0;

                    for (server_slot & slot : slots) {
                        json slot_data = slot.to_json(slots_debug == 0);

                        if (slot.is_processing()) {
                            n_processing_slots++;
                        } else {
                            n_idle_slots++;
                        }

                        slots_data.push_back(slot_data);
                    }
                    SRV_DBG("n_idle_slots = %d, n_processing_slots = %d\n", n_idle_slots, n_processing_slots);

                    auto res = std::make_unique<server_task_result_metrics>();
                    res->id                  = task.id;
                    res->slots_data          = std::move(slots_data);
                    res->n_idle_slots        = n_idle_slots;
                    res->n_processing_slots  = n_processing_slots;
                    res->n_tasks_deferred    = queue_tasks.queue_tasks_deferred_size();
                    res->t_start             = metrics.t_start;

                    res->n_prompt_tokens_processed_total = metrics.n_prompt_tokens_processed_total;
                    res->t_prompt_processing_total       = metrics.t_prompt_processing_total;
                    res->n_tokens_predicted_total        = metrics.n_tokens_predicted_total;
                    res->n_sampler_struct_top1_replacements_total = metrics.n_sampler_struct_top1_replacements_total;
                    res->n_sampler_struct_mixed_samples_total = metrics.n_sampler_struct_mixed_samples_total;
                    res->n_k3_constraint_conflicts_total = metrics.n_k3_constraint_conflicts_total;
                    res->n_k3_protocol_forced_tokens_total = metrics.n_k3_protocol_forced_tokens_total;
                    res->t_tokens_generation_total       = metrics.t_tokens_generation_total;

                    res->n_tokens_max = metrics.n_tokens_max;

                    res->n_prompt_tokens_processed = metrics.n_prompt_tokens_processed;
                    res->t_prompt_processing       = metrics.t_prompt_processing;
                    res->n_tokens_predicted        = metrics.n_tokens_predicted;
                    res->t_tokens_generation       = metrics.t_tokens_generation;

                    res->n_decode_total          = metrics.n_decode_total;
                    res->n_busy_slots_total      = metrics.n_busy_slots_total;

                    if (task.metrics_reset_bucket) {
                        metrics.reset_bucket();
                    }
                    queue_results.send(std::move(res));
                } break;
            case SERVER_TASK_TYPE_SLOT_SAVE:
                {
                    if (guard_enabled()) {
                        send_error(task, "K3 opener guard does not support slot files without a routing schedule identity", ERROR_TYPE_NOT_SUPPORTED);
                        break;
                    }
                    if (!check_no_mtmd(task.id)) {
                        break;
                    }

                    const int id_slot = task.slot_action.id_slot;
                    server_slot * slot = get_slot_by_id(id_slot);
                    if (slot == nullptr) {
                        send_error(task, "Invalid slot ID", ERROR_TYPE_INVALID_REQUEST);
                        break;
                    }
                    if (slot->is_processing()) {
                        // if requested slot is unavailable, we defer this task for processing later
                        SRV_DBG("requested slot is unavailable, defer task, id_task = %d\n", task.id);
                        queue_tasks.defer(std::move(task));
                        break;
                    }

                    const size_t token_count = slot->prompt.tokens.size();
                    const int64_t t_start = ggml_time_us();

                    std::string filename = task.slot_action.filename;
                    std::string filepath = task.slot_action.filepath;

                    const llama_tokens & tokens = slot->prompt.tokens.get_tokens();
                    const size_t nwrite = llama_state_seq_save_file(ctx, filepath.c_str(), slot->id, tokens.data(), token_count);

                    const int64_t t_end = ggml_time_us();
                    const double t_save_ms = (t_end - t_start) / 1000.0;

                    auto res = std::make_unique<server_task_result_slot_save_load>();
                    res->id       = task.id;
                    res->id_slot  = id_slot;
                    res->filename = filename;
                    res->is_save  = true;
                    res->n_tokens = token_count;
                    res->n_bytes  = nwrite;
                    res->t_ms     = t_save_ms;
                    queue_results.send(std::move(res));
                } break;
            case SERVER_TASK_TYPE_SLOT_RESTORE:
                {
                    if (guard_enabled()) {
                        send_error(task, "K3 opener guard does not support slot files without a routing schedule identity", ERROR_TYPE_NOT_SUPPORTED);
                        break;
                    }
                    if (!check_no_mtmd(task.id)) break;
                    const int id_slot = task.slot_action.id_slot;
                    server_slot * slot = get_slot_by_id(id_slot);
                    if (slot == nullptr) {
                        send_error(task, "Invalid slot ID", ERROR_TYPE_INVALID_REQUEST);
                        break;
                    }
                    if (slot->is_processing()) {
                        // if requested slot is unavailable, we defer this task for processing later
                        SRV_DBG("requested slot is unavailable, defer task, id_task = %d\n", task.id);
                        queue_tasks.defer(std::move(task));
                        break;
                    }

                    const int64_t t_start = ggml_time_us();

                    std::string filename = task.slot_action.filename;
                    std::string filepath = task.slot_action.filepath;

                    llama_tokens tokens;
                    tokens.resize(slot->n_ctx);
                    size_t token_count = 0;
                    size_t nread = llama_state_seq_load_file(ctx, filepath.c_str(), slot->id, tokens.data(), tokens.size(), &token_count);
                    if (nread == 0) {
                        slot->prompt.tokens.clear(); // KV may already been invalidated?
                        send_error(task, "Unable to restore slot, no available space in KV cache or invalid slot save file", ERROR_TYPE_INVALID_REQUEST);
                        break;
                    }
                    tokens.resize(token_count);
                    slot->prompt.tokens.clear();
                    slot->prompt.tokens.insert(tokens);

                    const int64_t t_end = ggml_time_us();
                    const double t_restore_ms = (t_end - t_start) / 1000.0;

                    auto res = std::make_unique<server_task_result_slot_save_load>();
                    res->id       = task.id;
                    res->id_slot  = id_slot;
                    res->filename = filename;
                    res->is_save  = false;
                    res->n_tokens = token_count;
                    res->n_bytes  = nread;
                    res->t_ms     = t_restore_ms;
                    queue_results.send(std::move(res));
                } break;
            case SERVER_TASK_TYPE_SLOT_ERASE:
                {
                    if (!check_no_mtmd(task.id)) {
                        break;
                    }
                    const int id_slot = task.slot_action.id_slot;
                    server_slot * slot = get_slot_by_id(id_slot);
                    if (slot == nullptr) {
                        send_error(task, "Invalid slot ID", ERROR_TYPE_INVALID_REQUEST);
                        break;
                    }
                    if (slot->is_processing()) {
                        // if requested slot is unavailable, we defer this task for processing later
                        SRV_DBG("requested slot is unavailable, defer task, id_task = %d\n", task.id);
                        queue_tasks.defer(std::move(task));
                        break;
                    }

                    // Erase token cache
                    const size_t n_erased = slot->prompt.tokens.size();

                    slot->prompt_clear(false);

                    auto res = std::make_unique<server_task_result_slot_erase>();
                    res->id       = task.id;
                    res->id_slot  = id_slot;
                    res->n_erased = n_erased;
                    queue_results.send(std::move(res));
                } break;
            case SERVER_TASK_TYPE_GET_LORA:
                {
                    // TODO @ngxson : make lora_adapters a dedicated member of server_context
                    auto & loras = params_base.lora_adapters;
                    auto res = std::make_unique<server_task_result_get_lora>();
                    res->id = task.id;
                    for (size_t i = 0; i < loras.size(); ++i) {
                        auto & lora = loras[i];
                        std::string alora_invocation_string = "";
                        const uint64_t n_alora_tokens = llama_adapter_get_alora_n_invocation_tokens(lora.ptr);
                        llama_tokens alora_invocation_tokens;
                        if (n_alora_tokens) {
                            const llama_token * alora_tokens = llama_adapter_get_alora_invocation_tokens(lora.ptr);
                            for (uint64_t j = 0; j < n_alora_tokens; ++j) {
                                alora_invocation_string += common_token_to_piece(vocab, alora_tokens[j]);
                                alora_invocation_tokens.push_back(alora_tokens[j]);
                            }
                        }
                        res->loras.push_back(server_task_result_get_lora::lora{
                            lora,
                            alora_invocation_string,
                            alora_invocation_tokens,
                        });
                    }
                    queue_results.send(std::move(res));
                } break;
            case SERVER_TASK_TYPE_SET_LORA:
                {
                    auto new_loras = construct_lora_list(task.set_lora);
                    // logging
                    for (size_t i = 0; i < new_loras.size(); ++i) {
                        SRV_INF("set lora adapter idx=%zu scale=%f\n", i, new_loras[i].scale);
                    }
                    // TODO @ngxson : make lora_adapters a dedicated member of server_context
                    params_base.lora_adapters = new_loras;
                    auto res = std::make_unique<server_task_result_apply_lora>();
                    res->id = task.id;
                    queue_results.send(std::move(res));
                } break;
        }
    }

    void update_slots() {
        // check if all slots are idle
        {
            bool all_idle = true;

            for (auto & slot : slots) {
                if (slot.is_processing()) {
                    all_idle = false;
                    break;
                }
            }

            if (all_idle) {
                SRV_INF("%s", "all slots are idle\n");

                return;
            }
        }

        {
            SRV_DBG("%s", "posting NEXT_RESPONSE\n");

            server_task task(SERVER_TASK_TYPE_NEXT_RESPONSE);
            task.id = queue_tasks.get_new_id();
            queue_tasks.post(std::move(task));
        }

        // apply context-shift if needed
        // TODO: simplify and improve
        for (server_slot & slot : slots) {
            if (slot.state == SLOT_STATE_GENERATING && slot.prompt.n_tokens() + 1 >= slot.n_ctx) {
                if (!params_base.ctx_shift) {
                    // this check is redundant (for good)
                    // we should never get here, because generation should already stopped in process_token()
                    send_error(slot, "context shift is disabled", ERROR_TYPE_SERVER);
                    slot.release();
                    continue;
                }

                if (mctx) {
                    // we should never reach this because params_base.ctx_shift is automatically disabled if mmproj is loaded
                    // we don't support ctx_shift because an image chunk may contains multiple tokens
                    GGML_ABORT("not supported by multimodal");
                }

                if (slot.task->is_parent() || slot.task->is_child()) {
                    send_error(slot, "context shift cannot be used for shared prompt", ERROR_TYPE_SERVER);
                    slot.release();
                    continue;
                }

                // Shift context
                int n_keep = slot.task->params.n_keep < 0 ? slot.task->n_tokens() : slot.task->params.n_keep;

                if (add_bos_token) {
                    n_keep += 1;
                }

                n_keep = std::min(slot.n_ctx - 4, n_keep);

                const int n_left    = slot.prompt.n_tokens() - n_keep;
                const int n_discard = slot.task->params.n_discard ? slot.task->params.n_discard : (n_left / 2);

                SLT_WRN(slot, "slot context shift, n_keep = %d, n_left = %d, n_discard = %d\n", n_keep, n_left, n_discard);

                llama_memory_seq_rm (llama_get_memory(ctx), slot.id, n_keep            , n_keep + n_discard);
                llama_memory_seq_add(llama_get_memory(ctx), slot.id, n_keep + n_discard, slot.prompt.n_tokens(), -n_discard);

                // add generated tokens to cache
                // ref: https://github.com/ggml-org/llama.cpp/pull/16818#discussion_r2473269481
                {
                    GGML_ASSERT(!slot.prompt.tokens.has_mtmd);

                    llama_tokens new_tokens = slot.prompt.tokens.get_tokens(); // copy
                    for (size_t i = n_keep + n_discard; i < new_tokens.size(); i++) {
                        new_tokens[i - n_discard] = new_tokens[i];
                    }

                    new_tokens.resize(slot.prompt.tokens.size() - n_discard);

                    slot.prompt.tokens.clear();
                    slot.prompt.tokens.insert(new_tokens);
                }

                slot.truncated = true;
            }
        }

        // start populating the batch for this iteration
        common_batch_clear(batch);

        // track if given slot can be batched with slots already in the batch
        server_slot * slot_batched = nullptr;

        auto accept_special_token = [&](server_slot & slot, llama_token token) {
            return params_base.special ||
                slot.task->params.sampling.preserved_tokens.find(token) != slot.task->params.sampling.preserved_tokens.end();
        };

        // first, add sampled tokens from any ongoing sequences
        for (auto & slot : slots) {
            if (slot.state != SLOT_STATE_GENERATING) {
                continue;
            }

            // check if we can batch this slot with the previous one
            if (!slot_batched) {
                slot_batched = &slot;
            } else if (!slot_batched->can_batch_with(slot)) {
                continue;
            }

            slot.update_batch(batch);
        }

        // process in chunks of params.n_batch
        int32_t n_batch  = llama_n_batch(ctx);
        int32_t n_ubatch = llama_n_ubatch(ctx);

        bool mac_adaptive_prefill = false;
#if defined(__APPLE__)
        const char * mac_adaptive = std::getenv("LLAMA_MAC_ADAPTIVE_PREFILL");
        mac_adaptive_prefill = mac_adaptive && std::strcmp(mac_adaptive, "1") == 0 &&
            params_base.n_parallel == 1 && batch.n_tokens == 0;
#endif
        if (mac_adaptive_prefill) {
            for (const auto & slot : slots) {
                if (!slot.is_processing() || !slot.task || slot.state == SLOT_STATE_GENERATING) {
                    continue;
                }
                const int32_t ceiling = std::min(n_batch, n_ubatch);
                if (mac_prefill_task != slot.task->id) {
                    mac_prefill_task = slot.task->id;
                    mac_prefill_size = std::min(256, ceiling);
                    mac_prefill_previous_size = 0;
                    mac_prefill_previous_ms_per_token = 0;
                    mac_prefill_settled = false;
                    SRV_INF("mac_adaptive_prefill task=%d initial=%d ceiling=%d\n",
                            mac_prefill_task, mac_prefill_size, ceiling);
                }
                n_batch = std::min(n_batch, mac_prefill_size);
                break;
            }
        }

        float  alora_scale       = -1.0f;
        size_t alora_disabled_id = 0;

        // next, batch any pending prompts without exceeding n_batch
        if (params_base.cont_batching || batch.n_tokens == 0) {
            for (auto & slot : slots) {
                if (!slot.is_processing()) {
                    continue;
                }

                // check if we can batch this slot with the previous one
                if (slot_batched && !slot_batched->can_batch_with(slot)) {
                    continue;
                }

                // check if this is a child slot
                if (slot.state == SLOT_STATE_WAIT_OTHER) {
                    SLT_DBG(slot, "%s", "waiting for parent slot to complete\n");
                    continue;
                }

                // this slot still has a prompt to be processed
                if (slot.state == SLOT_STATE_PROCESSING_PROMPT || slot.state == SLOT_STATE_STARTED) {
                    const auto & input_tokens = slot.task->tokens;

                    // used to determine the number of tokens added to the batch for the current slot
                    const auto n_tokens_prev = batch.n_tokens;

                    // TODO: maybe move branch to outside of this loop in the future
                    if (slot.state == SLOT_STATE_STARTED) {
                        slot.t_start_process_prompt = ggml_time_us();
                        slot.t_start_generation = 0;

                        slot.state = SLOT_STATE_PROCESSING_PROMPT;

                        SLT_INF(slot, "new prompt, n_ctx_slot = %d, n_keep = %d, task.n_tokens = %d\n",
                                slot.n_ctx, slot.task->params.n_keep, slot.task->n_tokens());

                        // print prompt tokens (for debugging)
                        /*if (1) {
                            // first 16 tokens (avoid flooding logs)
                            for (int i = 0; i < std::min<int>(16, input_tokens.size()); i++) {
                                SLT_DBG(slot, "prompt token %3d: %6d '%s'\n", i, input_tokens[i], common_token_to_piece(ctx, input_tokens[i]).c_str());
                            }
                        } else {
                            // all
                            for (int i = 0; i < (int) input_tokens.size(); i++) {
                                SLT_DBG(slot, "prompt token %3d: %6d '%s'\n", i, input_tokens[i], common_token_to_piece(ctx, input_tokens[i]).c_str());
                            }
                        }*/

                        // keep track how many tokens we can reuse from the previous state
                        int n_past = 0;

                        // empty prompt passed -> release the slot and send empty response
                        if (input_tokens.empty()) {
                            SLT_WRN(slot, "%s", "empty prompt - releasing slot\n");

                            slot.print_timings();
                            send_final_response(slot);
                            slot.release();

                            continue;
                        }

                        // TODO: support memory-less logits computation
                        if (slot.task->need_logits() && !llama_get_memory(ctx)) {
                            send_error(slot, "the current context does not logits computation. skipping", ERROR_TYPE_SERVER);
                            slot.release();
                            continue;
                        }

                        if (!slot.can_split()) {
                            if (slot.task->n_tokens() > n_ubatch) {
                                send_error(slot,
                                           string_format(
                                               "input (%d tokens) is too large to process. increase the physical batch "
                                               "size (current batch size: %d)",
                                               slot.task->n_tokens(), n_ubatch),
                                           ERROR_TYPE_SERVER);
                                slot.release();
                                continue;
                            }

                            if (slot.task->n_tokens() > slot.n_ctx) {
                                send_error(
                                    slot,
                                    string_format(
                                        "input (%d tokens) is larger than the max context size (%d tokens). skipping",
                                        slot.task->n_tokens(), slot.n_ctx),
                                    ERROR_TYPE_EXCEED_CONTEXT_SIZE);
                                slot.release();
                                continue;
                            }
                        } else {
                            if (slot.task->n_tokens() >= slot.n_ctx) {
                                send_error(slot,
                                           string_format("request (%d tokens) exceeds the available context size (%d "
                                                         "tokens), try increasing it",
                                                         slot.task->n_tokens(), slot.n_ctx),
                                           ERROR_TYPE_EXCEED_CONTEXT_SIZE);
                                slot.release();
                                continue;
                            }

                            if (slot.task->params.cache_prompt) {
                                // reuse any previously computed tokens that are common with the new prompt
                                n_past = slot.prompt.tokens.get_common_prefix(input_tokens);

                                // if there is an alora invoked, don't cache after the invocation start
                                if (slot.alora_invocation_start > 0) {
                                    SLT_DBG(slot, "only caching to alora invocation start (n_past = %d, alora_invocation_start = %d)\n", n_past, slot.alora_invocation_start);
                                    n_past = std::min(n_past, slot.alora_invocation_start - 1);
                                }

                                const auto n_cache_reuse = slot.task->params.n_cache_reuse;

                                const bool can_cache_reuse =
                                    llama_memory_can_shift(llama_get_memory(ctx)) &&
                                    !slot.prompt.tokens.has_mtmd;

                                if (!can_cache_reuse && n_cache_reuse > 0) {
                                    SLT_WRN(slot, "cache reuse is not supported - ignoring n_cache_reuse = %d\n", n_cache_reuse);
                                }

                                // reuse chunks from the cached prompt by shifting their KV cache in the new position
                                if (can_cache_reuse && n_cache_reuse > 0) {
                                    GGML_ASSERT(!slot.prompt.tokens.has_mtmd);

                                    size_t head_c = n_past; // cache
                                    size_t head_p = n_past; // current prompt

                                    if (mctx) {
                                        // we should never reach this
                                        GGML_ABORT("not supported by multimodal");
                                    }

                                    SLT_DBG(slot, "trying to reuse chunks with size > %d, n_past = %d\n", n_cache_reuse, n_past);

                                    while (head_c < slot.prompt.tokens.size() &&
                                           head_p < input_tokens.size()) {

                                        size_t n_match = 0;
                                        while (head_c + n_match < slot.prompt.tokens.size() &&
                                               head_p + n_match < input_tokens.size()       &&
                                               slot.prompt.tokens[head_c + n_match] == input_tokens[head_p + n_match]) {
                                            n_match++;
                                        }

                                        if (n_match >= (size_t) n_cache_reuse) {
                                            SLT_INF(slot, "reusing chunk with size %zu, shifting KV cache [%zu, %zu) -> [%zu, %zu)\n", n_match, head_c, head_c + n_match, head_p, head_p + n_match);
                                            //for (size_t i = head_p; i < head_p + n_match; i++) {
                                            //    SLT_DBG(slot, "cache token %3zu: %6d '%s'\n", i, prompt_tokens[i], common_token_to_piece(ctx, prompt_tokens[i]).c_str());
                                            //}

                                            const int64_t kv_shift = (int64_t) head_p - (int64_t) head_c;

                                            llama_memory_seq_rm (llama_get_memory(ctx), slot.id, head_p, head_c);
                                            llama_memory_seq_add(llama_get_memory(ctx), slot.id, head_c, head_c + n_match, kv_shift);

                                            for (size_t i = 0; i < n_match; i++) {
                                                slot.prompt.tokens.set_token(head_p + i, slot.prompt.tokens[head_c + i]);
                                                n_past++;
                                            }

                                            head_c += n_match;
                                            head_p += n_match;
                                        } else {
                                            head_c += 1;
                                        }
                                    }

                                    SLT_DBG(slot, "after context reuse, new n_past = %d\n", n_past);
                                }
                            } else {
                                // if we don't cache the prompt, we have to remove all previous tokens
                                n_past = 0;
                            }

                            llama_pos pos_next = slot.prompt.tokens.pos_next(n_past);

                            // the largest pos_min required for a checkpoint to be useful
                            const auto pos_min_thold = std::max(0, pos_next - n_swa);

                            if (n_past > 0 && n_past < slot.prompt.n_tokens()) {
                                const auto pos_min = llama_memory_seq_pos_min(llama_get_memory(ctx), slot.id);
                                if (pos_min == -1) {
                                    SLT_WRN(slot, "n_past = %d, slot.prompt.tokens.size() = %d, seq_id = %d, pos_min = %d - forcing full prompt re-evaluation (non-standard attention architecture cache mismatch)\n", n_past, (int) slot.prompt.tokens.size(), slot.id, pos_min);
                                    // Non-standard attention (e.g. DeepSeek V4 CSA+HCA): cache state can be inconsistent. Safe fallback.
                                    pos_next = 0;
                                    n_past  = 0;
                                }

                                // when the prompt prefix does not match, print the tokens around the mismatch
                                // this is useful for debugging prompt caching
                                if (slots_debug) {
                                    const int np0 = std::max<int>(n_past - 4, 0);
                                    const int np1 = std::min<int>(n_past + 6, std::min(slot.prompt.tokens.size(), slot.task->tokens.size()));

                                    std::stringstream ss0;
                                    std::stringstream ss1;

                                    std::stringstream st0;
                                    std::stringstream st1;

                                    ss0 << "old: ... ";
                                    ss1 << "new: ... ";

                                    for (int i = np0; i < np1; i++) {
                                        if (i == n_past) {
                                            ss0 << " | ";
                                            ss1 << " | ";
                                        }

                                        {
                                            const auto token = slot.prompt.tokens[i];
                                            const auto piece = token != LLAMA_TOKEN_NULL ? common_token_to_piece(ctx, token) : "[mtmd]";
                                            ss0 << piece;
                                            st0 << std::setw(8) << token;
                                        }

                                        {
                                            const auto token = slot.task->tokens[i];
                                            const auto piece = token != LLAMA_TOKEN_NULL ? common_token_to_piece(ctx, token) : "[mtmd]";
                                            ss1 << piece;
                                            st1 << std::setw(8) << token;
                                        }
                                    }

                                    SLT_WRN(slot, "%s\n", ss0.str().c_str());
                                    SLT_WRN(slot, "%s\n", ss1.str().c_str());

                                    SLT_WRN(slot, "%s\n", st0.str().c_str());
                                    SLT_WRN(slot, "%s\n", st1.str().c_str());
                                }

                                if (pos_min >= pos_min_thold) {
                                    SLT_WRN(slot, "n_past = %d, slot.prompt.tokens.size() = %d, seq_id = %d, pos_min = %d, n_swa = %d\n", n_past, (int) slot.prompt.tokens.size(), slot.id, pos_min, n_swa);

                                    // search for a context checkpoint
                                    const auto it = std::find_if(
                                        slot.prompt.checkpoints.rbegin(),
                                        slot.prompt.checkpoints.rend(),
                                        [&, func_name = __func__](const auto & cur) {
                                            // guarantee that a checkpoint will result in at least one token being processed [TAG_PROMPT_LOGITS]
                                            LOG_INF("slot %12.*s: id %2d | task %d | Checking checkpoint with [%d, %d] against %d...\n", 12,
                                                func_name, (slot).id, ((slot).task ? (slot).task->id : -1), cur.pos_min, cur.pos_max, pos_min_thold);
                                            if (slot.ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL) {
                                                // a state that cannot be rolled back resumes exactly where it was saved, so the
                                                // checkpoint has to lie inside the common prefix and leave a prompt token to process;
                                                // the window margin below is for sliding-window states that are truncated after loading
                                                return cur.pos_max < pos_next && cur.n_tokens < (int64_t) slot.task->n_tokens();
                                            }
                                            return cur.pos_min < pos_min_thold || cur.pos_min == 0;
                                        }
                                    );

                                    bool do_reset = it == slot.prompt.checkpoints.rend();

                                    if (!do_reset) {
                                        // restore the context checkpoint
                                        const size_t checkpoint_size = it->data.size();
                                        const size_t n = llama_state_seq_set_data_ext(ctx, it->data.data(), checkpoint_size, slot.id, LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY);

                                        if (n != checkpoint_size) {
                                            SLT_ERR(slot, "failed to restore context checkpoint (pos_min = %d, pos_max = %d, n_tokens = %" PRId64 ", size = %.3f MiB)\n", it->pos_min, it->pos_max, it->n_tokens, (float) checkpoint_size / 1024 / 1024);
                                            do_reset = true;
                                            //printf("[DEBUG] `do_reset` was set to `true` after failing to restore a checkpoint");
                                        } else {
                                            pos_next = std::min(pos_next, std::max(it->pos_min + 1, it->pos_max));
                                            n_past = std::min(slot.prompt.tokens.size_up_to_pos(pos_next), (size_t) it->n_tokens);
                                            SLT_WRN(slot, "restored context checkpoint (pos_min = %d, pos_max = %d, n_tokens = %" PRId64 ", n_past = %d, size = %.3f MiB)\n", it->pos_min, it->pos_max, it->n_tokens, n_past, (float) checkpoint_size / 1024 / 1024);
                                        }
                                    }

                                    if (do_reset) {
                                        SLT_WRN(slot, "forcing full prompt re-processing due to lack of cache data (likely due to SWA or hybrid/recurrent memory, see %s)\n",
                                                "https://github.com/ggml-org/llama.cpp/pull/13194#issuecomment-2868343055");
                                        pos_next = 0;
                                        n_past = 0;
                                    }
                                }
                            }

                            {
                                // erase any checkpoints with pos_max > pos_next
                                for (auto it = slot.prompt.checkpoints.begin(); it != slot.prompt.checkpoints.end();) {
                                    const auto & cur = *it;
                                    if (cur.pos_max > pos_next) {
                                        SLT_WRN(slot, "erased invalidated context checkpoint (pos_min = %d, pos_max = %d, n_tokens = %" PRId64 ", n_swa = %d, pos_next = %d, size = %.3f MiB)\n", cur.pos_min, cur.pos_max, cur.n_tokens, n_swa, pos_next, (float) cur.data.size() / 1024 / 1024);
                                        it = slot.prompt.checkpoints.erase(it);
                                    } else {
                                        ++it;
                                    }
                                }
                            }
                        }

                        // [TAG_PROMPT_LOGITS]
                        if (n_past == slot.task->n_tokens() && n_past > 0) {
                            SLT_WRN(slot, "need to evaluate at least 1 token for each active slot (n_past = %d, task.n_tokens() = %d)\n", n_past, slot.task->n_tokens());
                            n_past--;
                            SLT_WRN(slot, "n_past was set to %d\n", n_past);
                        }

                        slot.n_prompt_tokens_cache = n_past;
                        slot.n_prompt_tokens_processed = 0;

                        slot.prompt.tokens.keep_first(n_past);

                        // send initial 0% progress update if needed
                        // this is to signal the client that the request has started processing
                        if (slot.task->params.stream && slot.task->params.return_progress) {
                            send_partial_response(slot, {}, true);
                        }
                    }

                    if (!slot.can_split()) {
                        // cannot fit the prompt in the current batch - will try next iter
                        if (batch.n_tokens + slot.task->n_tokens() > n_batch) {
                            continue;
                        }
                    }

                    // truncate any tokens that are beyond n_past for this slot
                    const llama_pos p0 = slot.prompt.tokens.pos_next();

                    SLT_INF(slot, "n_tokens = %d, memory_seq_rm [%d, end)\n", slot.prompt.n_tokens(), p0);

                    if (!llama_memory_seq_rm(llama_get_memory(ctx), slot.id, p0, -1)) {
                        bool restored = false;

                        if (slot.ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL) {
                            const server_prompt_checkpoint * checkpoint = server_prompt_find_checkpoint_before_pos(slot.prompt, p0);

                            if (checkpoint != nullptr) {
                                const size_t checkpoint_size = checkpoint->data.size();
                                const size_t n = llama_state_seq_set_data_ext(ctx, checkpoint->data.data(), checkpoint_size, slot.id, LLAMA_STATE_SEQ_FLAGS_PARTIAL_ONLY);

                                if (n == checkpoint_size) {
                                    slot.prompt.tokens.keep_first(checkpoint->n_tokens);
                                    slot.n_prompt_tokens_cache = checkpoint->n_tokens;
                                    restored = true;
                                    SLT_WRN(slot, "restored context checkpoint after failed memory_seq_rm (pos_min = %d, pos_max = %d, n_tokens = %" PRId64 ", size = %.3f MiB)\n",
                                            checkpoint->pos_min, checkpoint->pos_max, checkpoint->n_tokens, (float) checkpoint_size / 1024 / 1024);
                                } else {
                                    SLT_ERR(slot, "failed to restore context checkpoint after failed memory_seq_rm (pos_min = %d, pos_max = %d, n_tokens = %" PRId64 ", size = %.3f MiB)\n",
                                            checkpoint->pos_min, checkpoint->pos_max, checkpoint->n_tokens, (float) checkpoint_size / 1024 / 1024);
                                }
                            }
                        }

                        if (!restored) {
                            SLT_WRN(slot, "failed to truncate tokens with position >= %d - clearing the memory\n", p0);

                            slot.prompt_clear(true);

                            // there is no common part left
                            slot.n_prompt_tokens_cache = 0;
                        }
                    }

                    // The cache decision can change again when sequence removal fails.
                    // Reserve only after the remaining prompt length is final.
                    if (server_prefill_new_tokens_enabled() && slot.task->need_sampling()) {
                        const uint32_t prompt_tokens = static_cast<uint32_t>(slot.task->n_tokens());
                        const uint32_t prefill_tokens = prompt_tokens -
                            static_cast<uint32_t>(slot.prompt.n_tokens());
                        if (!server_moe_workspace_transition(
                                slot.ctx, "request_begin", slot.task->id, prompt_tokens, prefill_tokens)) {
                            send_error(slot, "failed to prepare GPU memory for prompt processing", ERROR_TYPE_SERVER);
                            slot.release();
                            continue;
                        }
                        n_ubatch = llama_n_ubatch(ctx);
                    }

                    // If using an alora, there may be uncached tokens that come
                    // before the invocation sequence. When this happens, the
                    // tokens before the invocation sequence need to be
                    // processed without the adapter in a separate batch, then
                    // the adapter needs to be enabled for the remaining tokens.
                    if (lora_all_alora(slot.lora) && slot.alora_invocation_start - 1 > slot.prompt.n_tokens()) {
                        SLT_DBG(slot, "processing pre-alora tokens without the adapter (n_tokens = %d, alora_invocation_start = %d)\n", slot.prompt.n_tokens(), slot.alora_invocation_start);
                        const auto & enabled_loras = lora_get_enabled_ids(slot.lora);
                        GGML_ASSERT(enabled_loras.size() == 1);
                        alora_scale = slot.lora[enabled_loras[0]].scale;
                        slot.lora[enabled_loras[0]].scale = 0.0f;
                        alora_disabled_id = enabled_loras[0];
                    }

                    bool do_checkpoint = params_base.n_ctx_checkpoints > 0;

                    // make checkpoints only for completion tasks
                    do_checkpoint = do_checkpoint && slot.task->type == SERVER_TASK_TYPE_COMPLETION;

                    // make a checkpoint of the parts of the memory that cannot be rolled back.
                    // checkpoints are created only if:
                    // - the model does not support partial sequence removal
                    // - the model uses SWA (and we are not using `swa_full`)
                    do_checkpoint = do_checkpoint && (
                            (slot.ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL) ||
                            (n_swa > 0));

                    // A memory that can save an earlier state is checkpointed after the batch is decoded
                    // (checkpoint_decoded_prompt) rather than by stopping the batch at each checkpoint: with
                    // experts streamed from disk, every extra prompt batch streams the experts again.
                    const bool checkpoint_after_decode = checkpoint_at_align > 0 &&
                        slot.task->type == SERVER_TASK_TYPE_COMPLETION &&
                        (params_base.n_ctx_checkpoints > 0 || prompt_cache);
                    if (checkpoint_after_decode) {
                        do_checkpoint = false;
                    }

                    bool has_mtmd = false;

                    // check if we should process the image
                    while (slot.prompt.n_tokens() < slot.task->n_tokens() && input_tokens[slot.prompt.n_tokens()] == LLAMA_TOKEN_NULL) {
                        // process the image
                        size_t n_tokens_out = 0;
                        int32_t res = input_tokens.process_chunk(ctx, mctx, slot.prompt.n_tokens(), slot.prompt.tokens.pos_next(), slot.id, n_tokens_out);
                        if (res != 0) {
                            SLT_ERR(slot, "failed to process image, res = %d\n", res);
                            send_error(slot, "failed to process image", ERROR_TYPE_SERVER);
                            slot.release();
                            continue;
                        }

                        slot.n_prompt_tokens_processed += n_tokens_out;

                        // add the image chunk to cache
                        {
                            const auto & chunk = input_tokens.find_chunk(slot.prompt.n_tokens());
                            slot.prompt.tokens.push_back(chunk.get()); // copy
                        }

                        has_mtmd = true;
                    }

                    // add prompt tokens for processing in the current batch
                    while (slot.prompt.n_tokens() < slot.task->n_tokens() && batch.n_tokens < n_batch) {
                        // get next token to process
                        llama_token cur_tok = input_tokens[slot.prompt.n_tokens()];
                        if (cur_tok == LLAMA_TOKEN_NULL) {
                            break; // end of text chunk
                        }

                        // if this is an alora request with pre-invocation
                        // tokens that are not cached, we need to stop filling
                        // this batch at those pre-invocation tokens.
                        if (alora_scale > 0 && slot.prompt.n_tokens() == slot.alora_invocation_start - 1) {
                            SLT_DBG(slot, "stop prompt batch filling at (n_tokens = %d, alora_invocation_start = %d)\n", slot.prompt.n_tokens(), slot.alora_invocation_start);
                            break;
                        }

                        const bool is_last_prompt_token = slot.prompt.n_tokens() + 1 == slot.task->n_tokens();
                        if ((server_prompt_last_token_single_enabled() || slot.expert_guard.active()) && is_last_prompt_token && batch.n_tokens > 0) {
                            // Start or a prompt-primed opener must protect the logits predicting the first
                            // sampled token. Earlier prompt rows do not consume either budget.
                            // The DeepSeek-V4 MoE path can return bad first-token logits when the final prompt
                            // token is decoded together with earlier prompt tokens.
                            break;
                        }

                        // embedding requires all tokens in the batch to be output
                        common_batch_add(batch,
                            cur_tok,
                            slot.prompt.tokens.pos_next(),
                            { slot.id },
                            slot.task->need_embd());
                        slot.prompt.tokens.push_back(cur_tok);

                        slot.n_prompt_tokens_processed++;

                        // process the last few tokens of the prompt separately in order to allow for a checkpoint to be created.
                        // create checkpoints that many tokens before the end of the prompt:
                        //  - 4 + n_ubatch
                        //  - 4
                        // ref: https://github.com/ggml-org/llama.cpp/pull/20288
                        if (do_checkpoint) {
                            static const int checkpoint_offsets[] = {4 + n_ubatch, 4};

                            bool should_break = false;
                            for (int offset : checkpoint_offsets) {
                                const int n_last = std::min(n_batch, offset);
                                if (slot.task->n_tokens() == slot.prompt.n_tokens() + n_last) {
                                    should_break = true;
                                    break;
                                }
                            }
                            if (should_break) {
                                break;
                            }
                        }
                    }

                    // the number of tokens added to the batch for the current slot
                    const auto n_tokens_cur = batch.n_tokens - n_tokens_prev;

                    if (checkpoint_after_decode && n_tokens_cur > 0 && !has_mtmd) {
                        slot.prompt_batch.n0      = slot.prompt.n_tokens() - n_tokens_cur;
                        slot.prompt_batch.n1      = slot.prompt.n_tokens();
                        slot.prompt_batch.row_end = batch.n_tokens;
                    }

                    // entire prompt has been processed
                    if (slot.prompt.n_tokens() == slot.task->n_tokens()) {
                        slot.state = SLOT_STATE_DONE_PROMPT;

                        GGML_ASSERT(batch.n_tokens > 0);

                        // extract the logits only for the last token
                        batch.logits[batch.n_tokens - 1] = true;

                        slot.n_decoded = 0;
                        slot.i_batch   = batch.n_tokens - 1;

                        slot.init_sampler();
                        SLT_INF(slot, "prompt processing done, n_tokens = %d, batch.n_tokens = %d\n", slot.prompt.n_tokens(), batch.n_tokens);
                    } else {
                        if (slot.task->n_tokens() < slot.prompt.n_tokens() + n_ubatch) {
                            // near the end of the prompt
                            do_checkpoint = do_checkpoint && true;
                        } else {
                            // only do non-end checkpoints if the "checkpoint every n tokens" option is set
                            do_checkpoint = do_checkpoint && params_base.checkpoint_every_nt > 0;

                            if (do_checkpoint) {
                                llama_pos last_checkpoint = 0;
                                if (!slot.prompt.checkpoints.empty()) {
                                    last_checkpoint = slot.prompt.checkpoints.back().n_tokens;
                                }

                                do_checkpoint = do_checkpoint && slot.prompt.n_tokens() - batch.n_tokens - last_checkpoint >= params_base.checkpoint_every_nt;

                                if (do_checkpoint) {
                                    SLT_INF(slot, "%d tokens since last checkpoint at %d, creating new checkpoint during processing at position %d\n", params_base.checkpoint_every_nt, last_checkpoint, slot.prompt.n_tokens());
                                }
                            }
                        }

                        SLT_INF(slot, "prompt processing progress, n_tokens = %d, batch.n_tokens = %d, progress = %f\n", slot.prompt.n_tokens(), batch.n_tokens, (float) slot.prompt.n_tokens() / slot.task->n_tokens());
                    }

                    const auto pos_min = llama_memory_seq_pos_min(llama_get_memory(ctx), slot.id);
                    const auto pos_max = llama_memory_seq_pos_max(llama_get_memory(ctx), slot.id);

                    // no need for empty or small checkpoints
                    do_checkpoint = do_checkpoint && (pos_min >= 0 && slot.prompt.n_tokens() >= 64);

                    // do not checkpoint after mtmd chunks
                    do_checkpoint = do_checkpoint && !has_mtmd;

                    // no need to create checkpoints that are too close together
                    do_checkpoint = do_checkpoint && (slot.prompt.checkpoints.empty() || slot.prompt.n_tokens() - n_tokens_cur > slot.prompt.checkpoints.back().n_tokens + 64);
                    SLT_DBG(slot, "main/do_checkpoint = %s, pos_min = %d, pos_max = %d\n", do_checkpoint ? "yes" : "no", pos_min, pos_max);

                    // note: we create the checkpoint before calling llama_decode(), so the current batch is not
                    //       yet processed and therefore it is not part of the checkpoint.
                    if (do_checkpoint) {
                        create_checkpoint(slot, n_tokens_cur, pos_min, pos_max);
                    }
                }

                if (!slot_batched) {
                    slot_batched = &slot;
                }

                if (batch.n_tokens >= n_batch) {
                    break;
                }
            }
        }

        SRV_DBG("decoding batch, n_tokens = %d\n", batch.n_tokens);

        if (slot_batched) {
            // apply lora, only need to do it once per batch
            common_set_adapter_lora(ctx, slot_batched->lora);

            // if the lora is temporarily disabled for an alora, re-enable it
            // for next time
            if (alora_scale > 0.0f) {
                SRV_DBG("re-enabling alora with scale %f\n", alora_scale);
                slot_batched->lora[alora_disabled_id].scale = alora_scale;
            }

            llama_set_embeddings(ctx, slot_batched->task->need_embd());
        }

        if (batch.n_tokens == 0) {
            SRV_WRN("%s", "no tokens to decode\n");

            if (++n_empty_consecutive > 3) {
                GGML_ABORT("fatal error - please provide logs and repro in %s\n", "https://github.com/ggml-org/llama.cpp/pull/20277");
            }
        } else {
            n_empty_consecutive = 0;
        }

        int32_t i_next = 0;

        // process the created batch of tokens
        for (int32_t i = 0; i < batch.n_tokens; i = i_next) {
            const int32_t n_tokens = std::min(n_batch, batch.n_tokens - i);

            llama_batch batch_view = {
                n_tokens,
                batch.token    + i,
                nullptr,
                batch.pos      + i,
                batch.n_seq_id + i,
                batch.seq_id   + i,
                batch.logits   + i,
            };

            const bool predictive_row = slot_batched && slot_batched->i_batch >= i &&
                slot_batched->i_batch < i + n_tokens &&
                (slot_batched->state == SLOT_STATE_GENERATING || slot_batched->state == SLOT_STATE_DONE_PROMPT);
            const bool start_guarded = predictive_row && slot_batched->expert_guard.start_active();
            const bool opener_guarded = predictive_row && slot_batched->expert_guard.opener_active();
            const bool control_guarded = predictive_row && slot_batched->expert_guard.control_active();
            const bool guarded = start_guarded || opener_guarded || control_guarded;
            if (guard_enabled()) {
                GGML_ASSERT(!guarded || n_tokens == 1);
                if (!llama_k3_runtime_guard_set(ctx, guarded)) { GGML_ABORT("cannot select frozen K3 guard policy"); }
                if (slot_batched && (slot_batched->guard_last_selected != guarded ||
                        slot_batched->guard_last_start_selected != start_guarded ||
                        slot_batched->guard_last_opener_selected != opener_guarded ||
                        slot_batched->guard_last_control_selected != control_guarded)) {
                    SLT_INF(*slot_batched, "opener guard switch: active=%d, prediction=%d, remaining=%u"
                        ", start_active=%d, opener_active=%d, start_remaining=%u, control_active=%d, control_remaining=%u\n",
                        int(guarded), slot_batched->n_decoded + 1, slot_batched->expert_guard.remaining(),
                        int(start_guarded), int(opener_guarded), slot_batched->expert_guard.start_remaining(),
                        int(control_guarded), slot_batched->expert_guard.control_remaining());
                    slot_batched->guard_last_selected = guarded;
                    slot_batched->guard_last_start_selected = start_guarded;
                    slot_batched->guard_last_opener_selected = opener_guarded;
                    slot_batched->guard_last_control_selected = control_guarded;
                }
            }

            const int64_t mac_batch_start = mac_adaptive_prefill ? ggml_time_us() : 0;
            const int ret = llama_decode(ctx, batch_view);
            if (mac_adaptive_prefill && ret == 0 && n_tokens > 1) {
                llama_synchronize(ctx);
                const double elapsed_ms = double(ggml_time_us() - mac_batch_start) / 1000.0;
                const double ms_per_token = elapsed_ms / n_tokens;
                const int32_t used_size = mac_prefill_size;
                // Exclude short checkpoint/tail batches from size comparisons.
                if (n_tokens == used_size && !mac_prefill_settled) {
                    if (mac_prefill_previous_size > 0 && used_size > mac_prefill_previous_size &&
                            ms_per_token > 1.20 * mac_prefill_previous_ms_per_token) {
                        mac_prefill_size = mac_prefill_previous_size;
                        mac_prefill_settled = true;
                    } else {
                        mac_prefill_previous_size = used_size;
                        mac_prefill_previous_ms_per_token = ms_per_token;
                        const int32_t ceiling = std::min(llama_n_batch(ctx), llama_n_ubatch(ctx));
                        mac_prefill_size = std::min(ceiling, used_size * 2);
                    }
                }
                SRV_INF("mac_adaptive_prefill task=%d tokens=%d elapsed_ms=%.3f next=%d settled=%d\n",
                        mac_prefill_task, n_tokens, elapsed_ms, mac_prefill_size, int(mac_prefill_settled));
            }

            metrics.on_decoded(slots);

            if (ret != 0) {
                if (guard_enabled() && slot_batched) { ++slot_batched->guard_failed_decodes; }
                {
                    std::string err;

                    if (n_batch == 1 && ret == 1) {
                        // TODO: try to terminate only the largest active slot/sequence and continue with the rest
                        //       need to remove the tokens from the current batch too
                        err = "Context size has been exceeded.";
                    }

                    if (ret == -1) {
                        err = "Invalid input batch.";
                    }

                    if (ret < -1) {
                        // TODO: update slot state based on llama_memory_seq_pos_min() and llama_memory_seq_pos_max()
                        err = "Compute error.";
                    }

                    // TODO: handle ret == 2 (abort) when we start aborting

                    if (!err.empty()) {
                        SRV_ERR("%s i = %d, n_batch = %d, ret = %d\n", err.c_str(), i, n_batch, ret);

                        for (auto & slot : slots) {
                            if (slot.is_processing()) {
                                send_error(slot, err);
                                slot.release();

                                // note: it's complicated to keep track of how much of the current batch has been
                                //       processed before the error occurred, so we simply clear the entire context
                                slot.prompt_clear(false);
                            }
                        }

                        break;
                    }
                }

                // retry with half the batch size to try to find a free slot in the KV cache
                if (!try_clear_idle_slots()) {
                    n_batch /= 2;
                }

                SRV_WRN("failed to find free space in the KV cache, retrying with smaller batch size, i = %d, n_batch = %d, ret = %d\n", i, n_batch, ret);

                continue; // continue loop of n_batch
            }

            if (guarded) {
                ++slot_batched->guard_predictions;
                slot_batched->guard_start_predictions += start_guarded;
                slot_batched->guard_opener_predictions += opener_guarded;
                slot_batched->guard_overlap_predictions += start_guarded && opener_guarded;
                slot_batched->guard_control_predictions += control_guarded;
                // Existing overlap is S/O only. Adding control-only preserves
                // union = start + opener - overlap + control_only for all three.
                slot_batched->guard_control_only_predictions += control_guarded && !start_guarded && !opener_guarded;
                slot_batched->expert_guard.commit_forward(true);
            }

            for (auto & slot : slots) {
                if (slot.can_speculate() &&
                    !common_speculative_process(slot.spec.get(), batch_view, slot.id)) {
                    throw std::runtime_error("failed to process target-conditioned speculative batch");
                }
            }

            // move the head of the batch forward with the number of tokens we just processed
            i_next = i + n_tokens;

            for (auto & slot : slots) {
                if (slot.prompt_batch.row_end > 0 && slot.prompt_batch.row_end <= i_next && slot.task) {
                    checkpoint_decoded_prompt(slot);
                }
            }

            // on successful decode, restore the original batch size
            n_batch = llama_n_batch(ctx);
            if (mac_adaptive_prefill && mac_prefill_size > 0) {
                n_batch = std::min(n_batch, mac_prefill_size);
            }

            // handle `n_cmpl > 1` tasks - when the main prompt is processed, activate all child tasks too
            for (auto & slot : slots) {
                if (slot.state == SLOT_STATE_DONE_PROMPT && slot.task->is_parent()) {
                    std::vector<server_slot *> children;
                    for (auto & other : slots) {
                        if (other.state == SLOT_STATE_WAIT_OTHER && slot.task->id == other.task->id_parent) {
                            children.push_back(&other);
                        }
                    }

                    // all children slots should already launched by launch_slots_with_parent_task()
                    // copy state to the child slots
                    for (auto & child : children) {
                        SLT_INF(slot, " - copying state to child %d\n", child->id);

                        GGML_ASSERT(child->state == SLOT_STATE_WAIT_OTHER);

                        slot.copy_state_to(*child);
                        child->state = SLOT_STATE_DONE_PROMPT;
                    }
                }
            }

            for (auto & slot : slots) {
                // optionally send prompt processing progress
                if (slot.state == SLOT_STATE_PROCESSING_PROMPT || slot.state == SLOT_STATE_DONE_PROMPT) {
                    if (slot.task->params.stream && slot.task->params.return_progress) {
                        send_partial_response(slot, {}, true);
                    }
                }

                if (slot.i_batch < (int) i || slot.i_batch >= (int) (i + n_tokens)) {
                    continue; // continue loop of slots
                }

                if (slot.state == SLOT_STATE_DONE_PROMPT) {
                    if (slot.task->type == SERVER_TASK_TYPE_EMBEDDING) {
                        // prompt evaluated for embedding
                        send_embedding(slot, batch_view);
                        slot.release();
                        slot.i_batch = -1;
                        continue; // continue loop of slots
                    }

                    if (slot.task->type == SERVER_TASK_TYPE_RERANK) {
                        send_rerank(slot, batch_view);
                        slot.release();
                        slot.i_batch = -1;
                        continue; // continue loop of slots
                    }

                    GGML_ASSERT(slot.task->need_sampling());

                    // prompt evaluated for next-token prediction
                    server_moe_phase_report(
                        slot.ctx, "prefill_done", slot.task ? slot.task->id : -1);
                    slot.state = SLOT_STATE_GENERATING;

                    if (slot.can_speculate()) {
                        common_speculative_begin(slot.spec.get(), slot.prompt.tokens.get_text_tokens());
                    }
                } else if (slot.state != SLOT_STATE_GENERATING) {
                    continue; // continue loop of slots
                }

                if (slot.can_speculate() && !slot.spec_draft.empty()) {
                    continue; // sample using speculative decoding
                }

                const int tok_idx = slot.i_batch - i;

                llama_token id = LLAMA_TOKEN_NULL;
                auto next_protocol = slot.k3_protocol;
                const bool k3_active = sampler_struct_top1.config.active();
                const bool budget_forced = k3_active && common_sampler_is_budget_forcing(slot.smpl.get());
                const bool protocol_forced = k3_active && slot.k3_protocol.forcing();
                try {
                    if (k3_active) {
                        id = common_sampler_sample(slot.smpl.get(), slot.ctx, tok_idx, true,
                            [&](llama_token_data_array & candidates) { slot.k3_protocol.mask(candidates); });
                        const llama_token sampled = id;
                        const auto * q = common_sampler_get_candidates(slot.smpl.get(), false);
                        const auto replacement = sampler_struct_top1.apply(sampled, *q,
                            budget_forced || protocol_forced, slot.k3_protocol.is_label_token(sampled));
                        id = replacement.token;
                        // Validate and stage the observer before changing any live history.
                        next_protocol.accept(id);
                        const auto & sampled_info = sampler_struct_top1.tokens[sampled];
                        const auto & top1_info = sampler_struct_top1.tokens[replacement.top1];
                        metrics.n_sampler_struct_top1_replacements_total += replacement.replaced;
                        metrics.n_sampler_struct_mixed_samples_total += sampled_info.mixed;
                        metrics.n_k3_protocol_forced_tokens_total += protocol_forced;
                        if (replacement.replaced || sampled_info.mixed || budget_forced || protocol_forced) {
                            const json event = {
                                {"task", slot.task->id}, {"slot", slot.id}, {"prediction", slot.n_decoded + 1},
                                {"input_pos", batch_view.pos[tok_idx]}, {"output_pos", batch_view.pos[tok_idx] + 1},
                                {"sampled", sampled}, {"sampled_piece", sampled_info.bytes},
                                {"sampled_bytes_hex", server_struct_bytes_hex(sampled_info.bytes)},
                                {"sampled_p", replacement.sampled_p}, {"top1", replacement.top1},
                                {"top1_piece", top1_info.bytes}, {"top1_bytes_hex", server_struct_bytes_hex(top1_info.bytes)},
                                {"top1_p", replacement.top1_p}, {"final", id}, {"q_size", q->size},
                                {"probability_basis", "effective_q_before_projection"},
                                {"min_top1_p", sampler_struct_top1.config.min_top1_p},
                                {"sampled_mixed", sampled_info.mixed}, {"budget_forced", budget_forced},
                                {"protocol_forced", protocol_forced}, {"protocol_phase", slot.k3_protocol.name()},
                                {"replaced", replacement.replaced},
                                {"replacements_total", metrics.n_sampler_struct_top1_replacements_total}
                            };
                            SLT_INF(slot, "%s %s\n", replacement.replaced ? "sampler_struct_top1_replace" :
                                sampled_info.mixed ? "sampler_struct_mixed_sample" : "k3_sampler_forced",
                                event.dump(-1, ' ', true, json::error_handler_t::replace).c_str());
                        }
                    } else {
                        id = common_sampler_sample(slot.smpl.get(), slot.ctx, tok_idx);
                    }
                } catch (const std::exception & e) {
                    ++metrics.n_k3_constraint_conflicts_total;
                    const json event = {
                        {"task", slot.task->id}, {"slot", slot.id}, {"prediction", slot.n_decoded + 1},
                        {"input_pos", batch_view.pos[tok_idx]}, {"error", e.what()},
                        {"protocol_phase", slot.k3_protocol.name()}, {"stack", slot.k3_protocol.stack()},
                        {"label_bytes_hex", server_struct_bytes_hex(slot.k3_protocol.label_bytes())},
                        {"budget_forced", budget_forced}, {"protocol_forced", protocol_forced},
                        {"conflicts_total", metrics.n_k3_constraint_conflicts_total}
                    };
                    SLT_ERR(slot, "k3_constraint_conflict %s\n", event.dump().c_str());
                    send_error(slot, e.what(), ERROR_TYPE_SERVER);
                    slot.release();
                    slot.i_batch = -1;
                    continue;
                }

                slot.i_batch = -1;
                const bool reasoning_end_complete = k3_active && slot.k3_protocol.state() == server_k3_protocol::CLOSE_LABEL &&
                    next_protocol.state() == server_k3_protocol::AFTER_THINK;
                const bool reasoning_end_token = reasoning_end_complete || (k3_active &&
                    next_protocol.state() == server_k3_protocol::CLOSE_LABEL && next_protocol.stack().back() == "think");
                common_sampler_accept(slot.smpl.get(), id, true, reasoning_end_token, reasoning_end_complete);
                const char * token_trace = std::getenv("LLAMA_K3_SERVER_TOKEN_TRACE");
                if (token_trace && std::strcmp(token_trace, "1") == 0) {
                    SLT_INF(slot, "k3_output_token prediction=%d input_pos=%d token=%d budget_forced=%d protocol_forced=%d\n",
                        slot.n_decoded + 1, batch_view.pos[tok_idx], id, int(budget_forced), int(protocol_forced));
                }
                if (k3_active) { slot.k3_protocol = std::move(next_protocol); }
                const bool was_opened = slot.expert_guard.opened();
                const uint64_t control_triggers_before = slot.expert_guard.control_triggers();
                slot.expert_guard.accept_generated(id);
                if (!was_opened && slot.expert_guard.opened()) { slot.guard_opened_after_token = slot.n_decoded + 1; }
                if (slot.expert_guard.control_triggers() != control_triggers_before) {
                    SLT_INF(slot, "opener guard control trigger: token=%d, after_token=%d, remaining=%u, triggers=%" PRIu64 "\n",
                        id, slot.n_decoded + 1, slot.expert_guard.control_remaining(), slot.expert_guard.control_triggers());
                }

                // here we have synchronized the llama_context (due to the sampling above), so we can do time measurement
                const int64_t t_current = ggml_time_us();

                slot.n_decoded += 1;

                if (slot.n_decoded == 1) {
                    slot.t_start_generation = t_current;
                    slot.t_prompt_processing = (slot.t_start_generation - slot.t_start_process_prompt) / 1e3;
                    metrics.on_prompt_eval(slot);
                }

                slot.t_token_generation = std::max<int64_t>(1, t_current - slot.t_start_generation) / 1e3;

                completion_token_output result;
                result.tok          = id;
                result.text_to_send = common_token_to_piece(slot.ctx, result.tok, accept_special_token(slot, result.tok));
                result.prob         = 1.0f; // TODO: set it here instead of doing inside populate_token_probs

                if (slot.task->params.sampling.n_probs > 0) {
                    populate_token_probs(slot, result, slot.task->params.post_sampling_probs, params_base.special, tok_idx);
                }

                if (!process_token(result, slot)) {
                    // release slot because of stop condition
                    flush_loop_output_hold(slot);
                    slot.print_timings();
                    send_final_response(slot);
                    metrics.on_prediction(slot);
                    slot.release();

                    continue;
                }
            }

            // speculative decoding - main model sample and accept
            for (auto & slot : slots) {
                if (slot.state != SLOT_STATE_GENERATING || !slot.can_speculate() || slot.spec_draft.empty()) {
                    continue;
                }

                // save the original draft size
                const size_t n_draft = slot.spec_draft.size();

                GGML_ASSERT(n_draft > 0);

                bool spec_partial = false;
                bool spec_recomputed = false;
                size_t spec_argmax_checked = 0;
                size_t spec_argmax_matched = 0;
                size_t spec_accepted_argmax_checked = 0;
                size_t spec_accepted_argmax_matched = 0;
                double spec_recompute_ms = 0.0;

                // verify and try to accept the draft
                {
                    const bool use_ckpt = slot.ctx_seq_rm_type == COMMON_CONTEXT_SEQ_RM_TYPE_FULL;

                    GGML_ASSERT(slot.spec_i_batch.size() == n_draft + 1);

                    llama_tokens verifier_argmax;
                    verifier_argmax.reserve(slot.spec_i_batch.size());
                    const int32_t n_vocab = llama_vocab_n_tokens(vocab);
                    for (const int32_t i_batch : slot.spec_i_batch) {
                        const float * logits = llama_get_logits_ith(slot.ctx, i_batch);
                        if (logits == nullptr) {
                            verifier_argmax.push_back(LLAMA_TOKEN_NULL);
                            continue;
                        }
                        verifier_argmax.push_back((llama_token) std::distance(
                            logits, std::max_element(logits, logits + n_vocab)));
                    }

                    auto accepted = common_sampler_sample_and_accept_n(slot.smpl.get(), slot.ctx, slot.spec_i_batch, slot.spec_draft);
                    slot.spec_i_batch.clear();

                    SLT_DBG(slot, "%s: n_draft=%zu, accepted=%zu\n", __func__, slot.spec_draft.size(), accepted.size());

                    GGML_ASSERT(accepted.size() >= 1);

                    spec_partial = accepted.size() < slot.spec_draft.size() + 1;
                    spec_argmax_checked = accepted.size();
                    spec_accepted_argmax_checked = accepted.size() - 1;
                    for (size_t i = 0; i < accepted.size(); ++i) {
                        spec_argmax_matched += accepted[i] == verifier_argmax[i];
                        if (i < spec_accepted_argmax_checked) {
                            spec_accepted_argmax_matched += accepted[i] == verifier_argmax[i];
                        }
                    }

                    if (spec_partial && !use_ckpt) {
                        LOG_DBG("%s: partial acceptance: %zu < %zu\n", __func__, accepted.size(), slot.spec_draft.size());
                    }

                    if (use_ckpt) {
                        const int64_t t_recompute_start = ggml_time_us();
                        if (!recompute_speculative_prefix(slot, accepted)) {
                            throw std::runtime_error(
                                "failed to sequentially recompute speculative target prefix");
                        }
                        spec_recompute_ms = (ggml_time_us() - t_recompute_start) / 1e3;
                        spec_recomputed = true;
                    }

                    common_speculative_accept(slot.spec.get(), accepted.size() - 1);

                    slot.spec_draft = std::move(accepted);
                }

                const int64_t t_current = ggml_time_us();

                const auto ids = std::move(slot.spec_draft);

                slot.n_spec_blocks++;
                const double spec_step_ms = slot.t_spec_step_start_us > 0 ?
                    (t_current - slot.t_spec_step_start_us) / 1e3 : 0.0;
                SLT_INF(slot,
                        "speculative block audit: block=%" PRIu64 " proposed=%zu accepted=%zu "
                        "sampled=%zu accepted_argmax_matched=%zu accepted_argmax_checked=%zu "
                        "sampled_argmax_matched=%zu sampled_argmax_checked=%zu partial=%d "
                        "recomputed=%d replay_rows=%zu draft_ms=%.3f recompute_ms=%.3f "
                        "step_ms=%.3f semantics=batch-verifier\n",
                        slot.n_spec_blocks, n_draft, ids.size() - 1, ids.size(),
                        spec_accepted_argmax_matched, spec_accepted_argmax_checked,
                        spec_argmax_matched, spec_argmax_checked, spec_partial,
                        spec_recomputed, spec_recomputed ? ids.size() : 0,
                        slot.t_spec_draft_ms, spec_recompute_ms, spec_step_ms);
                slot.t_spec_step_start_us = 0;
                slot.t_spec_draft_ms = 0.0;

                slot.n_decoded += ids.size();
                slot.t_token_generation = std::max<int64_t>(1, t_current - slot.t_start_generation) / 1e3;

                // update how many tokens out of those tested were accepted
                slot.n_draft_accepted += ids.size() - 1;
                slot.n_draft_total += n_draft;

                // Recurrent targets have already rebuilt their committed prefix
                // token by token from the speculative checkpoint above.
                if (slot.ctx_seq_rm_type != COMMON_CONTEXT_SEQ_RM_TYPE_FULL) {
                    slot.prompt.tokens.keep_first(slot.prompt.n_tokens() - n_draft);
                    slot.prompt.tokens.insert({ids.begin(), ids.end() - 1});
                }

                slot.sampled = ids.back(); // last accepted token
                SLT_DBG(slot, "add accepted tokens: sampled=%d, ids.size=%zu, n_draft=%zu\n", slot.sampled, ids.size(), n_draft);

                llama_memory_seq_rm(llama_get_memory(slot.ctx), slot.id, slot.prompt.tokens.pos_next(), -1);

                for (size_t i = 0; i < ids.size(); ++i) {
                    completion_token_output result;

                    result.tok          = ids[i];
                    result.text_to_send = common_token_to_piece(slot.ctx, result.tok, accept_special_token(slot, result.tok));
                    result.prob         = 1.0f; // set later

                    // TODO: set result.probs

                    if (!process_token(result, slot)) {
                        flush_loop_output_hold(slot);
                        slot.print_timings();
                        send_final_response(slot);
                        metrics.on_prediction(slot);
                        slot.release();

                        break;
                    }
                }

                SLT_DBG(slot, "accepted %d/%d draft tokens, new n_tokens = %d\n", (int) ids.size() - 1, (int) n_draft, slot.prompt.n_tokens());
            }
        }

        SRV_DBG("%s", "run slots completed\n");
    }

    int get_slot_n_ctx() {
        return slots.back().n_ctx;
    }

    server_response_reader get_response_reader() {
        return server_response_reader(queue_tasks, queue_results, HTTP_POLLING_SECONDS);
    }
};

//
// server_context (public API)
//

server_context::server_context() : impl(new server_context_impl()) {}
server_context::~server_context() = default;

bool server_context::load_model(common_params & params) {
    return impl->load_model(params);
}

void server_context::start_loop() {
    auto & params = impl->params_base;
    impl->queue_tasks.start_loop(params.sleep_idle_seconds * 1000);
}

void server_context::terminate() {
    impl->queue_tasks.terminate();
}

llama_context * server_context::get_llama_context() const {
    return impl->ctx;
}

server_response_reader server_context::get_response_reader() {
    return impl->get_response_reader();
}

server_context_meta server_context::get_meta() const {
    auto bos_id = llama_vocab_bos(impl->vocab);
    auto eos_id = llama_vocab_eos(impl->vocab);
    auto bos_token_str = bos_id != LLAMA_TOKEN_NULL ? common_token_to_piece(impl->ctx, bos_id, true) : "";
    auto eos_token_str = eos_id != LLAMA_TOKEN_NULL ? common_token_to_piece(impl->ctx, eos_id, true) : "";

    return server_context_meta {
        /* build_info             */ std::string(llama_build_info()),
        /* model_name             */ impl->model_name,
        /* model_aliases          */ impl->model_aliases,
        /* model_tags             */ impl->model_tags,
        /* model_path             */ impl->params_base.model.path,
        /* has_mtmd               */ impl->mctx != nullptr,
        /* has_inp_image          */ impl->chat_params.allow_image,
        /* has_inp_audio          */ impl->chat_params.allow_audio,
        /* json_webui_settings    */ impl->json_webui_settings,
        /* slot_n_ctx             */ impl->get_slot_n_ctx(),
        /* pooling_type           */ llama_pooling_type(impl->ctx),

        /* chat_params            */ impl->chat_params,
        /* chat_template_caps     */ common_chat_templates_get_caps(impl->chat_params.tmpls.get()),

        /* bos_token_str          */ bos_token_str,
        /* eos_token_str          */ eos_token_str,
        /* fim_pre_token          */ llama_vocab_fim_pre(impl->vocab),
        /* fim_sub_token          */ llama_vocab_fim_suf(impl->vocab),
        /* fim_mid_token          */ llama_vocab_fim_mid(impl->vocab),
        /* fim_pad_token          */ llama_vocab_fim_pad(impl->vocab),
        /* fim_rep_token          */ llama_vocab_fim_rep(impl->vocab),
        /* fim_sep_token          */ llama_vocab_fim_sep(impl->vocab),

        /* logit_bias_eog         */ impl->params_base.sampling.logit_bias_eog,

        /* model_vocab_type       */ llama_vocab_type(impl->vocab),
        /* model_vocab_n_tokens   */ llama_vocab_n_tokens(impl->vocab),
        /* model_n_ctx_train      */ llama_model_n_ctx_train(impl->model),
        /* model_n_embd_inp       */ llama_model_n_embd(impl->model),
        /* model_n_params         */ llama_model_n_params(impl->model),
        /* model_size             */ llama_model_size(impl->model),
    };
}



// generator-like API for HTTP response generation
// may have bypass_sleep = true if the task does not use ctx_server
struct server_res_generator : server_http_res {
    server_response_reader rd;
    server_res_generator(server_queue & queue_tasks, server_response & queue_results, int sleep_idle_seconds, bool bypass_sleep = false)
            : rd(queue_tasks, queue_results, HTTP_POLLING_SECONDS) {
        // fast path in case sleeping is disabled
        bypass_sleep |= sleep_idle_seconds < 0;
        if (!bypass_sleep) {
            queue_tasks.wait_until_no_sleep();
        }
    }
    void ok(const json & response_data) {
        status = 200;
        data = safe_json_to_str(response_data);
    }
    void error(const json & error_data) {
        status = json_value(error_data, "code", 500);
        data = safe_json_to_str({{ "error", error_data }});
    }
};

void server_context::on_sleeping_changed(std::function<void(bool)> callback) {
    impl->queue_tasks.on_sleeping_state(std::move(callback));
}


//
// server_routes
//

std::unique_ptr<server_res_generator> server_routes::handle_completions_impl(
            const server_http_req & req,
            server_task_type type,
            const json & data,
            const std::vector<raw_buffer> & files,
            task_response_type res_type) {
    GGML_ASSERT(type == SERVER_TASK_TYPE_COMPLETION || type == SERVER_TASK_TYPE_INFILL);

    auto res = create_response();
    auto completion_id = gen_chatcmplid();
    auto & rd = res->rd;

    try {
        std::vector<server_task> tasks;

        const auto & prompt = data.at("prompt");
        if (server_raw_io_log_enabled()) {
            SRV_INF("raw_io id=%s input_pre_tokenizer=%s\n", completion_id.c_str(), prompt.dump().c_str());
        }

        // process prompt
        std::vector<server_tokens> inputs;
        int64_t n_shared_prefix = 0;

        if (res_type != TASK_RESPONSE_TYPE_NONE && ctx_server.mctx != nullptr) {
            // This is the case used by OAI compatible chat path with MTMD. TODO It can be moved to the path below.
            std::vector<llama_tokenize_input_span> spans;
            if (data.contains("chat_input_spans")) {
                // Validate legacy fallbacks and ranges before media processing.
                tokenize_chat_prompt(ctx_server.vocab, data);
                for (const auto & span : data.at("chat_input_spans")) {
                    spans.push_back({span.at(0).get<int32_t>(), span.at(1).get<int32_t>()});
                }
            }
            inputs.push_back(process_mtmd_prompt(ctx_server.mctx, prompt.get<std::string>(), files, spans));
        } else if (res_type != TASK_RESPONSE_TYPE_NONE && data.contains("chat_input_spans")) {
            inputs.emplace_back(tokenize_chat_prompt(ctx_server.vocab, data), false);
            n_shared_prefix = server_shared_prefix_tokens(ctx_server.vocab, data, inputs.back().get_tokens());
        } else {
            // Everything else, including multimodal completions.
            inputs = tokenize_input_prompts(ctx_server.vocab, ctx_server.mctx, prompt, true, true);
        }

        // tasks.reserve(inputs.size()); // TODO: this is inaccurate due to child tasks

        for (size_t i = 0; i < inputs.size(); i++) {
            server_task task = server_task(type);

            task.id = rd.get_new_id();

            task.tokens = std::move(inputs[i]);
            task.n_shared_prefix = n_shared_prefix;
            task.params = server_task::params_from_json_cmpl(
                    ctx_server.vocab,
                    params,
                    meta->slot_n_ctx,
                    meta->logit_bias_eog,
                    data);
            task.id_slot = json_value(data, "id_slot", -1);

            // OAI-compat
            task.params.res_type          = res_type;
            task.params.oaicompat_cmpl_id = completion_id;
            task.params.oaicompat_model   = meta->model_name;

            // prepare child tasks
            if (task.params.n_cmpl > 1) {
                int n_children = task.params.n_cmpl - 1;
                for (int j = 0; j < n_children; j++) {
                    task.add_child(task.id, rd.get_new_id());
                }
            }

            tasks.push_back(std::move(task));
        }

        rd.post_tasks(std::move(tasks));
    } catch (const std::exception & e) {
        res->error(format_error_response(e.what(), ERROR_TYPE_INVALID_REQUEST));
        return res;
    }

    bool stream = json_value(data, "stream", false);

    if (!stream) {
        // non-stream, wait for the results
        auto all_results = rd.wait_for_all(req.should_stop);
        if (all_results.is_terminated) {
            return res; // connection is closed
        } else if (all_results.error) {
            res->error(all_results.error->to_json());
            return res;
        } else {
            json arr = json::array();
            for (auto & res : all_results.results) {
                GGML_ASSERT(dynamic_cast<server_task_result_cmpl_final*>(res.get()) != nullptr);
                arr.push_back(res->to_json());
            }
            GGML_ASSERT(!arr.empty() && "empty results");
            if (arr.size() == 1) {
                // if single request, return single object instead of array
                res->ok(arr[0]);
            } else if (res_type == TASK_RESPONSE_TYPE_OAI_CHAT || res_type == TASK_RESPONSE_TYPE_OAI_CMPL) {
                // if multiple results in OAI format, we need to re-format them
                json & choices = arr[0]["choices"];
                for (size_t i = 1; i < arr.size(); i++) {
                    choices.push_back(std::move(arr[i]["choices"][0]));
                }
                res->ok(arr[0]);
            } else {
                // multi-results, non-OAI compat
                res->ok(arr);
            }
        }
    } else {
        // in streaming mode, the first error must be treated as non-stream response
        // this is to match the OAI API behavior
        // ref: https://github.com/ggml-org/llama.cpp/pull/16486#discussion_r2419657309
        auto first_result = rd.next(req.should_stop);
        if (first_result == nullptr) {
            GGML_ASSERT(req.should_stop());
            return res; // connection is closed
        }

        if (first_result->is_error()) {
            res->error(first_result->to_json());
            return res;
        }

        GGML_ASSERT(
            dynamic_cast<server_task_result_cmpl_partial*>(first_result.get()) != nullptr ||
            dynamic_cast<server_task_result_cmpl_final*>  (first_result.get()) != nullptr
        );

        // next responses are streamed
        // to be sent immediately
        json first_result_json = first_result->to_json();
        if (res_type == TASK_RESPONSE_TYPE_ANTHROPIC) {
            res->data = format_anthropic_sse(first_result_json);
        } else if (res_type == TASK_RESPONSE_TYPE_OAI_RESP) {
            res->data = format_oai_resp_sse(first_result_json);
        } else {
            res->data = format_oai_sse(first_result_json);
        }
        res->status = 200;
        res->content_type = "text/event-stream";
        res->next = [res_this = res.get(), res_type, &req](std::string & output) -> bool {
            static auto format_error = [](task_response_type res_type, const json & res_json) {
                if (res_type == TASK_RESPONSE_TYPE_ANTHROPIC) {
                    return format_anthropic_sse({
                        {"event", "error"},
                        {"data", res_json},
                    });
                } else {
                    return format_oai_sse(json {{ "error", res_json }});
                }
            };

            try {
                if (req.should_stop()) {
                    SRV_DBG("%s", "stopping streaming due to should_stop condition\n");
                    return false; // should_stop condition met
                }

                if (!res_this->data.empty()) {
                    // flush the first chunk
                    output = std::move(res_this->data);
                    res_this->data.clear();
                    return true;
                }

                server_response_reader & rd = res_this->rd;

                // check if there is more data
                if (!rd.has_next()) {
                    switch (res_type) {
                        case TASK_RESPONSE_TYPE_NONE:
                        case TASK_RESPONSE_TYPE_OAI_RESP:
                        case TASK_RESPONSE_TYPE_ANTHROPIC:
                            output = "";
                            break;

                        default:
                            output = "data: [DONE]\n\n";
                            break;
                    }
                    SRV_DBG("%s", "all results received, terminating stream\n");
                    return false; // no more data, terminate
                }

                // receive subsequent results
                auto result = rd.next(req.should_stop);
                if (result == nullptr) {
                    SRV_DBG("%s", "stopping streaming due to should_stop condition\n");
                    GGML_ASSERT(req.should_stop());
                    return false; // should_stop condition met
                }

                // send the results
                if (result->is_error()) {
                    json res_json = result->to_json();
                    output = format_error(res_type, res_json);
                    SRV_DBG("%s", "error received during streaming, terminating stream\n");
                    return false; // terminate on error
                } else {
                    GGML_ASSERT(
                        dynamic_cast<server_task_result_cmpl_partial*>(result.get()) != nullptr
                        || dynamic_cast<server_task_result_cmpl_final*>(result.get()) != nullptr
                    );
                    json res_json = result->to_json();
                    if (res_type == TASK_RESPONSE_TYPE_ANTHROPIC) {
                        output = format_anthropic_sse(res_json);
                    } else if (res_type == TASK_RESPONSE_TYPE_OAI_RESP) {
                        output = format_oai_resp_sse(res_json);
                    } else {
                        output = format_oai_sse(res_json);
                    }
                }

                // has next data, continue
                return true;

            } catch (const std::exception & e) {
                json error_json = format_error_response(e.what(), ERROR_TYPE_SERVER);
                output = format_error(res_type, error_json);

                // terminate on exception
                return false;
            }
        };
    }

    return res;
}

std::unique_ptr<server_res_generator> server_routes::create_response(bool bypass_sleep) {
    return std::make_unique<server_res_generator>(queue_tasks, queue_results, params.sleep_idle_seconds, bypass_sleep);
}

server_routes::server_routes(const common_params & params, server_context & ctx_server)
        : params(params),
          ctx_server(*ctx_server.impl),
          queue_tasks(ctx_server.impl->queue_tasks),
          queue_results(ctx_server.impl->queue_results) {
    init_routes();
}

void server_routes::init_routes() {
    // IMPORTANT: all lambda functions must start with create_response()
    // this is to ensure that the server_res_generator can handle sleeping case correctly

    this->get_health = [this](const server_http_req &) {
        // error and loading states are handled by middleware
        auto res = create_response(true);

        // this endpoint can be accessed during sleeping
        // the next LOC is to avoid someone accidentally use ctx_server
        bool ctx_server; // do NOT delete this line
        GGML_UNUSED(ctx_server);

        res->ok({{"status", "ok"}});
        return res;
    };

    this->get_metrics = [this](const server_http_req & req) {
        auto res = create_response();
        if (!params.endpoint_metrics) {
            res->error(format_error_response("This server does not support metrics endpoint. Start it with `--metrics`", ERROR_TYPE_NOT_SUPPORTED));
            return res;
        }

        // request slots data using task queue
        {
            server_task task(SERVER_TASK_TYPE_METRICS);
            task.id = res->rd.get_new_id();
            res->rd.post_task(std::move(task), true); // high-priority task
        }

        // get the result
        auto result = res->rd.next(req.should_stop);
        if (!result) {
            // connection was closed
            GGML_ASSERT(req.should_stop());
            return res;
        }

        if (result->is_error()) {
            res->error(result->to_json());
            return res;
        }

        // TODO: get rid of this dynamic_cast
        auto res_task = dynamic_cast<server_task_result_metrics*>(result.get());
        GGML_ASSERT(res_task != nullptr);

        // metrics definition: https://prometheus.io/docs/practices/naming/#metric-names
        json all_metrics_def = json {
            {"counter", {{
                    {"name",  "prompt_tokens_total"},
                    {"help",  "Number of prompt tokens processed."},
                    {"value",  (uint64_t) res_task->n_prompt_tokens_processed_total}
            }, {
                    {"name",  "prompt_seconds_total"},
                    {"help",  "Prompt process time"},
                    {"value",  (uint64_t) res_task->t_prompt_processing_total / 1.e3}
            }, {
                    {"name",  "tokens_predicted_total"},
                    {"help",  "Number of generation tokens processed."},
                    {"value",  (uint64_t) res_task->n_tokens_predicted_total}
            }, {
                    {"name",  "sampler_struct_top1_replacements_total"},
                    {"help",  "Structural non-top-1 samples projected to effective-distribution top-1."},
                    {"value", res_task->n_sampler_struct_top1_replacements_total}
            }, {
                    {"name", "sampler_struct_mixed_samples_total"},
                    {"help", "Mixed body/structure pieces sampled; never projected."},
                    {"value", res_task->n_sampler_struct_mixed_samples_total}
            }, {
                    {"name", "k3_constraint_conflicts_total"},
                    {"help", "Requests failed on an empty or inconsistent K3 sampling constraint."},
                    {"value", res_task->n_k3_constraint_conflicts_total}
            }, {
                    {"name", "k3_protocol_forced_tokens_total"},
                    {"help", "Protocol-forced tokens exempt from structural projection."},
                    {"value", res_task->n_k3_protocol_forced_tokens_total}
            }, {
                    {"name",  "tokens_predicted_seconds_total"},
                    {"help",  "Predict process time"},
                    {"value",  (uint64_t) res_task->t_tokens_generation_total / 1.e3}
            }, {
                    {"name",  "n_decode_total"},
                    {"help",  "Total number of llama_decode() calls"},
                    {"value",  res_task->n_decode_total}
            }, {
                    {"name",  "n_tokens_max"},
                    {"help",  "Largest observed n_tokens."},
                    {"value",  res_task->n_tokens_max}
            }, {
                    {"name",  "n_busy_slots_per_decode"},
                    {"help",  "Average number of busy slots per llama_decode() call"},
                    {"value",  (float) res_task->n_busy_slots_total / std::max((float) res_task->n_decode_total, 1.f)}
            }}},
            {"gauge", {{
                    {"name",  "prompt_tokens_seconds"},
                    {"help",  "Average prompt throughput in tokens/s."},
                    {"value",  res_task->n_prompt_tokens_processed ? 1.e3 / res_task->t_prompt_processing * res_task->n_prompt_tokens_processed : 0.}
            },{
                    {"name",  "predicted_tokens_seconds"},
                    {"help",  "Average generation throughput in tokens/s."},
                    {"value",  res_task->n_tokens_predicted ? 1.e3 / res_task->t_tokens_generation * res_task->n_tokens_predicted : 0.}
            },{
                    {"name",  "requests_processing"},
                    {"help",  "Number of requests processing."},
                    {"value",  (uint64_t) res_task->n_processing_slots}
            },{
                    {"name",  "requests_deferred"},
                    {"help",  "Number of requests deferred."},
                    {"value",  (uint64_t) res_task->n_tasks_deferred}
            }}}
        };

        std::stringstream prometheus;

        for (const auto & el : all_metrics_def.items()) {
            const auto & type        = el.key();
            const auto & metrics_def = el.value();

            for (const auto & metric_def : metrics_def) {
                const std::string name = metric_def.at("name");
                const std::string help = metric_def.at("help");

                auto value = json_value(metric_def, "value", 0.);
                prometheus << "# HELP llamacpp:" << name << " " << help  << "\n"
                            << "# TYPE llamacpp:" << name << " " << type  << "\n"
                            << "llamacpp:"        << name << " " << value << "\n";
            }
        }

        res->headers["Process-Start-Time-Unix"] = std::to_string(res_task->t_start);
        res->content_type = "text/plain; version=0.0.4";
        res->status = 200;
        res->data = prometheus.str();
        return res;
    };

    this->get_slots = [this](const server_http_req & req) {
        auto res = create_response();
        if (!params.endpoint_slots) {
            res->error(format_error_response("This server does not support slots endpoint. Start it with `--slots`", ERROR_TYPE_NOT_SUPPORTED));
            return res;
        }

        // request slots data using task queue
        {
            server_task task(SERVER_TASK_TYPE_METRICS);
            task.id = res->rd.get_new_id();
            res->rd.post_task(std::move(task), true); // high-priority task
        }

        // get the result
        auto result = res->rd.next(req.should_stop);
        if (!result) {
            // connection was closed
            GGML_ASSERT(req.should_stop());
            return res;
        }

        if (result->is_error()) {
            res->error(result->to_json());
            return res;
        }

        // TODO: get rid of this dynamic_cast
        auto * res_task = dynamic_cast<server_task_result_metrics*>(result.get());
        GGML_ASSERT(res_task != nullptr);

        // optionally return "fail_on_no_slot" error
        if (!req.get_param("fail_on_no_slot").empty()) {
            if (res_task->n_idle_slots == 0) {
                res->error(format_error_response("no slot available", ERROR_TYPE_UNAVAILABLE));
                return res;
            }
        }

        res->ok(res_task->slots_data);
        return res;
    };

    this->post_slots = [this](const server_http_req & req) {
        auto res = create_response();
        if (params.slot_save_path.empty()) {
            res->error(format_error_response("This server does not support slots action. Start it with `--slot-save-path`", ERROR_TYPE_NOT_SUPPORTED));
            return res;
        }

        std::string id_slot_str = req.get_param("id_slot");

        int id_slot;
        try {
            id_slot = std::stoi(id_slot_str);
        } catch (const std::exception &) {
            res->error(format_error_response("Invalid slot ID", ERROR_TYPE_INVALID_REQUEST));
            return res;
        }

        std::string action = req.get_param("action");

        if (action == "save") {
            return handle_slots_save(req, id_slot);
        }
        if (action == "restore") {
            return handle_slots_restore(req, id_slot);
        }
        if (action == "erase") {
            return handle_slots_erase(req, id_slot);
        }

        res->error(format_error_response("Invalid action", ERROR_TYPE_INVALID_REQUEST));
        return res;
    };

    this->get_props = [this](const server_http_req &) {
        auto res = create_response(true);

        // this endpoint can be accessed during sleeping
        // the next LOC is to avoid someone accidentally use ctx_server
        bool ctx_server; // do NOT delete this line
        GGML_UNUSED(ctx_server);

        task_params tparams;
        tparams.sampling = params.sampling;
        json default_generation_settings_for_props = json {
            { "params", tparams.to_json(true) },
            { "n_ctx",  meta->slot_n_ctx },
        };

        std::string tmpl_default = common_chat_templates_source(meta->chat_params.tmpls.get(), "");
        std::string tmpl_tools   = common_chat_templates_source(meta->chat_params.tmpls.get(), "tool_use");

        json props = {
            { "default_generation_settings", default_generation_settings_for_props },
            { "total_slots",                 params.n_parallel },
            { "model_alias",                 meta->model_name },
            { "model_path",                  meta->model_path },
            { "modalities",                  json {
                {"vision", meta->has_inp_image},
                {"audio",  meta->has_inp_audio},
            } },
            { "media_marker",                get_media_marker() },
            { "endpoint_slots",              params.endpoint_slots },
            { "endpoint_props",              params.endpoint_props },
            { "endpoint_metrics",            params.endpoint_metrics },
            { "webui",                       params.webui },
            { "webui_settings",              meta->json_webui_settings },
            { "chat_template",               tmpl_default },
            { "chat_template_caps",          meta->chat_template_caps },
            { "bos_token",                   meta->bos_token_str },
            { "eos_token",                   meta->eos_token_str },
            { "build_info",                  meta->build_info },
            { "is_sleeping",                 queue_tasks.is_sleeping() },
        };
        if (params.use_jinja) {
            if (!tmpl_tools.empty()) {
                props["chat_template_tool_use"] = tmpl_tools;
            }
        }
        res->ok(props);
        return res;
    };

    this->post_props = [this](const server_http_req &) {
        auto res = create_response();
        if (!params.endpoint_props) {
            res->error(format_error_response("This server does not support changing global properties. Start it with `--props`", ERROR_TYPE_NOT_SUPPORTED));
            return res;
        }
        // update any props here

        res->ok({{ "success", true }});
        return res;
    };

    this->post_infill = [this](const server_http_req & req) {
        auto res = create_response();
        // check model compatibility
        std::string err;
        if (llama_vocab_fim_pre(ctx_server.vocab) == LLAMA_TOKEN_NULL) {
            err += "prefix token is missing. ";
        }
        if (llama_vocab_fim_suf(ctx_server.vocab) == LLAMA_TOKEN_NULL) {
            err += "suffix token is missing. ";
        }
        if (llama_vocab_fim_mid(ctx_server.vocab) == LLAMA_TOKEN_NULL) {
            err += "middle token is missing. ";
        }
        if (!err.empty()) {
            res->error(format_error_response(string_format("Infill is not supported by this model: %s", err.c_str()), ERROR_TYPE_NOT_SUPPORTED));
            return res;
        }

        // validate input
        json data = json::parse(req.body);
        if (data.contains("prompt") && !data.at("prompt").is_string()) {
            // prompt is optional
            res->error(format_error_response("\"prompt\" must be a string", ERROR_TYPE_INVALID_REQUEST));
        }

        if (!data.contains("input_prefix")) {
            res->error(format_error_response("\"input_prefix\" is required", ERROR_TYPE_INVALID_REQUEST));
        }

        if (!data.contains("input_suffix")) {
            res->error(format_error_response("\"input_suffix\" is required", ERROR_TYPE_INVALID_REQUEST));
        }

        if (data.contains("input_extra") && !data.at("input_extra").is_array()) {
            // input_extra is optional
            res->error(format_error_response("\"input_extra\" must be an array of {\"filename\": string, \"text\": string}", ERROR_TYPE_INVALID_REQUEST));
            return res;
        }

        json input_extra = json_value(data, "input_extra", json::array());
        for (const auto & chunk : input_extra) {
            // { "text": string, "filename": string }
            if (!chunk.contains("text") || !chunk.at("text").is_string()) {
                res->error(format_error_response("extra_context chunk must contain a \"text\" field with a string value", ERROR_TYPE_INVALID_REQUEST));
                return res;
            }
            // filename is optional
            if (chunk.contains("filename") && !chunk.at("filename").is_string()) {
                res->error(format_error_response("extra_context chunk's \"filename\" field must be a string", ERROR_TYPE_INVALID_REQUEST));
                return res;
            }
        }
        data["input_extra"] = input_extra; // default to empty array if it's not exist

        std::string prompt = json_value(data, "prompt", std::string());
        std::vector<server_tokens> tokenized_prompts = tokenize_input_prompts(ctx_server.vocab, ctx_server.mctx, prompt, false, true);
        SRV_DBG("creating infill tasks, n_prompts = %d\n", (int) tokenized_prompts.size());
        data["prompt"] = format_prompt_infill(
            ctx_server.vocab,
            data.at("input_prefix"),
            data.at("input_suffix"),
            data.at("input_extra"),
            params.n_batch,
            params.n_predict,
            meta->slot_n_ctx,
            params.spm_infill,
            tokenized_prompts[0].get_tokens() // TODO: this could maybe be multimodal.
        );

        std::vector<raw_buffer> files; // dummy
        return handle_completions_impl(
            req,
            SERVER_TASK_TYPE_INFILL,
            data,
            files,
            TASK_RESPONSE_TYPE_NONE); // infill is not OAI compatible
    };

    this->post_completions = [this](const server_http_req & req) {
        auto res = create_response();
        std::vector<raw_buffer> files; // dummy
        const json body = json::parse(req.body);
        return handle_completions_impl(
            req,
            SERVER_TASK_TYPE_COMPLETION,
            body,
            files,
            TASK_RESPONSE_TYPE_NONE);
    };

    this->post_completions_oai = [this](const server_http_req & req) {
        auto res = create_response();
        std::vector<raw_buffer> files; // dummy
        const json body = json::parse(req.body);
        return handle_completions_impl(
            req,
            SERVER_TASK_TYPE_COMPLETION,
            body,
            files,
            TASK_RESPONSE_TYPE_OAI_CMPL);
    };

    this->post_chat_completions = [this](const server_http_req & req) {
        auto res = create_response();
        std::vector<raw_buffer> files;
        json body = json::parse(req.body);
        json body_parsed = oaicompat_chat_params_parse(
            body,
            meta->chat_params,
            files);
        return handle_completions_impl(
            req,
            SERVER_TASK_TYPE_COMPLETION,
            body_parsed,
            files,
            TASK_RESPONSE_TYPE_OAI_CHAT);
    };

    this->post_responses_oai = [this](const server_http_req & req) {
        auto res = create_response();
        std::vector<raw_buffer> files;
        json body = server_chat_convert_responses_to_chatcmpl(json::parse(req.body));
        SRV_DBG("%s\n", "Request converted: OpenAI Responses -> OpenAI Chat Completions");
        SRV_DBG("converted request: %s\n", body.dump().c_str());
        json body_parsed = oaicompat_chat_params_parse(
            body,
            meta->chat_params,
            files);
        return handle_completions_impl(
            req,
            SERVER_TASK_TYPE_COMPLETION,
            body_parsed,
            files,
            TASK_RESPONSE_TYPE_OAI_RESP);
    };

    this->post_transcriptions_oai = [this](const server_http_req & req) {
        auto res = create_response();

        if (!meta->has_mtmd || !meta->chat_params.allow_audio) {
            res->error(format_error_response("The current model does not support audio input.", ERROR_TYPE_NOT_SUPPORTED));
            return res;
        }

        std::vector<raw_buffer> files;
        json body = convert_transcriptions_to_chatcmpl(
            json::parse(req.body),
            meta->chat_params.tmpls.get(),
            req.files,
            files);
        SRV_DBG("%s\n", "Request converted: OpenAI Transcriptions -> OpenAI Chat Completions");
        SRV_DBG("converted request: %s\n", body.dump().c_str());
        json body_parsed = oaicompat_chat_params_parse(
            body,
            meta->chat_params,
            files);
        return handle_completions_impl(
            req,
            SERVER_TASK_TYPE_COMPLETION,
            body_parsed,
            files,
            TASK_RESPONSE_TYPE_OAI_ASR);
    };

    this->post_anthropic_messages = [this](const server_http_req & req) {
        auto res = create_response();
        std::vector<raw_buffer> files;
        json body = server_chat_convert_anthropic_to_oai(json::parse(req.body));
        SRV_DBG("%s\n", "Request converted: Anthropic -> OpenAI Chat Completions");
        SRV_DBG("converted request: %s\n", body.dump().c_str());
        json body_parsed = oaicompat_chat_params_parse(
            body,
            meta->chat_params,
            files);
        return handle_completions_impl(
            req,
            SERVER_TASK_TYPE_COMPLETION,
            body_parsed,
            files,
            TASK_RESPONSE_TYPE_ANTHROPIC);
    };

    this->post_anthropic_count_tokens = [this](const server_http_req & req) {
        auto res = create_response();
        std::vector<raw_buffer> files;
        json body = server_chat_convert_anthropic_to_oai(json::parse(req.body));
        SRV_DBG("%s\n", "Request converted: Anthropic -> OpenAI Chat Completions");
        SRV_DBG("converted request: %s\n", body.dump().c_str());
        json body_parsed = oaicompat_chat_params_parse(
            body,
            meta->chat_params,
            files);

        json prompt = body_parsed.at("prompt");
        llama_tokens tokens = tokenize_chat_prompt(ctx_server.vocab, body_parsed);
        res->ok({{"input_tokens", static_cast<int>(tokens.size())}});
        return res;
    };

    // same with handle_chat_completions, but without inference part
    this->post_apply_template = [this](const server_http_req & req) {
        auto res = create_response();
        std::vector<raw_buffer> files; // dummy, unused
        json body = json::parse(req.body);
        json data = oaicompat_chat_params_parse(
            body,
            meta->chat_params,
            files);
        // Authoritative tokens retain message provenance; the flattened prompt
        // alone cannot safely be re-tokenized with parse_special=true.
        auto tokens = tokenize_chat_prompt(ctx_server.vocab, data);
        res->ok({{ "prompt", std::move(data.at("prompt")) },
                 { "tokens", tokens }, { "input_spans", data.at("chat_input_spans") }});
        return res;
    };

    this->get_models = [this](const server_http_req &) {
        auto res = create_response(true);

        // this endpoint can be accessed during sleeping
        // the next LOC is to avoid someone accidentally use ctx_server
        bool ctx_server; // do NOT delete this line
        GGML_UNUSED(ctx_server);

        json models = {
            {"models", {
                {
                    {"name",  meta->model_name},
                    {"model", meta->model_name},
                    {"modified_at", ""},
                    {"size", ""},
                    {"digest", ""}, // dummy value, llama.cpp does not support managing model file's hash
                    {"type", "model"},
                    {"description", ""},
                    {"tags", {""}},
                    {"capabilities", meta->has_mtmd ? json({"completion","multimodal"}) : json({"completion"})},
                    {"parameters", ""},
                    {"details", {
                        {"parent_model", ""},
                        {"format", "gguf"},
                        {"family", ""},
                        {"families", {""}},
                        {"parameter_size", ""},
                        {"quantization_level", ""}
                    }}
                }
            }},
            {"object", "list"},
            {"data", {
                {
                    {"id",       meta->model_name},
                    {"aliases",  meta->model_aliases},
                    {"tags",     meta->model_tags},
                    {"object",   "model"},
                    {"created",  std::time(0)},
                    {"owned_by", "llamacpp"},
                    {"meta",     {
                        {"vocab_type",  meta->model_vocab_type},
                        {"n_vocab",     meta->model_vocab_n_tokens},
                        {"n_ctx_train", meta->model_n_ctx_train},
                        {"n_embd",      meta->model_n_embd_inp},
                        {"n_params",    meta->model_n_params},
                        {"size",        meta->model_size},
                    }},
                },
            }}
        };

        res->ok(models);
        return res;
    };

    this->post_tokenize = [this](const server_http_req & req) {
        auto res = create_response();
        const json body = json::parse(req.body);
        json tokens_response = json::array();
        if (body.count("content") != 0) {
            const bool add_special = json_value(body, "add_special", false);
            const bool parse_special = json_value(body, "parse_special", true);
            const bool with_pieces = json_value(body, "with_pieces", false);

            llama_tokens tokens = tokenize_mixed(ctx_server.vocab, body.at("content"), add_special, parse_special);

            if (with_pieces) {
                for (const auto& token : tokens) {
                    std::string piece = common_token_to_piece(ctx_server.vocab, token);
                    json piece_json;

                    // Check if the piece is valid UTF-8
                    if (is_valid_utf8(piece)) {
                        piece_json = piece;
                    } else {
                        // If not valid UTF-8, store as array of byte values
                        piece_json = json::array();
                        for (unsigned char c : piece) {
                            piece_json.push_back(static_cast<int>(c));
                        }
                    }

                    tokens_response.push_back({
                        {"id", token},
                        {"piece", piece_json}
                    });
                }
            } else {
                tokens_response = tokens;
            }
        }

        res->ok(json{{"tokens", std::move(tokens_response)}});
        return res;
    };

    this->post_detokenize = [this](const server_http_req & req) {
        auto res = create_response();
        const json body = json::parse(req.body);

        std::string content;
        if (body.count("tokens") != 0) {
            const llama_tokens tokens = body.at("tokens");
            content = tokens_to_str(ctx_server.vocab, tokens);
        }

        res->ok(json{{"content", std::move(content)}});
        return res;
    };

    this->post_embeddings = [this](const server_http_req & req) {
        return handle_embeddings_impl(req, TASK_RESPONSE_TYPE_NONE);
    };

    this->post_embeddings_oai = [this](const server_http_req & req) {
        return handle_embeddings_impl(req, TASK_RESPONSE_TYPE_OAI_EMBD);
    };

    this->post_rerank = [this](const server_http_req & req) {
        auto res = create_response();
        if (!params.embedding || params.pooling_type != LLAMA_POOLING_TYPE_RANK) {
            res->error(format_error_response("This server does not support reranking. Start it with `--reranking`", ERROR_TYPE_NOT_SUPPORTED));
            return res;
        }

        const json body = json::parse(req.body);

        // if true, use TEI API format, otherwise use Jina API format
        // Jina: https://jina.ai/reranker/
        // TEI: https://huggingface.github.io/text-embeddings-inference/#/Text%20Embeddings%20Inference/rerank
        bool is_tei_format = body.contains("texts");

        json query;
        if (body.count("query") == 1) {
            query = body.at("query");
            if (!query.is_string()) {
                res->error(format_error_response("\"query\" must be a string", ERROR_TYPE_INVALID_REQUEST));
                return res;
            }
        } else {
            res->error(format_error_response("\"query\" must be provided", ERROR_TYPE_INVALID_REQUEST));
            return res;
        }

        std::vector<std::string> documents = json_value(body, "documents",
                                             json_value(body, "texts", std::vector<std::string>()));
        if (documents.empty()) {
            res->error(format_error_response("\"documents\" must be a non-empty string array", ERROR_TYPE_INVALID_REQUEST));
            return res;
        }

        int top_n = json_value(body, "top_n", (int)documents.size());

        // create and queue the task
        json responses = json::array();
        auto & rd = res->rd;
        {
            std::vector<server_task> tasks;
            tasks.reserve(documents.size());
            for (size_t i = 0; i < documents.size(); i++) {
                auto tmp = format_prompt_rerank(ctx_server.model, ctx_server.vocab, ctx_server.mctx, query, documents[i]);
                server_task task = server_task(SERVER_TASK_TYPE_RERANK);
                task.id     = rd.get_new_id();
                task.tokens = std::move(tmp);
                tasks.push_back(std::move(task));
            }
            rd.post_tasks(std::move(tasks));
        }

        // wait for the results
        auto all_results = rd.wait_for_all(req.should_stop);

        // collect results
        if (all_results.is_terminated) {
            return res; // connection is closed
        } else if (all_results.error) {
            res->error(all_results.error->to_json());
            return res;
        } else {
            for (auto & res : all_results.results) {
                GGML_ASSERT(dynamic_cast<server_task_result_rerank*>(res.get()) != nullptr);
                responses.push_back(res->to_json());
            }
        }

        // write JSON response
        json root = format_response_rerank(
            body,
            meta->model_name,
            responses,
            is_tei_format,
            documents,
            top_n);

        res->ok(root);
        return res;
    };

    this->get_lora_adapters = [this](const server_http_req & req) {
        auto res = create_response();

        auto & rd = res->rd;
        {
            server_task task(SERVER_TASK_TYPE_GET_LORA);
            task.id = rd.get_new_id();
            rd.post_task(std::move(task));
        }

        // get the result
        auto result = rd.next(req.should_stop);
        if (!result) {
            // connection was closed
            GGML_ASSERT(req.should_stop());
            return res;
        }

        if (result->is_error()) {
            res->error(result->to_json());
            return res;
        }

        GGML_ASSERT(dynamic_cast<server_task_result_get_lora*>(result.get()) != nullptr);
        res->ok(result->to_json());
        return res;
    };

    this->post_lora_adapters = [this](const server_http_req & req) {
        auto res = create_response();
        const json body = json::parse(req.body);
        if (!body.is_array()) {
            res->error(format_error_response("Request body must be an array", ERROR_TYPE_INVALID_REQUEST));
            return res;
        }

        auto & rd = res->rd;
        {
            server_task task(SERVER_TASK_TYPE_SET_LORA);
            task.id = rd.get_new_id();
            task.set_lora = parse_lora_request(body);
            rd.post_task(std::move(task));
        }

        // get the result
        auto result = rd.next(req.should_stop);
        if (!result) {
            // connection was closed
            GGML_ASSERT(req.should_stop());
            return res;
        }

        if (result->is_error()) {
            res->error(result->to_json());
            return res;
        }

        GGML_ASSERT(dynamic_cast<server_task_result_apply_lora*>(result.get()) != nullptr);
        res->ok(result->to_json());
        return res;
    };
}

std::unique_ptr<server_res_generator> server_routes::handle_slots_save(const server_http_req & req, int id_slot) {
    auto res = create_response();
    const json request_data = json::parse(req.body);
    std::string filename = request_data.at("filename");
    if (!fs_validate_filename(filename)) {
        res->error(format_error_response("Invalid filename", ERROR_TYPE_INVALID_REQUEST));
        return res;
    }
    std::string filepath = params.slot_save_path + filename;

    auto & rd = res->rd;
    {
        server_task task(SERVER_TASK_TYPE_SLOT_SAVE);
        task.id = rd.get_new_id();
        task.slot_action.id_slot  = id_slot;
        task.slot_action.filename = filename;
        task.slot_action.filepath = filepath;
        rd.post_task(std::move(task));
    }

    auto result = rd.next(req.should_stop);
    if (!result) {
        // connection was closed
        GGML_ASSERT(req.should_stop());
        return res;
    }

    if (result->is_error()) {
        res->error(result->to_json());
        return res;
    }

    res->ok(result->to_json());
    return res;
}

std::unique_ptr<server_res_generator> server_routes::handle_slots_restore(const server_http_req & req, int id_slot) {
    auto res = create_response();
    const json request_data = json::parse(req.body);
    std::string filename = request_data.at("filename");
    if (!fs_validate_filename(filename)) {
        res->error(format_error_response("Invalid filename", ERROR_TYPE_INVALID_REQUEST));
        return res;
    }
    std::string filepath = params.slot_save_path + filename;

    auto & rd = res->rd;
    {
        server_task task(SERVER_TASK_TYPE_SLOT_RESTORE);
        task.id = rd.get_new_id();
        task.slot_action.id_slot  = id_slot;
        task.slot_action.filename = filename;
        task.slot_action.filepath = filepath;
        rd.post_task(std::move(task));
    }

    auto result = rd.next(req.should_stop);
    if (!result) {
        // connection was closed
        GGML_ASSERT(req.should_stop());
        return res;
    }

    if (result->is_error()) {
        res->error(result->to_json());
        return res;
    }

    GGML_ASSERT(dynamic_cast<server_task_result_slot_save_load*>(result.get()) != nullptr);
    res->ok(result->to_json());
    return res;
}

std::unique_ptr<server_res_generator> server_routes::handle_slots_erase(const server_http_req & req, int id_slot) {
    auto res = create_response();
    auto & rd = res->rd;
    {
        server_task task(SERVER_TASK_TYPE_SLOT_ERASE);
        task.id = rd.get_new_id();
        task.slot_action.id_slot = id_slot;
        rd.post_task(std::move(task));
    }

    auto result = rd.next(req.should_stop);
    if (!result) {
        // connection was closed
        GGML_ASSERT(req.should_stop());
        return res;
    }

    if (result->is_error()) {
        res->error(result->to_json());
        return res;
    }

    GGML_ASSERT(dynamic_cast<server_task_result_slot_erase*>(result.get()) != nullptr);
    res->ok(result->to_json());
    return res;
}

std::unique_ptr<server_res_generator> server_routes::handle_embeddings_impl(const server_http_req & req, task_response_type res_type) {
    auto res = create_response();
    if (!params.embedding) {
        res->error(format_error_response("This server does not support embeddings. Start it with `--embeddings`", ERROR_TYPE_NOT_SUPPORTED));
        return res;
    }

    if (res_type != TASK_RESPONSE_TYPE_NONE && meta->pooling_type == LLAMA_POOLING_TYPE_NONE) {
        res->error(format_error_response("Pooling type 'none' is not OAI compatible. Please use a different pooling type", ERROR_TYPE_INVALID_REQUEST));
        return res;
    }

    const json body = json::parse(req.body);

    // for the shape of input/content, see tokenize_input_prompts()
    json prompt;
    if (body.count("input") != 0) {
        prompt = body.at("input");
    } else if (body.contains("content")) {
        res_type = TASK_RESPONSE_TYPE_NONE; // "content" field is not OAI compatible
        prompt = body.at("content");
    } else {
        res->error(format_error_response("\"input\" or \"content\" must be provided", ERROR_TYPE_INVALID_REQUEST));
        return res;
    }

    bool use_base64 = false;
    if (body.count("encoding_format") != 0) {
        const std::string & format = body.at("encoding_format");
        if (format == "base64") {
            use_base64 = true;
        } else if (format != "float") {
            res->error(format_error_response("The format to return the embeddings in. Can be either float or base64", ERROR_TYPE_INVALID_REQUEST));
            return res;
        }
    }

    auto tokenized_prompts = tokenize_input_prompts(ctx_server.vocab, ctx_server.mctx, prompt, true, true);
    for (const auto & tokens : tokenized_prompts) {
        // this check is necessary for models that do not add BOS token to the input
        if (tokens.empty()) {
            res->error(format_error_response("Input content cannot be empty", ERROR_TYPE_INVALID_REQUEST));
            return res;
        }
    }

    int embd_normalize = 2; // default to Euclidean/L2 norm
    if (body.count("embd_normalize") != 0) {
        embd_normalize = body.at("embd_normalize");
        if (meta->pooling_type == LLAMA_POOLING_TYPE_NONE) {
            SRV_DBG("embd_normalize is not supported by pooling type %d, ignoring it\n", meta->pooling_type);
        }
    }

    // create and queue the task
    json responses = json::array();
    auto & rd = res->rd;
    {
        std::vector<server_task> tasks;
        for (size_t i = 0; i < tokenized_prompts.size(); i++) {
            server_task task = server_task(SERVER_TASK_TYPE_EMBEDDING);

            task.id     = rd.get_new_id();
            task.tokens = std::move(tokenized_prompts[i]);

            // OAI-compat
            task.params.res_type = res_type;
            task.params.embd_normalize = embd_normalize;

            tasks.push_back(std::move(task));
        }
        rd.post_tasks(std::move(tasks));
    }

    // wait for the results
    auto all_results = rd.wait_for_all(req.should_stop);

    // collect results
    if (all_results.is_terminated) {
        return res; // connection is closed
    } else if (all_results.error) {
        res->error(all_results.error->to_json());
        return res;
    } else {
        for (auto & res : all_results.results) {
            GGML_ASSERT(dynamic_cast<server_task_result_embd*>(res.get()) != nullptr);
            responses.push_back(res->to_json());
        }
    }

    // write JSON response
    json root = res_type == TASK_RESPONSE_TYPE_OAI_EMBD
        ? format_embeddings_response_oaicompat(body, meta->model_name, responses, use_base64)
        : json(responses);
    res->ok(root);
    return res;
}
