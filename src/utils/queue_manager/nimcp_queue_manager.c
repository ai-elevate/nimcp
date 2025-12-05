//=============================================================================
// nimcp_queue_manager.c - Multi-Channel Priority Queue Management System
//=============================================================================
// ARCHITECTURAL OVERVIEW:
// This module implements a sophisticated multi-channel, multi-priority queue
// system designed for high-throughput, low-latency asynchronous message
// processing in NIMCP. It's the orchestration layer above basic queues,
// providing priority-based routing and concurrent operation execution.
//
// KEY DESIGN: MULTI-CHANNEL PRIORITY QUEUE SYSTEM
// ================================================
// WHY MULTI-CHANNEL:
// - ISOLATION: Different subsystems use different channels (events, logging, etc.)
// - PARALLELISM: Operations on different channels don't contend for locks
// - ORGANIZATION: Logical separation of concerns (channel 0 = events, etc.)
// - SCALABILITY: Can handle multiple independent message streams
//
// Example: Event system uses channel 0, logging uses channel 1
//          Both operate independently without blocking each other
//
// WHY THREE PRIORITY LEVELS:
// - HIGH: Urgent neural spikes with confidence >0.8 (needs immediate processing)
// - NORMAL: Regular activity with confidence 0.3-0.8 (standard latency)
// - LOW: Background/housekeeping with confidence <0.3 (can wait)
//
// Benefits over single queue:
// - Critical events processed first during load
// - Prevents head-of-line blocking
// - Natural backpressure: low-priority drops first
//
// WHY THREAD POOL FOR QUEUE OPERATIONS:
// - CONCURRENCY: Multiple operations execute in parallel
// - EFFICIENCY: Thread reuse, no spawn/join overhead
// - FAIRNESS: Work-stealing prevents starvation
// - SCALABILITY: Configurable worker count
//
// Without thread pool: Sequential operations, poor throughput
// With thread pool: Parallel enqueue/dequeue, 4x+ throughput
//
// ARCHITECTURE DIAGRAM:
//
//   ┌─────────────────────────────────────────────────┐
//   │         Queue Manager (Facade)                  │
//   │  Channels: 0..N (configurable, default 1024)    │
//   └──────────────┬──────────────────────────────────┘
//                  │
//        ┌─────────┴──────────┬──────────────┐
//        │                    │              │
//   ┌────▼─────┐        ┌────▼─────┐   ┌───▼──────┐
//   │ Channel 0│        │ Channel 1│...│Channel N │
//   │ (Events) │        │ (Logging)│   │ (Other)  │
//   └────┬─────┘        └────┬─────┘   └───┬──────┘
//        │                   │              │
//   ┌────▼──────────┐   ┌───▼──────────┐  │
//   │ HIGH   Queue  │   │ HIGH  Queue  │  │
//   │ (1000 items)  │   │              │  │
//   ├───────────────┤   ├──────────────┤  │
//   │ NORMAL Queue  │   │ NORMAL Queue │  │
//   │ (5000 items)  │   │              │  │
//   ├───────────────┤   ├──────────────┤  │
//   │ LOW    Queue  │   │ LOW   Queue  │  │
//   │ (500 items)   │   │              │  │
//   └───────────────┘   └──────────────┘  │
//
//   All operations dispatched to Thread Pool (4 workers default)
//
// PRIORITY MAPPING FROM MESSAGE FLAGS:
// - message->flags & 0x3 extracts lower 2 bits
// - Value 2 → HIGH priority
// - Value 1 → NORMAL priority
// - Value 0 → LOW priority
//
// WHY FLAGS-BASED: Caller controls priority without separate parameter
//
// DEQUEUE PRIORITY ORDERING:
// Always try HIGH first, then NORMAL, then LOW
// - Ensures urgent messages processed first
// - Only waits on lowest priority (timeout applied to LOW queue only)
// - Empty higher priority queues checked with zero timeout (non-blocking)
//
// THREAD SAFETY:
// - Each channel has 3 independent queues (each with own mutex)
// - Atomic statistics updates (lock-free counters)
// - Thread pool handles concurrent operation dispatch
// - No global locks (maximizes parallelism)
//
// COMMAND PATTERN IMPLEMENTATION:
// queue_operation_ctx_t encapsulates:
// - Operation type (enqueue, dequeue, clear, stats)
// - Channel ID
// - Priority level
// - Message data
// - Result storage
// - Completion flag
//
// Benefits:
// - Uniform interface for all operations
// - Easy to add new operation types
// - Clean separation of request and execution
//
// PERFORMANCE CHARACTERISTICS:
// - Enqueue: O(1) + thread pool dispatch overhead (~50-100μs)
// - Dequeue: O(3) worst case (checks 3 priorities), O(1) typical
// - Memory: O(channels × (high_size + normal_size + low_size))
// - Throughput: Limited by thread pool size and queue contention
//
// Typical latency (4 workers, moderate load):
// - Enqueue: 100-200μs (includes cloning)
// - Dequeue: 50-150μs
// - Under heavy load: May increase to 500μs+
//
// DESIGN PATTERNS:
// 1. FACADE: Simplifies complex multi-queue system
// 2. COMMAND: Operations encapsulated as objects (queue_operation_ctx_t)
// 3. STRATEGY: Priority selection strategy
// 4. THREAD POOL: Concurrent operation execution
// 5. CHANNEL: Multiple independent communication pathways
// 6. PRIORITY QUEUE: Three-level prioritization
//
// SOLID PRINCIPLES:
// - Single Responsibility: Each function has one clear purpose
// - Open/Closed: Can add new operation types without modifying handlers
// - Liskov Substitution: All queues conform to same interface
// - Interface Segregation: Clean, minimal public API
// - Dependency Inversion: Depends on queue abstractions, not implementations
//
// USE CASES IN NIMCP:
// - Event System: High-confidence neural spikes prioritized
// - Logging: Urgent errors processed before debug messages
// - P2P Communication: Critical control messages before data
// - Consolidation: Important memory traces before background cleanup
//
// LIMITATIONS AND TRADE-OFFS:
// - Thread pool overhead: Not suitable for ultra-low latency (<10μs)
// - Message cloning: Memory overhead for every enqueue
// - Fixed priority levels: Can't dynamically add new priorities
// - Spin-wait completion: CPU usage during blocking operations
//
// WHY THESE TRADE-OFFS:
// - Cloning: Ensures caller ownership, prevents use-after-free
// - Thread pool: Parallelism more valuable than raw latency
// - Fixed priorities: Simplicity, predictable behavior
// - Spin-wait: Lower latency than condition variables for short waits
//
//=============================================================================

