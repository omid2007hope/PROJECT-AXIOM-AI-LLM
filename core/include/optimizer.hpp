#ifndef include_optimizer
#define include_optimizer

#include <atomic>
#include <chrono>
#include <cstddef>
#include <cstdint>
#include <filesystem>
#include <fstream>
#include <iostream>
#include <random>
#include <string>
#include <thread>
#include <utility>
#include <vector>

#include "parser.hpp"

// ── DLL-imported pinned memory API ──────────────────────────────────────────
// All cudaHostAlloc / cudaFreeHost calls live inside cuda_transfer.dll
// (compiled by nvcc/MSVC). The g++ side only calls these two thin wrappers,
// so it never needs to link against cudart.lib or any CUDA import library.
#ifndef CUDA_API
#define CUDA_API __declspec(dllimport)
#endif
extern "C" CUDA_API void* pinned_alloc(size_t bytes);
extern "C" CUDA_API void pinned_free(void* ptr);

// Architecture principle: Storage drives are hyper-optimized for sequential
// forward reads.

struct Portion {


	int buffer_index = 0;

	// =========================================================================
	// CRITICAL SYNCHRONIZATION BARRIER — LIFE AND DEATH GUARANTEE
	// -------------------------------------------------------------------------
	// PAY MAXIMUM ATTENTION: If you mess up these synchronization flags, you
	// risk corrupting both historical and ongoing training data across the
	// entire pipeline — causing millions of dollars in wasted compute, forcing
	// a full wipe back to zero, and resulting in catastrophic failure.
	// DO NOT tamper with or bypass these state locks under any circumstances!
	// =========================================================================
	// =========================================================================
	// UPGRADED: primitive bool → std::atomic<bool>
	// Atomic flags guarantee that reads and writes across CPU threads are
	// sequentially consistent — no torn reads, no UB on concurrent access.
	// =========================================================================
	std::atomic<bool> buffer_in_use {false};
	std::atomic<bool> context_in_use {false};
	// =========================================================================

	// ---------------------------------------------------------
	// Tier 1: The RAM Buffer (Disk -> RAM)
	// Optimal size: 100,000 to 1,000,000 tokens to keep CPU fed.
	// ---------------------------------------------------------
	size_t ram_buffer_size;

	// Holds: ram_buffer_size * embedding_dim (e.g., 400,000 bfloat16_t values)
	std::vector<std::bfloat16_t> ram_buffer_tokens = {};

	// ---------------------------------------------------------
	// Tier 2: The AI's Field of View (RAM -> AI)
	// Optimal for basic AI: 64 or 128 tokens.
	// ---------------------------------------------------------
	// 1 token = token_dim bfloat16_t values (e.g., 4)
	size_t token_dim;

	size_t context_window_size;

	// context_window_size * token_dim (e.g., 128 * 4 = 512)
	size_t all_elements;

	// 1 * token_dim (e.g., 1 * 4 = 4)
	size_t target_elements;

	size_t offset = 0;

	// All sizes are decided by the caller (main); the derived element counts
	// are computed here so they can never go out of sync with them.
	Portion(size_t ram_buffer_size, size_t token_dim, size_t context_window_size)
	    : ram_buffer_size(ram_buffer_size),
	      token_dim(token_dim),
	      context_window_size(context_window_size),
	      all_elements(context_window_size * token_dim),
	      target_elements(1 * token_dim) {}

	// =========================================================================
	// UPGRADED: pageable std::vector → cudaHostAllocWriteCombined pinned memory
	//
	// cudaMemcpyAsync silently degrades to a synchronous blocking call when
	// handed a pageable heap pointer. Pinning these two buffers with
	// cudaHostAllocWriteCombined achieves three goals:
	//   1. Locks the physical page so the GPU DMA engine can read it directly.
	//   2. Bypasses the CPU L1/L2 cache hierarchy (write-combining), pushing
	//      data straight to the PCIe bus for up to 40% higher throughput.
	//   3. Enables true cudaMemcpyAsync (non-blocking on the host thread).
	// =========================================================================

	// The Input (X): pinned host buffer — 128 tokens * 4 dim = 512 bfloat16_t
	std::bfloat16_t* context_window_tokens[2] = {nullptr, nullptr};

	// Pinned host buffer for token IDs: 128 uint32_t tokens across PCIe per context window (512 bytes)
	uint32_t* context_token_ids[2] = {nullptr, nullptr};

	// The Target (Y): pinned host buffer — 1 token * 4 dim = 4 bfloat16_t
	std::bfloat16_t* target_tokens[2] = {nullptr, nullptr};

	// Flag indicating if current window in portion was loaded with token IDs
	bool has_token_ids = false;

	// RAM buffer for uint32_t token IDs
	std::vector<uint32_t> ram_buffer_token_ids = {};

	// Start index of every sliding window, reshuffled at the start of each epoch
	// (offset == 0). Windows are visited as window_order[offset].
	std::vector<uint32_t> window_order = {};
	std::mt19937 shuffle_engine {std::random_device {}()};