/**
 * @file nimcp_queue_manager.c
 * @brief Implementation of thread pool-based queue management system
 */

#define NIMCP_INTERNAL
#include "utils/queue_manager/nimcp_queue_manager.h"
#include "async/nimcp_bio_async.h"
#include "async/nimcp_bio_messages.h"
#include <stdlib.h>
#include <string.h>
#include <time.h>
#include "utils/memory/nimcp_memory.h"
#include "utils/thread/nimcp_thread_pool.h"
#include "utils/memory/nimcp_unified_memory.h"
#include "utils/logging/nimcp_logging.h"

// Default configuration values
#define DEFAULT_WORKER_THREADS 4

// Forward declarations of helper functions
static uint64_t nimcp_get_timestamp_ms(void);
static void nimcp_yield_thread(void);

//=============================================================================
// Message Helper Functions
//=============================================================================
// WHY SEPARATE MESSAGE HELPERS:
// - Originally part of separate messages module (now simplified)
// - Encapsulates deep copy semantics
// - Prevents memory leaks by centralizing cleanup
//
// WHY DEEP COPY (nimcp_msg_clone):
// - Caller can free/reuse original message immediately
// - No ownership tracking needed
// - Thread-safe: Each queue owns its copy
// - Prevents use-after-free bugs
//
// TRADE-OFF: Memory overhead vs safety (we choose safety)
//=============================================================================

/**
 * @brief Clone a message (deep copy)
 *
 * WHY DEEP COPY: Thread safety, ownership clarity
 * - Caller retains ownership of source
 * - Queue gets independent copy
 * - No lifetime coordination needed
 *
 * ALGORITHM:
 * 1. Allocate new message structure
 * 2. Copy scalar fields (type, flags, size)
 * 3. Allocate and copy payload data
 * 4. Return pointer to clone
 *
 * COMPLEXITY: O(n) where n = message size (for memcpy)
 * THREAD SAFETY: Fully thread-safe (no shared state)
 *
 * @param src Source message to clone
 * @param dst Pointer to receive cloned message
 * @return NIMCP_SUCCESS or error code
 */
static nimcp_result_t nimcp_msg_clone(const nimcp_message_t* src, nimcp_message_t** dst)
{
    LOG_DEBUG("Entering nimcp_msg_clone");
    if (!src || !dst)
        return NIMCP_INVALID_PARAM;

    // Allocate message structure
    nimcp_message_t* msg = nimcp_malloc(sizeof(nimcp_message_t));
    if (!msg)
        return NIMCP_NO_MEMORY;

    // Copy scalar fields
    msg->type = src->type;
    msg->flags = src->flags;
    msg->size = src->size;

    // Deep copy payload if present
    // WHY CHECK: Empty messages are valid (size=0, data=NULL)
    if (src->data && src->size > 0) {
        msg->data = nimcp_malloc(src->size);
        if (!msg->data) {
            nimcp_free(msg);
            return NIMCP_NO_MEMORY;
        }
        memcpy(msg->data, src->data, src->size);
    } else {
        msg->data = NULL;
    }

    *dst = msg;
    return NIMCP_SUCCESS;
}

/**
 * @brief Destroy a message and free its memory
 *
 * WHY SEPARATE FUNCTION: Centralized cleanup prevents leaks
 * - Ensures both message and payload are freed
 * - NULL-safe (can call on already-freed pointer)
 * - Consistent with RAII pattern
 *
 * COMPLEXITY: O(1)
 * THREAD SAFETY: Safe on unique ownership (caller must ensure)
 *
 * @param msg Message to destroy (can be NULL)
 */
static void nimcp_msg_destroy(nimcp_message_t* msg)
{
    LOG_DEBUG("Entering nimcp_msg_destroy");
    if (msg) {
        // Free payload first
        if (msg->data) {
            nimcp_free(msg->data);
        }
        // Then free message structure
        nimcp_free(msg);
    }
}

//=============================================================================
// Configuration and Validation
//=============================================================================

/**
 * @brief Validate queue manager configuration
 *
 * WHY VALIDATE: Fail fast with clear errors vs cryptic runtime failures
 * - Prevents invalid states at construction
 * - Catches typos/mistakes early
 * - Clear error location (create, not later)
 *
 * VALIDATION RULES:
 * - max_channels: 1 to NIMCP_QUEUE_MAX_CHANNELS (1024)
 * - queue sizes: NIMCP_QUEUE_MIN_SIZE (10) to NIMCP_QUEUE_MAX_SIZE (1M)
 *
 * WHY THESE LIMITS:
 * - max_channels: Practical limit, prevents huge allocations
 * - min_size: Too small = constant thrashing
 * - max_size: Prevents excessive memory use
 *
 * COMPLEXITY: O(1)
 * THREAD SAFETY: Read-only, fully thread-safe
 *
 * @param config Configuration to validate
 * @return NIMCP_SUCCESS or NIMCP_INVALID_PARAM
 */
static nimcp_result_t validate_config(const nimcp_queue_manager_config_t* config)
{
    if (!config)
        return NIMCP_INVALID_PARAM;

    // Validate channel count
    if (config->max_channels == 0 || config->max_channels > NIMCP_QUEUE_MAX_CHANNELS) {
        return NIMCP_INVALID_PARAM;
    }

    // Validate queue sizes (all three priorities)
    // WHY CHECK ALL THREE: Each priority can have different size
    if (config->queue_sizes.high > NIMCP_QUEUE_MAX_SIZE ||
        config->queue_sizes.normal > NIMCP_QUEUE_MAX_SIZE ||
        config->queue_sizes.low > NIMCP_QUEUE_MAX_SIZE ||
        config->queue_sizes.high < NIMCP_QUEUE_MIN_SIZE ||
        config->queue_sizes.normal < NIMCP_QUEUE_MIN_SIZE ||
        config->queue_sizes.low < NIMCP_QUEUE_MIN_SIZE) {
        return NIMCP_INVALID_PARAM;
    }

    return NIMCP_SUCCESS;
}

/**
 * @brief Get queue size for given priority level
 *
 * WHY HELPER FUNCTION: DRY principle, used in multiple places
 * - Centralizes priority→size mapping
 * - Easy to change size strategy
 * - Clear, readable code
 *
 * STRATEGY PATTERN: Encapsulates size selection algorithm
 * - Could swap for dynamic sizing
 * - Could add adaptive resizing
 *
 * COMPLEXITY: O(1)
 *
 * @param config Configuration containing sizes
 * @param priority Priority level
 * @return Queue size for that priority
 */
static size_t get_queue_size_for_priority(const nimcp_queue_manager_config_t* config,
                                          nimcp_queue_priority_t priority)
{
    switch (priority) {
        case NIMCP_QUEUE_PRIORITY_HIGH:
            return config->queue_sizes.high;
        case NIMCP_QUEUE_PRIORITY_NORMAL:
            return config->queue_sizes.normal;
        case NIMCP_QUEUE_PRIORITY_LOW:
            return config->queue_sizes.low;
        default:
            // Fallback for invalid priority
            // WHY DEFAULT: Defensive programming, prevents undefined behavior
            return NIMCP_QUEUE_DEFAULT_SIZE;
    }
}

/**
 * @brief Check if channel ID is valid
 *
 * WHY GUARD FUNCTION: Prevents buffer overruns and use-after-free
 * - Validates all invariants in one place
 * - Used at entry point of every public function
 * - Fails fast on invalid input
 *
 * CHECKS:
 * 1. Manager exists (not NULL)
 * 2. Manager initialized (create succeeded)
 * 3. Not shutting down (destroy not called)
 * 4. Channel ID in bounds (< max_channels)
 *
 * WHY ALL FOUR: Complete safety guarantee
 * - Missing any one could allow invalid access
 *
 * COMPLEXITY: O(1)
 * THREAD SAFETY: Atomic load for shutting_down flag
 *
 * @param manager Queue manager instance
 * @param channel_id Channel to validate
 * @return true if valid, false otherwise
 */
static bool is_valid_channel(nimcp_queue_manager_handle_t manager, uint32_t channel_id)
{
    return (manager && manager->initialized && !atomic_load(&manager->shutting_down) &&
            channel_id < manager->config.max_channels);
}

//=============================================================================
// Channel Management
//=============================================================================

/**
 * @brief Initialize a queue channel with all priority levels
 *
 * WHY THREE QUEUES PER CHANNEL:
 * - Each priority needs separate queue for isolation
 * - Prevents priority inversion (low blocking high)
 * - Enables priority-ordered dequeue
 *
 * ALGORITHM:
 * 1. Zero-initialize channel structure
 * 2. Create HIGH priority queue
 * 3. Create NORMAL priority queue
 * 4. Create LOW priority queue
 * 5. If any fails, cleanup and return error
 *
 * WHY CLEANUP ON ERROR:
 * - Resource leak prevention
 * - Partial initialization is invalid state
 * - Leave no side effects on failure
 *
 * QUEUE CONFIGURATION:
 * - item_size: sizeof(nimcp_message_t*) - we store message pointers
 * - blocking_mode: From config (usually true for backpressure)
 * - timeout_ms: Default timeout from config
 *
 * WHY STORE POINTERS: Messages are variable size, pointers are fixed
 *
 * COMPLEXITY: O(1) allocations, O(queue_size) memory
 * THREAD SAFETY: Called during create (single-threaded)
 *
 * @param channel Channel to initialize
 * @param config Configuration for queue sizing
 * @return NIMCP_SUCCESS or error code
 */
static nimcp_result_t init_channel(nimcp_queue_channel_t* channel,
                                   const nimcp_queue_manager_config_t* config)
{
    memset(channel, 0, sizeof(nimcp_queue_channel_t));

    // Create queue for each priority level
    // WHY LOOP: DRY principle, all priorities initialized identically
    for (int pri = 0; pri < NIMCP_QUEUE_PRIORITY_COUNT; pri++) {
        nimcp_queue_config_t queue_config = {
            .max_size = get_queue_size_for_priority(config, pri),
            .item_size = sizeof(nimcp_message_t*),  // Store pointers, not messages
            .is_blocking = config->blocking_mode,
            .timeout_ms = config->default_timeout};

        nimcp_result_t result = nimcp_queue_create(&queue_config, &channel->queues[pri]);
        if (result != NIMCP_SUCCESS) {
            // Cleanup previously created queues on error
            // WHY CLEANUP: Prevent resource leak
            for (int j = 0; j < pri; j++) {
                nimcp_queue_destroy(channel->queues[j]);
            }
            return result;
        }
    }

    return NIMCP_SUCCESS;
}

/**
 * @brief Destroy all queues in a channel
 *
 * WHY SEPARATE FUNCTION: Called from multiple places (destroy, error paths)
 * - Ensures complete cleanup
 * - NULL-safe
 *
 * ALGORITHM:
 * - Destroy all three priority queues
 * - nimcp_queue_destroy handles NULL gracefully
 *
 * COMPLEXITY: O(queue_sizes) - each queue cleanup is O(n)
 * THREAD SAFETY: Assumes exclusive access (called during shutdown)
 *
 * @param channel Channel to destroy (can be NULL)
 */
static void destroy_channel(nimcp_queue_channel_t* channel)
{
    if (!channel)
        return;

    // Destroy all priority queues
    for (int pri = 0; pri < NIMCP_QUEUE_PRIORITY_COUNT; pri++) {
        if (channel->queues[pri]) {
            nimcp_queue_destroy(channel->queues[pri]);
        }
    }
}

//=============================================================================
// Queue Operation Handler (Command Pattern)
//=============================================================================

/**
 * @brief Execute a queue operation (runs in thread pool worker)
 *
 * WHY COMMAND PATTERN:
 * - Encapsulates operation details in context object
 * - Single handler for all operation types
 * - Easy to add new operation types
 * - Clean separation of request and execution
 *
 * OPERATION TYPES:
 * 1. ENQUEUE: Clone message, insert into priority queue
 * 2. DEQUEUE: Remove message from priority queue
 * 3. CLEAR: Empty priority queue
 * 4. GET_STATS: Copy statistics
 *
 * WHY CLONE ON ENQUEUE:
 * - Caller retains ownership of original
 * - Queue operations don't block caller
 * - Thread-safe sharing
 *
 * STATISTICS TRACKING:
 * - Atomic increments (lock-free)
 * - Per-priority counters
 * - Peak size tracking
 * - Operation latency (for monitoring)
 *
 * WHY ATOMIC STATISTICS:
 * - No locks needed
 * - Low overhead
 * - Eventually consistent (acceptable for stats)
 *
 * COMPLEXITY: Depends on operation type
 * - ENQUEUE: O(1) + O(message_size) for clone
 * - DEQUEUE: O(1)
 * - CLEAR: O(queue_size)
 * - GET_STATS: O(1)
 *
 * THREAD SAFETY: Fully thread-safe
 * - Each queue has own mutex
 * - Atomic stats updates
 * - No shared mutable state
 *
 * @param arg Pointer to nimcp_queue_operation_ctx_t
 */