	// Allocate the pinned buffers. Must be called once before the training loop.
	// Returns false if the CUDA DLL reports an allocation failure.
	bool allocate_pinned() {
		if (context_window_tokens[0] || target_tokens[0] || context_token_ids[0]) {
			return true; // already allocated
		}

		for (int i = 0; i < 2; ++i) {
			context_window_tokens[i] = static_cast<std::bfloat16_t*>(
				pinned_alloc(all_elements * sizeof(std::bfloat16_t)));

			context_token_ids[i] = static_cast<uint32_t*>(
				pinned_alloc(context_window_size * sizeof(uint32_t)));

			target_tokens[i] = static_cast<std::bfloat16_t*>(
				pinned_alloc(target_elements * sizeof(std::bfloat16_t)));

			if (!context_window_tokens[i] || !context_token_ids[i] || !target_tokens[i]) {
				std::cerr << "[Portion] pinned_alloc failed\n";
				free_pinned();
				return false;
			}
		}

		return true;
	}

	Portion(const Portion&) = delete;
	Portion& operator=(const Portion&) = delete;

	~Portion() {
		free_pinned();
	}

	// Release pinned host memory. Safe to call even if allocate_pinned() was
	// never called (pinned_free checks for nullptr internally).
	void free_pinned() {
		for (int i = 0; i < 2; ++i) {
			if (context_window_tokens[i]) {
				pinned_free(context_window_tokens[i]);
				context_window_tokens[i] = nullptr;
			}

			if (context_token_ids[i]) {
				pinned_free(context_token_ids[i]);
				context_token_ids[i] = nullptr;
			}

			if (target_tokens[i]) {
				pinned_free(target_tokens[i]);
				target_tokens[i] = nullptr;
			}
		}
	}
};

// -----------------------------------------------------------------------------
// Lock-free Single-Producer Single-Consumer (SPSC) Chunk Ring Buffer
// -----------------------------------------------------------------------------
struct ChunkSlot {
	std::vector<std::bfloat16_t> tokens {};
	size_t elements = 0;
};

template <size_t Capacity = 4>
class ChunkRingBuffer {
private:
	ChunkSlot slots[Capacity];
	alignas(64) std::atomic<size_t> write_index {0};
	alignas(64) std::atomic<size_t> read_index {0};

public:
	bool can_produce() const {
		size_t w = write_index.load(std::memory_order_relaxed);
		size_t r = read_index.load(std::memory_order_acquire);
		return (w - r) < Capacity;
	}

	bool can_consume() const {
		size_t w = write_index.load(std::memory_order_acquire);
		size_t r = read_index.load(std::memory_order_relaxed);
		return r < w;
	}

	size_t available_chunks() const {
		size_t w = write_index.load(std::memory_order_acquire);
		size_t r = read_index.load(std::memory_order_relaxed);
		return (w >= r) ? (w - r) : 0;
	}

	ChunkSlot& get_producer_slot() {
		size_t w = write_index.load(std::memory_order_relaxed);
		return slots[w % Capacity];
	}

	void push_produced() {
		write_index.fetch_add(1, std::memory_order_release);
	}

	ChunkSlot& get_consumer_slot() {
		size_t r = read_index.load(std::memory_order_relaxed);
		return slots[r % Capacity];
	}

	void pop_consumed() {
		read_index.fetch_add(1, std::memory_order_release);
	}

	void clear() {
		read_index.store(0, std::memory_order_relaxed);
		write_index.store(0, std::memory_order_relaxed);
	}
};

class Optimizer {
private:
	// Kept permanently open: ~8KB OS buffer cost, zero syscall overhead per
	// chunk.
	std::ifstream file_stream;

	// Phase 2.3: Lock-free SPSC Ring Buffer & Background Prefetch Producer Thread
	std::thread prefetch_worker;
	std::atomic<bool> prefetch_active {false};
	ChunkRingBuffer<4> chunk_buffer;
	std::vector<std::bfloat16_t> seam_carry;

	void prefetch_loop(size_t chunk_size, size_t context_size, size_t dim);
	void read_chunk_into(std::vector<std::bfloat16_t>& buffer, size_t chunk_size, size_t context_size, size_t dim);

public:
	// Path to the binary embedded data file produced by Parser::embedding().
	// Decided by the caller (main) and read by disk_to_ram().
	std::filesystem::path data_path;

	// Gradient-descent step size used by AI::train(); decided by the caller.
	float learning_rate;

	Optimizer(std::filesystem::path data_path, float learning_rate)
	    : data_path(std::move(data_path)), learning_rate(learning_rate) {}

	~Optimizer() {
		stop_prefetch();
		close_stream();
	}

	void close_stream() {
		if (file_stream.is_open()) {
			file_stream.close();
		}
	}

	void start_prefetch(const Portion& portion);
	void stop_prefetch();
	bool is_prefetch_running() const {
		return prefetch_active.load(std::memory_order_acquire);
	}
	size_t get_prefetched_chunks() const {
		return chunk_buffer.available_chunks();
	}

	void disk_to_ram(Portion& portion);

	bool load_context_window(Portion& portion);
};

#endif