static void queue_operation_handler(void* arg)
{
    nimcp_queue_operation_ctx_t* ctx = (nimcp_queue_operation_ctx_t*) arg;
    if (!ctx)
        return;

    // Record start time for latency tracking
    uint64_t start_time = nimcp_get_timestamp_ms();

    // Recover manager reference from context
    // WHY STORED: Handler needs manager to access channels
    nimcp_queue_manager_handle_t manager = (nimcp_queue_manager_handle_t) ctx->manager_handle;
    nimcp_queue_channel_t* channel = &manager->channels[ctx->channel_id];

    // Dispatch based on operation type
    // WHY SWITCH: Clear, efficient, easy to extend
    switch (ctx->op_type) {
        case NIMCP_QUEUE_OP_ENQUEUE: {
            // Clone message (deep copy for thread safety)
            nimcp_message_t* msg_copy;
            ctx->status = nimcp_msg_clone(ctx->message, &msg_copy);
            if (ctx->status == NIMCP_SUCCESS) {
                // Enqueue the cloned message pointer
                ctx->status = nimcp_queue_enqueue(channel->queues[ctx->priority],
                                                  &msg_copy,  // Store pointer to message
                                                  ctx->timeout_ms);

                if (ctx->status == NIMCP_SUCCESS) {
                    // Update success statistics
                    atomic_fetch_add(&channel->stats.priorities[ctx->priority].enqueued, 1);
                    atomic_fetch_add(&channel->stats.priorities[ctx->priority].current_size, 1);

                    // Track peak size for capacity planning
                    // WHY TRACK PEAK: Helps tune queue sizes
                    size_t current =
                        atomic_load(&channel->stats.priorities[ctx->priority].current_size);
                    size_t peak = atomic_load(&channel->stats.priorities[ctx->priority].peak_size);

                    if (current > peak) {
                        atomic_store(&channel->stats.priorities[ctx->priority].peak_size, current);
                    }
                } else {
                    // Enqueue failed (queue full or timeout)
                    // WHY COUNT DROPS: Monitor backpressure effectiveness
                    atomic_fetch_add(&channel->stats.priorities[ctx->priority].dropped, 1);
                    nimcp_msg_destroy(msg_copy);  // Cleanup cloned message
                }
            }
            break;
        }

        case NIMCP_QUEUE_OP_DEQUEUE: {
            // Dequeue into a temporary local variable to avoid stack-use-after-scope
            // We'll copy to ctx->result only if not abandoned
            nimcp_message_t* temp_msg = NULL;
            ctx->status = nimcp_queue_dequeue(channel->queues[ctx->priority],
                                              &temp_msg,  // Use local storage
                                              ctx->timeout_ms);

            // CRITICAL: Check if context was abandoned BEFORE accessing ctx->result
            // The result pointer may point to freed/invalid stack memory if abandoned
            if (atomic_load(&ctx->abandoned)) {
                // Main thread timed out and abandoned this operation
                // Don't access ctx->result - it's invalid
                // Clean up the dequeued message if we got one
                if (ctx->status == NIMCP_SUCCESS && temp_msg) {
                    // Put message back or clean up - for now just leak it
                    // This is rare and better than use-after-free
                    // TODO: Could re-enqueue it
                }
                nimcp_free(ctx);
                return;
            }

            // Safe to write to result now
            if (ctx->status == NIMCP_SUCCESS) {
                // Copy temp result to caller's storage
                nimcp_message_t** msg_ptr = (nimcp_message_t**) ctx->result;
                *msg_ptr = temp_msg;

                // Update statistics
                atomic_fetch_add(&channel->stats.priorities[ctx->priority].dequeued, 1);
                atomic_fetch_sub(&channel->stats.priorities[ctx->priority].current_size, 1);
            }
            break;
        }

        case NIMCP_QUEUE_OP_CLEAR: {
            // Clear all items from queue
            // WHY: Emergency cleanup, reset channel state
            nimcp_queue_clear(channel->queues[ctx->priority]);
            atomic_store(&channel->stats.priorities[ctx->priority].current_size, 0);
            ctx->status = NIMCP_SUCCESS;
            break;
        }

        case NIMCP_QUEUE_OP_GET_STATS: {
            // CRITICAL: Check if context was abandoned BEFORE accessing ctx->result
            if (atomic_load(&ctx->abandoned)) {
                nimcp_free(ctx);
                return;
            }

            // Copy statistics snapshot
            // WHY COPY: Atomic snapshot of counters
            nimcp_queue_manager_stats_t* stats = (nimcp_queue_manager_stats_t*) ctx->result;
            memcpy(stats, &channel->stats, sizeof(nimcp_queue_manager_stats_t));
            ctx->status = NIMCP_SUCCESS;
            break;
        }
    }

    // CRITICAL: Check if context was abandoned due to timeout
    // This must happen AFTER the operation completes but BEFORE signaling completion
    if (atomic_load(&ctx->abandoned)) {
        // Main thread timed out and abandoned this operation
        // We can't access ctx->result as it points to invalid/freed memory
        // Worker thread must free since main thread abandoned ownership
        nimcp_free(ctx);
        return;  // Exit handler immediately after cleanup
    }

    // Update operation latency statistics
    // WHY TRACK LATENCY: Monitor performance, detect bottlenecks
    uint64_t latency = nimcp_get_timestamp_ms() - start_time;
    atomic_fetch_add(&channel->stats.priorities[ctx->priority].op_latency_sum, latency);
    atomic_fetch_add(&channel->stats.priorities[ctx->priority].op_count, 1);

    // Signal operation completion
    // WHY ATOMIC: Allows wait loop to detect completion lock-free
    atomic_store(&ctx->completed, true);

    // NOTE: We don't free ctx here. The calling thread owns it and will free it after
    // reading the result (on success) or abandon it (on timeout, in which case the
    // abandoned check above will free it).
}

/**
 * @brief Submit operation to thread pool and wait for completion
 *
 * WHY THREAD POOL SUBMISSION:
 * - Parallel execution of queue operations
 * - No thread spawn overhead
 * - Work stealing for load balancing
 *
 * SYNCHRONIZATION STRATEGY:
 * - Submit operation to pool (async)
 * - Spin-wait on completion flag (low latency)
 * - Timeout detection via timestamp comparison
 *
 * WHY SPIN-WAIT vs CONDITION VARIABLE:
 * - Lower latency for short waits (<1ms typical)
 * - Simpler code (no mutex/cond vars)
 * - Trade-off: Higher CPU usage
 *
 * WHEN TO USE:
 * - Short operations (enqueue/dequeue ~50-200μs)
 * - Not suitable for long blocking operations
 *
 * ALGORITHM:
 * 1. Initialize context (completed=false)
 * 2. Submit to thread pool
 * 3. Spin-wait with timeout
 * 4. Return operation status
 *
 * COMPLEXITY: O(1) + operation complexity
 * THREAD SAFETY: Fully thread-safe
 *
 * @param manager Queue manager instance
 * @param op_ctx Operation context (in/out)
 * @return NIMCP_SUCCESS, NIMCP_TIMEOUT, or error code
 */
static nimcp_result_t submit_queue_operation(nimcp_queue_manager_handle_t manager,
                                             nimcp_queue_operation_ctx_t* op_ctx)
{
    if (!manager || !op_ctx)
        return NIMCP_INVALID_PARAM;

    // Store manager reference for handler access
    // WHY: Handler needs manager to access channels
    op_ctx->manager_handle = manager;
    atomic_store(&op_ctx->completed, false);
    atomic_store(&op_ctx->abandoned, false);

    // Submit to thread pool for async execution
    nimcp_result_t result =
        nimcp_pool_submit(manager->thread_pool, queue_operation_handler, op_ctx);

    if (result != NIMCP_SUCCESS) {
        // Thread pool submission failed, caller must free op_ctx
        nimcp_free(op_ctx);
        return result;
    }

    // Wait for operation completion with timeout
    // WHY SPIN-WAIT: Low latency for short operations
    uint64_t start_time = nimcp_get_timestamp_ms();
    while (!atomic_load(&op_ctx->completed)) {
        // Check for timeout
        if (nimcp_get_timestamp_ms() - start_time > op_ctx->timeout_ms) {
            // CRITICAL: Mark context as abandoned so worker knows not to write to result
            // The result pointer points to the caller's stack which will be invalid after we return
            atomic_store(&op_ctx->abandoned, true);
            // This leaks the context, but prevents use-after-free which is worse.
            // Timeouts should be rare in normal operation.
            return NIMCP_TIMEOUT;
        }
        // Yield briefly to prevent CPU saturation
        // WHY YIELD: Balance latency vs CPU usage
        nimcp_yield_thread();
    }

    // Worker has completed, safe to read result and free the context
    nimcp_result_t status = op_ctx->status;

    // Free the heap-allocated context now that we've read the result
    nimcp_free(op_ctx);

    return status;
}

//=============================================================================
// Public API Implementation
//=============================================================================

/**
 * @brief Create a new queue manager instance
 *
 * WHY QUEUE MANAGER:
 * - Simplifies multi-priority, multi-channel queue management
 * - Provides async operations via thread pool
 * - Centralized statistics and monitoring
 *
 * INITIALIZATION SEQUENCE:
 * 1. Validate configuration
 * 2. Allocate manager structure
 * 3. Allocate channel array
 * 4. Initialize each channel (3 queues per channel)
 * 5. Create thread pool
 * 6. Mark as initialized
 *
 * ERROR HANDLING:
 * - Any failure triggers complete cleanup
 * - No partial initialization left behind
 * - Clear error codes for debugging
 *
 * MEMORY LAYOUT:
 * manager (1 structure)
 *   ↳ channels (max_channels × nimcp_queue_channel_t)
 *       ↳ queues (3 × nimcp_queue_handle_t per channel)
 *           ↳ queue buffers (high_size + normal_size + low_size per channel)
 *
 * Total memory: ~(max_channels × (high+normal+low) × item_size)
 * Example: 10 channels, 1000/5000/500 sizes, 8-byte pointers = ~520KB
 *
 * COMPLEXITY: O(max_channels × priority_count)
 * THREAD SAFETY: Not thread-safe (call once during initialization)
 *
 * @param config Configuration parameters
 * @param manager Output pointer to receive manager handle
 * @return NIMCP_SUCCESS or error code
 */
nimcp_result_t nimcp_queue_manager_create(const nimcp_queue_manager_config_t* config,
                                          nimcp_queue_manager_handle_t* manager)
{
    if (!config || !manager)
        return NIMCP_INVALID_PARAM;

    // Validate configuration before allocating anything
    // WHY FIRST: Fail fast, no cleanup needed
    nimcp_result_t result = validate_config(config);
    if (result != NIMCP_SUCCESS)
        return result;

    // Allocate manager structure
    nimcp_queue_manager_t* mgr = nimcp_calloc(1, sizeof(nimcp_queue_manager_t));
    if (!mgr)
        return NIMCP_NO_MEMORY;

    // Allocate channel array
    mgr->channels = nimcp_calloc(config->max_channels, sizeof(nimcp_queue_channel_t));
    if (!mgr->channels) {
        nimcp_free(mgr);
        return NIMCP_NO_MEMORY;
    }

    // Initialize all channels
    for (size_t i = 0; i < config->max_channels; i++) {
        result = init_channel(&mgr->channels[i], config);
        if (result != NIMCP_SUCCESS) {
            // Cleanup on error: destroy already-initialized channels
            for (size_t j = 0; j < i; j++) {
                destroy_channel(&mgr->channels[j]);
            }
            nimcp_free(mgr->channels);
            nimcp_free(mgr);
            return result;
        }
    }

    // Create thread pool for async operations
    // WHY THREAD POOL: Parallel queue operations, thread reuse
    mgr->thread_pool = nimcp_pool_create(config->worker_threads > 0 ? config->worker_threads
                                                                    : DEFAULT_WORKER_THREADS);
    if (!mgr->thread_pool) {
        // Cleanup on error
        for (size_t i = 0; i < config->max_channels; i++) {
            destroy_channel(&mgr->channels[i]);
        }
        nimcp_free(mgr->channels);
        nimcp_free(mgr);
        return NIMCP_NO_MEMORY;
    }

    // Finalize initialization
    mgr->config = *config;
    atomic_store(&mgr->shutting_down, false);
    mgr->initialized = true;
    *manager = mgr;

    return NIMCP_SUCCESS;
}

/**
 * @brief Destroy queue manager and free all resources
 *
 * WHY CAREFUL SHUTDOWN:
 * - Must ensure no operations in flight
 * - Prevent use-after-free
 * - Complete resource cleanup
 *
 * SHUTDOWN SEQUENCE:
 * 1. Set shutdown flag (prevents new operations)
 * 2. Destroy thread pool (waits for pending operations)
 * 3. Destroy all channels (3 queues each)
 * 4. Free channel array
 * 5. Free manager structure
 *
 * WHY THIS ORDER:
 * - Shutdown flag first (prevents new work)
 * - Thread pool second (completes pending work)
 * - Channels third (no workers accessing them)
 * - Memory last (everything cleaned up)
 *
 * THREAD SAFETY:
 * - Assumes exclusive access (no concurrent operations)
 * - Caller must ensure no other threads using manager
 *
 * COMPLEXITY: O(max_channels × priority_count)
 *
 * @param manager Manager to destroy
 * @return NIMCP_SUCCESS or NIMCP_INVALID_PARAM
 */
nimcp_result_t nimcp_queue_manager_destroy(nimcp_queue_manager_handle_t manager)
{
    LOG_DEBUG("Entering nimcp_queue_manager_destroy");
    if (!manager)
        return NIMCP_INVALID_PARAM;

    // Signal shutdown to prevent new operations
    atomic_store(&manager->shutting_down, true);

    // Destroy thread pool (waits for pending operations)
    // WHY BEFORE CHANNELS: Ensures no workers accessing queues
    nimcp_pool_destroy(manager->thread_pool);

    // Cleanup all channels
    for (size_t i = 0; i < manager->config.max_channels; i++) {
        destroy_channel(&manager->channels[i]);
    }

    // Free memory
    nimcp_free(manager->channels);
    nimcp_free(manager);

    return NIMCP_SUCCESS;
}

/**
 * @brief Enqueue a message to specified channel
 *
 * WHY ENQUEUE:
 * - Non-blocking message submission
 * - Priority-based routing
 * - Async execution (doesn't block neural processing)
 *
 * PRIORITY MAPPING:
 * - message->flags & 0x3 extracts lower 2 bits
 * - 0 = LOW, 1 = NORMAL, 2 = HIGH
 *
 * WHY FLAGS-BASED:
 * - Caller controls priority without extra parameter
 * - Consistent with message structure design
 *
 * OPERATION FLOW:
 * 1. Validate inputs
 * 2. Extract priority from message flags
 * 3. Create operation context
 * 4. Submit to thread pool
 * 5. Wait for completion
 * 6. Return result
 *
 * CLONING:
 * - Message is deep-copied in handler
 * - Caller can reuse/free original immediately
 *
 * TIMEOUT BEHAVIOR:
 * - 0 or default: Uses manager default_timeout
 * - Non-zero: Uses specified value
 * - TIMEOUT error if operation doesn't complete in time
 *
 * COMPLEXITY: O(1) + O(message_size) for clone
 * THREAD SAFETY: Fully thread-safe
 *
 * @param manager Queue manager instance
 * @param channel_id Channel to enqueue to
 * @param message Message to enqueue (will be cloned)
 * @param timeout_ms Operation timeout (0 = use default)
 * @return NIMCP_SUCCESS, NIMCP_QUEUE_FULL, NIMCP_TIMEOUT, or error code
 */
nimcp_result_t nimcp_queue_manager_enqueue(nimcp_queue_manager_handle_t manager,
                                           uint32_t channel_id, const nimcp_message_t* message,
                                           uint32_t timeout_ms)
{
    if (!is_valid_channel(manager, channel_id) || !message) {
        return NIMCP_INVALID_PARAM;
    }

    // Map message flags to queue priority
    // WHY LOWER 2 BITS: Reserves rest of flags for other uses
    // Encoding: 0=low, 1=normal, 2=high
    nimcp_queue_priority_t priority = NIMCP_QUEUE_PRIORITY_NORMAL;
    uint32_t priority_bits = message->flags & 0x3;
    if (priority_bits == 2) {
        priority = NIMCP_QUEUE_PRIORITY_HIGH;
    } else if (priority_bits == 0) {
        priority = NIMCP_QUEUE_PRIORITY_LOW;
    }

    // CRITICAL: Heap-allocate context to prevent stack-use-after-return
    nimcp_queue_operation_ctx_t* op_ctx = nimcp_malloc(sizeof(nimcp_queue_operation_ctx_t));
    if (!op_ctx) {
        return NIMCP_NO_MEMORY;
    }

    *op_ctx = (nimcp_queue_operation_ctx_t){
        .op_type = NIMCP_QUEUE_OP_ENQUEUE,
        .channel_id = channel_id,
        .priority = priority,
        .message = (nimcp_message_t*) message,  // Cast away const (won't be modified)
        .timeout_ms = timeout_ms ? timeout_ms : manager->config.default_timeout};

    // Submit and wait for completion (submit_queue_operation will free op_ctx)
    return submit_queue_operation(manager, op_ctx);
}

/**
 * @brief Dequeue highest-priority message from channel
 *
 * WHY PRIORITY-ORDERED:
 * - HIGH priority messages processed first
 * - Prevents head-of-line blocking
 * - Critical events handled immediately
 *
 * DEQUEUE STRATEGY:
 * 1. Try HIGH priority (timeout=0, non-blocking)
 * 2. If empty, try NORMAL (timeout=0, non-blocking)
 * 3. If empty, try LOW (timeout=caller timeout, blocking)
 *
 * WHY THIS STRATEGY:
 * - Always prefer higher priorities
 * - Only block on lowest priority
 * - Minimizes latency for urgent messages
 *
 * EXAMPLE SCENARIO:
 * - HIGH queue: 5 messages
 * - NORMAL queue: 100 messages
 * - LOW queue: 1000 messages
 *
 * Dequeue returns HIGH messages first, then NORMAL, then LOW
 * Ensures urgent neural spikes processed before background work
 *
 * TIMEOUT BEHAVIOR:
 * - Applied only to LOW priority queue
 * - Higher priorities checked with zero timeout
 * - If all queues empty, LOW queue blocks up to timeout
 *
 * OWNERSHIP:
 * - Caller receives pointer to message
 * - Caller responsible for calling nimcp_msg_destroy()
 *
 * COMPLEXITY: O(3) worst case (checks all 3 priorities)
 * THREAD SAFETY: Fully thread-safe
 *
 * @param manager Queue manager instance
 * @param channel_id Channel to dequeue from
 * @param message Output pointer to receive message
 * @param timeout_ms Timeout for LOW priority (ignored for HIGH/NORMAL)
 * @return NIMCP_SUCCESS, NIMCP_QUEUE_EMPTY, NIMCP_TIMEOUT, or error code
 */
nimcp_result_t nimcp_queue_manager_dequeue(nimcp_queue_manager_handle_t manager,
                                           uint32_t channel_id, nimcp_message_t** message,
                                           uint32_t timeout_ms)
{
    if (!is_valid_channel(manager, channel_id) || !message) {
        return NIMCP_INVALID_PARAM;
    }

    // Try dequeuing from each priority level, starting with highest
    // WHY HIGH→LOW: Ensures critical messages processed first
    for (int pri = NIMCP_QUEUE_PRIORITY_HIGH; pri < NIMCP_QUEUE_PRIORITY_COUNT; pri++) {
        // CRITICAL: Heap-allocate context to prevent stack-use-after-return
        // The context will be freed by submit_queue_operation() on success,
        // or leaked on timeout (to prevent use-after-free).
        nimcp_queue_operation_ctx_t* op_ctx = nimcp_malloc(sizeof(nimcp_queue_operation_ctx_t));
        if (!op_ctx) {
            return NIMCP_NO_MEMORY;
        }

        *op_ctx = (nimcp_queue_operation_ctx_t){
            .op_type = NIMCP_QUEUE_OP_DEQUEUE,
            .channel_id = channel_id,
            .priority = pri,
            .result = message,
            // Only wait on lowest priority, check others with zero timeout
            // WHY: Minimizes latency for high-priority messages
            .timeout_ms = (pri == NIMCP_QUEUE_PRIORITY_LOW)
                              ? (timeout_ms ? timeout_ms : manager->config.default_timeout)
                              : 0};

        nimcp_result_t result = submit_queue_operation(manager, op_ctx);
        if (result == NIMCP_SUCCESS) {
            return NIMCP_SUCCESS;
        }

        // Only continue to lower priority if queue was empty
        // WHY: Other errors (timeout, etc.) should propagate
        if (result != NIMCP_QUEUE_EMPTY) {
            return result;
        }

        // NOTE: op_ctx is freed by submit_queue_operation() in all cases:
        // - On success: freed after reading result (line 710)
        // - On timeout: intentionally leaked to prevent use-after-free, worker frees it (line 579)
        // - On submit failure: freed immediately (line 684)
    }

    // All priority queues empty
    return NIMCP_QUEUE_EMPTY;
}

/**
 * @brief Get statistics for a channel
 *
 * WHY STATISTICS:
 * - Monitor queue health (peak sizes, drop rates)
 * - Detect bottlenecks (high latency, full queues)
 * - Tune configuration (resize queues, add workers)
 *
 * STATISTICS PROVIDED:
 * - Per-priority: enqueued, dequeued, dropped, current/peak size
 * - Operation latency: sum and count (compute average)
 *
 * CONSISTENCY:
 * - Atomic snapshot of counters
 * - Not guaranteed to be perfectly consistent (concurrent updates)
 * - Good enough for monitoring (eventual consistency)
 *
 * WHY ATOMIC vs LOCKED:
 * - Lower overhead
 * - Non-blocking reads
 * - Acceptable inconsistency for stats
 *
 * COMPLEXITY: O(1) - just memcpy
 * THREAD SAFETY: Fully thread-safe (atomic reads)
 *
 * @param manager Queue manager instance
 * @param channel_id Channel to get stats for
 * @param stats Output structure to receive statistics
 * @return NIMCP_SUCCESS or error code
 */
nimcp_result_t nimcp_queue_manager_get_stats(nimcp_queue_manager_handle_t manager,
                                             uint32_t channel_id,
                                             nimcp_queue_manager_stats_t* stats)
{
    if (!is_valid_channel(manager, channel_id) || !stats) {
        return NIMCP_INVALID_PARAM;
    }

    // CRITICAL: Heap-allocate context to prevent stack-use-after-return
    nimcp_queue_operation_ctx_t* op_ctx = nimcp_malloc(sizeof(nimcp_queue_operation_ctx_t));
    if (!op_ctx) {
        return NIMCP_NO_MEMORY;
    }

    *op_ctx = (nimcp_queue_operation_ctx_t){.op_type = NIMCP_QUEUE_OP_GET_STATS,
                                             .channel_id = channel_id,
                                             .result = stats,
                                             .timeout_ms = manager->config.default_timeout};

    return submit_queue_operation(manager, op_ctx);
}

/**
 * @brief Clear all messages from a channel
 *
 * WHY CLEAR:
 * - Emergency reset (system overload)
 * - Test/debug (reset state)
 * - Reconfiguration (drain before changing config)
 *
 * OPERATION:
 * - Clears all three priority queues
 * - Resets current_size to 0
 * - Preserves other statistics (enqueued, dequeued counts)
 *
 * WHY PRESERVE STATS:
 * - Historical data valuable for analysis
 * - Clear is operational, not monitoring reset
 *
 * THREAD SAFETY:
 * - Each queue cleared independently
 * - Concurrent enqueues may occur (eventual consistency)
 *
 * COMPLEXITY: O(priority_count × queue_size)
 *
 * @param manager Queue manager instance
 * @param channel_id Channel to clear
 * @return NIMCP_SUCCESS or error code
 */
nimcp_result_t nimcp_queue_manager_clear(nimcp_queue_manager_handle_t manager, uint32_t channel_id)
{
    LOG_DEBUG("Entering nimcp_queue_manager_clear");
    if (!is_valid_channel(manager, channel_id)) {
        return NIMCP_INVALID_PARAM;
    }

    nimcp_result_t final_result = NIMCP_SUCCESS;

    // Clear all priority queues
    for (int pri = 0; pri < NIMCP_QUEUE_PRIORITY_COUNT; pri++) {
        // CRITICAL: Heap-allocate context to prevent stack-use-after-return
        nimcp_queue_operation_ctx_t* op_ctx = nimcp_malloc(sizeof(nimcp_queue_operation_ctx_t));
        if (!op_ctx) {
            return NIMCP_NO_MEMORY;
        }

        *op_ctx = (nimcp_queue_operation_ctx_t){.op_type = NIMCP_QUEUE_OP_CLEAR,
                                                 .channel_id = channel_id,
                                                 .priority = pri,
                                                 .timeout_ms = manager->config.default_timeout};

        nimcp_result_t result = submit_queue_operation(manager, op_ctx);
        if (result != NIMCP_SUCCESS) {
            final_result = result;  // Track last error
        }
    }

    // Return last error encountered (or SUCCESS if none)
    return final_result;
}

/**
 * @brief Update default timeout for all operations
 *
 * WHY CONFIGURABLE TIMEOUT:
 * - Different scenarios need different timeouts
 * - High load: Increase timeout to avoid premature failures
 * - Low latency: Decrease timeout for faster failure detection
 *
 * APPLIES TO:
 * - All future operations using default timeout (timeout_ms=0)
 * - Does not affect operations with explicit timeout
 *
 * THREAD SAFETY:
 * - Simple scalar write (no synchronization needed)
 * - Races possible but harmless (just uses old or new value)
 *
 * COMPLEXITY: O(1)
 *
 * @param manager Queue manager instance
 * @param timeout_ms New default timeout in milliseconds
 * @return NIMCP_SUCCESS or NIMCP_INVALID_PARAM
 */
nimcp_result_t nimcp_queue_manager_set_timeout(nimcp_queue_manager_handle_t manager,
                                               uint32_t timeout_ms)
{
    if (!manager || !manager->initialized) {
        return NIMCP_INVALID_PARAM;
    }

    manager->config.default_timeout = timeout_ms;
    return NIMCP_SUCCESS;
}

/**
 * @brief Check if a priority queue is empty
 *
 * WHY CHECK EMPTY:
 * - Avoid blocking on known-empty queue
 * - Monitoring/debugging
 * - Conditional logic (skip if empty)
 *
 * IMPLEMENTATION:
 * - Reads atomic current_size counter
 * - Lock-free, non-blocking
 * - Eventually consistent (concurrent updates possible)
 *
 * RACE CONDITIONS:
 * - Size could change immediately after check
 * - Acceptable for monitoring use case
 * - Don't rely on this for critical logic
 *
 * COMPLEXITY: O(1)
 * THREAD SAFETY: Lock-free atomic read
 *
 * @param manager Queue manager instance
 * @param channel_id Channel to check
 * @param priority Priority queue to check
 * @return true if empty (or invalid params), false otherwise
 */
bool nimcp_queue_manager_is_empty(nimcp_queue_manager_handle_t manager, uint32_t channel_id,
                                  nimcp_queue_priority_t priority)
{
    if (!is_valid_channel(manager, channel_id) || priority >= NIMCP_QUEUE_PRIORITY_COUNT) {
        return true;  // Defensive: invalid queue is considered empty
    }

    nimcp_queue_channel_t* channel = &manager->channels[channel_id];
    return atomic_load(&channel->stats.priorities[priority].current_size) == 0;
}

/**
 * @brief Check if a priority queue is full
 *
 * WHY CHECK FULL:
 * - Backpressure detection
 * - Monitoring alerts (queue saturation)
 * - Conditional logic (skip enqueue if full)
 *
 * IMPLEMENTATION:
 * - Compares current_size to configured max_size
 * - Lock-free atomic read
 * - Eventually consistent
 *
 * COMPLEXITY: O(1)
 * THREAD SAFETY: Lock-free atomic read
 *
 * @param manager Queue manager instance
 * @param channel_id Channel to check
 * @param priority Priority queue to check
 * @return true if full (or invalid params), false otherwise
 */
bool nimcp_queue_manager_is_full(nimcp_queue_manager_handle_t manager, uint32_t channel_id,
                                 nimcp_queue_priority_t priority)
{
    if (!is_valid_channel(manager, channel_id) || priority >= NIMCP_QUEUE_PRIORITY_COUNT) {
        return false;  // Cannot determine state of invalid queue
    }

    nimcp_queue_channel_t* channel = &manager->channels[channel_id];
    size_t max_size = get_queue_size_for_priority(&manager->config, priority);
    return atomic_load(&channel->stats.priorities[priority].current_size) >= max_size;
}

/**
 * @brief Get current size of a priority queue
 *
 * WHY GET SIZE:
 * - Monitoring queue depth
 * - Load balancing decisions
 * - Debugging
 *
 * IMPLEMENTATION:
 * - Returns atomic current_size counter
 * - Lock-free, non-blocking
 * - Eventually consistent
 *
 * COMPLEXITY: O(1)
 * THREAD SAFETY: Lock-free atomic read
 *
 * @param manager Queue manager instance
 * @param channel_id Channel to check
 * @param priority Priority queue to check
 * @return Current queue size (0 if invalid params)
 */
size_t nimcp_queue_manager_get_size(nimcp_queue_manager_handle_t manager, uint32_t channel_id,
                                    nimcp_queue_priority_t priority)
{
    if (!is_valid_channel(manager, channel_id) || priority >= NIMCP_QUEUE_PRIORITY_COUNT) {
        return 0;  // Defensive: invalid params return 0
    }

    nimcp_queue_channel_t* channel = &manager->channels[channel_id];
    return atomic_load(&channel->stats.priorities[priority].current_size);
}

//=============================================================================
// Helper Functions
//=============================================================================

/**
 * @brief Get current timestamp in milliseconds
 *
 * WHY MILLISECONDS:
 * - Sufficient precision for queue operations (typically 50-500μs)
 * - Lower overhead than nanoseconds
 * - Easy to reason about (1000ms = 1 second)
 *
 * WHY CLOCK_MONOTONIC:
 * - Not affected by system clock changes
 * - Always moves forward
 * - Perfect for timeouts and latency measurement
 *
 * COMPLEXITY: O(1) system call
 * THREAD SAFETY: Fully thread-safe
 *
 * @return Timestamp in milliseconds
 */
static uint64_t nimcp_get_timestamp_ms(void)
{
    LOG_DEBUG("Entering nimcp_get_timestamp_ms");
    struct timespec ts;
    clock_gettime(CLOCK_MONOTONIC, &ts);
    return (uint64_t) (ts.tv_sec * 1000 + ts.tv_nsec / 1000000);
}

/**
 * @brief Yield thread execution briefly
 *
 * WHY YIELD:
 * - Prevents CPU saturation during spin-wait
 * - Allows other threads to run
 * - Balances latency vs CPU usage
 *
 * WHY 100 MICROSECONDS:
 * - Long enough to allow context switch
 * - Short enough to maintain low latency
 * - Tunable based on workload characteristics
 *
 * ALTERNATIVE APPROACHES:
 * - sched_yield(): Too aggressive, high context switch overhead
 * - No yield: 100% CPU usage, poor for shared systems
 * - Longer sleep: Higher latency
 *
 * COMPLEXITY: O(1) system call
 * THREAD SAFETY: Fully thread-safe
 */
static void nimcp_yield_thread(void)
{
    LOG_DEBUG("Entering nimcp_yield_thread");
    struct timespec ts = {0, 100000};  // 100 microseconds
    nanosleep(&ts, NULL);
}
