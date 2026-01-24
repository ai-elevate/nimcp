/**
 * @file nimcp_meta_learning.c
 * @brief Phase 10.8: Meta-Learning Implementation - MAML Algorithm
 *
 * WHAT: Model-Agnostic Meta-Learning for rapid task adaptation
 * WHY:  Enable few-shot learning (1-shot, 5-shot, 10-shot)
 * HOW:  Implement MAML's two-level optimization (inner/outer loops)
 *
 * ALGORITHM OVERVIEW:
 * Inner Loop: θ' ← θ - α∇_θ L_support(θ)  (task-specific adaptation)
 * Outer Loop: θ ← θ - β∇_θ L_query(θ')     (meta-learning update)
 *
 * BIO-ASYNC INTEGRATION:
 * - Module ID: 0x0336 (BIO_MODULE_META_LEARNING)
 * - Publishes: adaptation events, task completions
 * - Subscribes: training triggers, task specifications
 *
 * @author NIMCP Phase 10 Team
 * @date 2025-11-09
 */

#define LOG_MODULE "meta_learning"

#include "cognitive/nimcp_meta_learning.h"
#include "cognitive/meta_learning/nimcp_meta_learning_snn_bridge.h"
#include "cognitive/meta_learning/nimcp_meta_learning_plasticity_bridge.h"
#include "cognitive/knowledge/nimcp_kg_reader.h"
#include "security/nimcp_security.h"
#include "security/nimcp_blood_brain_barrier.h"

#include "async/nimcp_bio_async.h"
#include "async/nimcp_bio_router.h"
#include "async/nimcp_bio_messages.h"
#include "utils/memory/nimcp_unified_memory.h"
#include "utils/logging/nimcp_logging.h"
#include "utils/containers/nimcp_vector.h"
#include "core/brain/nimcp_brain.h"
#include <string.h>
#include <math.h>
#include <stdio.h>
#include <stdarg.h>
#include "utils/memory/nimcp_memory_guards.h"  // For nimcp_calloc/nimcp_free
#include "utils/exception/nimcp_exception_macros.h"

//=============================================================================
// BIO-ASYNC MODULE REGISTRATION
//=============================================================================

#define BIO_MODULE_META_LEARNING 0x0336

//=============================================================================
// Error Handling (module-local)
//=============================================================================

static char last_error[512] = {0};

static void set_error(const char* fmt, ...)
{
    va_list args;
    va_start(args, fmt);
    vsnprintf(last_error, sizeof(last_error), fmt, args);
    va_end(args);
}

//=============================================================================
// Named Constants (NIMCP Coding Standards)
//=============================================================================

// MAML Hyperparameters
#define DEFAULT_INNER_LR 0.01f           // Task adaptation learning rate
#define DEFAULT_OUTER_LR 0.001f          // Meta-learning rate
#define DEFAULT_INNER_STEPS 5            // Gradient steps per task
#define DEFAULT_OUTER_BATCH_SIZE 8       // Tasks per meta-update
#define DEFAULT_SIMILARITY_THRESHOLD 0.7f // Transfer if similarity > 0.7

// Adaptive Learning Rates (per region)
#define LR_SENSORY_INIT 0.0001f          // V1, A1 (low plasticity)
#define LR_ASSOCIATION_INIT 0.001f       // IT, STS (medium plasticity)
#define LR_PREFRONTAL_INIT 0.01f         // PFC, OFC (high plasticity)

// Adaptive LR bounds
#define LR_MIN 0.00001f                  // Minimum learning rate
#define LR_MAX 0.1f                      // Maximum learning rate
#define LR_INCREASE_FACTOR 1.05f         // Multiply when loss decreases
#define LR_DECREASE_FACTOR 0.5f          // Multiply when loss increases

// Performance tracking
#define MAX_TASK_HISTORY 1000            // Maximum tasks to remember
#define CONVERGENCE_THRESHOLD 0.001f     // Loss delta for convergence

//=============================================================================
// Internal Structures (Opaque Pointer Implementation)
//=============================================================================

/**
 * @brief Meta-learner internal state
 *
 * WHAT: Complete state for MAML meta-learning
 * WHY:  Encapsulate implementation details
 * HOW:  Opaque pointer pattern (hidden from users)
 */
struct meta_learner_s {
    // Configuration
    meta_learning_config_t config;
    uint32_t num_regions;

    // Adaptive learning rates (per region)
    float learning_rates[META_REGION_COUNT];
    float previous_loss[META_REGION_COUNT];

    // Task history (for similarity computation)
    meta_task_t** task_history;
    uint32_t num_tasks_seen;
    uint32_t task_history_capacity;

    // Statistics
    float total_adaptation_gain;        // Sum of all adaptation gains
    uint64_t total_adaptation_steps;    // Sum of convergence steps
    uint32_t num_adaptations;           // Number of adaptations performed

    // Bio-async integration
    bio_module_context_t bio_ctx;   /**< Bio-async module context */
    bool bio_async_enabled;         /**< Bio-async registration status */

    // SNN and Plasticity bridge integration
    meta_learning_snn_bridge_t* snn_bridge;           /**< SNN bridge for spike-based meta-learning */
    meta_learning_plasticity_bridge_t* plasticity_bridge; /**< Plasticity bridge for synaptic learning */
    bool bridges_enabled;                              /**< Bridge integration status */
};

//=============================================================================
// Forward Declarations (Internal Helpers)
//=============================================================================

static float compute_loss(brain_t brain, const float** inputs,
                         const uint32_t* labels, uint32_t num_samples);
static brain_t clone_brain_parameters(brain_t source);
static bool apply_gradient_step(brain_t brain, const float** inputs,
                               const uint32_t* labels, uint32_t num_samples,
                               float learning_rate);
static bool add_task_to_history(meta_learner_t meta, const meta_task_t* task);

//=============================================================================
// Public API: Creation & Destruction
//=============================================================================

/**
 * @brief Get default meta-learning configuration
 *
 * WHAT: Return sensible defaults for MAML
 * WHY:  Simplify initialization for common use cases
 * HOW:  Struct with proven hyperparameters from Finn et al. (2017)
 *
 * COMPLEXITY: O(1)
 */
meta_learning_config_t meta_learning_default_config(void)
{
    meta_learning_config_t config = {
        .algorithm = META_ALGORITHM_MAML,
        .few_shot_k = FEW_SHOT_5,

        .inner_learning_rate = DEFAULT_INNER_LR,
        .inner_steps = DEFAULT_INNER_STEPS,

        .outer_learning_rate = DEFAULT_OUTER_LR,
        .outer_batch_size = DEFAULT_OUTER_BATCH_SIZE,

        .enable_task_similarity = true,
        .enable_adaptive_lr = true,
        .similarity_threshold = DEFAULT_SIMILARITY_THRESHOLD,

        .track_adaptation_speed = true,
        .max_adaptation_steps = 100
    };
    return config;
}

/**
 * @brief Create meta-learner
 *
 * WHAT: Initialize MAML meta-learning system
 * WHY:  Enable few-shot learning and fast adaptation
 * HOW:  Allocate state, initialize adaptive learning rates
 *
 * @param config Configuration (NULL for defaults)
 * @param num_regions Number of brain regions
 * @return Meta-learner handle or NULL on error
 *
 * COMPLEXITY: O(num_regions)
 * MEMORY: O(MAX_TASK_HISTORY)
 */
meta_learner_t meta_learner_create(const meta_learning_config_t* config,
                                   uint32_t num_regions)
{
    // =========================================================================
    // GUARD: Validate inputs
    // =========================================================================

    if (num_regions == 0) {
        set_error("Invalid num_regions: must be > 0");
        return NULL;
    }

    // =========================================================================
    // ALLOCATE: Meta-learner structure
    // =========================================================================

    meta_learner_t meta = nimcp_calloc(1, sizeof(struct meta_learner_s));
    if (!meta) {
        set_error("Failed to allocate meta_learner_s (%zu bytes)",
                 sizeof(struct meta_learner_s));
        return NULL;
    }

    // =========================================================================
    // INITIALIZE: Configuration
    // =========================================================================

    if (config) {
        meta->config = *config;
    } else {
        meta->config = meta_learning_default_config();
    }

    meta->num_regions = num_regions;

    // =========================================================================
    // INITIALIZE: Adaptive learning rates per region
    // =========================================================================
    // WHAT: Set initial LR based on neuroscience (sensory = stable, PFC = flexible)
    // WHY:  Different brain regions have different plasticity profiles
    // HOW:  Use named constants for region-specific initialization

    meta->learning_rates[META_REGION_SENSORY] = LR_SENSORY_INIT;
    meta->learning_rates[META_REGION_ASSOCIATION] = LR_ASSOCIATION_INIT;
    meta->learning_rates[META_REGION_PREFRONTAL] = LR_PREFRONTAL_INIT;

    // Initialize previous loss to infinity (no history yet)
    for (uint32_t i = 0; i < META_REGION_COUNT; i++) {
        meta->previous_loss[i] = INFINITY;
    }

    // =========================================================================
    // ALLOCATE: Task history for similarity computation
    // =========================================================================

    meta->task_history_capacity = MAX_TASK_HISTORY;
    meta->task_history = nimcp_calloc(MAX_TASK_HISTORY, sizeof(meta_task_t*));
    if (!meta->task_history) {
        set_error("Failed to allocate task history");
        nimcp_free(meta);
        return NULL;
    }

    meta->num_tasks_seen = 0;

    // =========================================================================
    // INITIALIZE: Statistics
    // =========================================================================

    meta->total_adaptation_gain = 0.0F;
    meta->total_adaptation_steps = 0;
    meta->num_adaptations = 0;

    NIMCP_LOGGING_DEBUG("Meta-learner created: algorithm=%d, K=%d, inner_lr=%.5f, outer_lr=%.5f",
                       meta->config.algorithm, meta->config.few_shot_k,
                       meta->config.inner_learning_rate, meta->config.outer_learning_rate);

    
    // Bio-async registration
    meta->bio_ctx = NULL;
    meta->bio_async_enabled = false;
    if (bio_router_is_initialized()) {
        bio_module_info_t bio_info = {
            .module_id = BIO_MODULE_KNOWLEDGE_META_LEARNING,
            .module_name = "meta_learning",
            .inbox_capacity = 32,
            .user_data = meta
        };
        meta->bio_ctx = bio_router_register_module(&bio_info);
        if (meta->bio_ctx) {
            meta->bio_async_enabled = true;
        }
    }

    // =========================================================================
    // INITIALIZE: SNN and Plasticity bridges
    // =========================================================================

    meta->snn_bridge = NULL;
    meta->plasticity_bridge = NULL;
    meta->bridges_enabled = false;

    // Create SNN bridge with default config
    meta_learning_snn_config_t snn_config = meta_learning_snn_config_default();
    meta->snn_bridge = meta_learning_snn_create(&snn_config);

    // Create Plasticity bridge with default config
    meta_learning_plasticity_config_t plasticity_config = meta_learning_plasticity_config_default();
    meta->plasticity_bridge = meta_learning_plasticity_create(&plasticity_config);

    // Set bridges_enabled if both bridges created successfully
    if (meta->snn_bridge && meta->plasticity_bridge) {
        meta->bridges_enabled = true;
        NIMCP_LOGGING_DEBUG("Meta-learner bridges enabled: SNN and Plasticity");
    } else {
        NIMCP_LOGGING_DEBUG("Meta-learner bridges partially enabled or disabled");
    }

    return meta;
}

/**
 * @brief Destroy meta-learner
 *
 * WHAT: Free all meta-learning resources
 * WHY:  Prevent memory leaks
 * HOW:  Free task history and main structure
 *
 * COMPLEXITY: O(num_tasks_seen)
 */
void meta_learner_destroy(meta_learner_t meta)
{
    // Guard clause: Handle NULL gracefully
    if (!meta) {
        return;
    }

    // Destroy SNN and Plasticity bridges
    if (meta->snn_bridge) {
        meta_learning_snn_destroy(meta->snn_bridge);
        meta->snn_bridge = NULL;
    }
    if (meta->plasticity_bridge) {
        meta_learning_plasticity_destroy(meta->plasticity_bridge);
        meta->plasticity_bridge = NULL;
    }
    meta->bridges_enabled = false;

    // Free task history
    if (meta->task_history) {
        for (uint32_t i = 0; i < meta->num_tasks_seen; i++) {
            if (meta->task_history[i]) {
                meta_task_destroy(meta->task_history[i]);
            }
        }
        nimcp_free(meta->task_history);
    }

    // Free meta-learner structure
    nimcp_free(meta);

    NIMCP_LOGGING_DEBUG("Meta-learner destroyed");
}

//=============================================================================
// Public API: MAML Core Functions
//=============================================================================

/**
 * @brief Perform MAML inner loop (task adaptation)
 *
 * WHAT: Adapt brain to new task using K examples (support set)
 * WHY:  Core of few-shot learning - fast task-specific optimization
 * HOW:  Clone parameters, take K gradient steps on support set
 *
 * ALGORITHM:
 * θ' ← clone(θ)
 * for step in 1..inner_steps:
 *     loss ← compute_loss(θ', support_inputs, support_labels)
 *     θ' ← θ' - α * ∇_θ' loss
 * return θ'
 *
 * @param meta Meta-learner handle
 * @param brain Original brain (θ)
 * @param support_inputs Support set inputs [K × input_dim]
 * @param support_labels Support set labels [K]
 * @param num_support Number of support examples (K)
 * @param adapted_brain Output: adapted brain (θ')
 * @return true on success, false on error
 *
 * COMPLEXITY: O(inner_steps * network_forward_backward)
 */
bool meta_maml_inner_loop(meta_learner_t meta, brain_t brain,
                          const float** support_inputs, const uint32_t* support_labels,
                          uint32_t num_support, brain_t* adapted_brain)
{
    // =========================================================================
    // GUARD: Validate inputs
    // =========================================================================

    if (!meta) {
        set_error("NULL meta-learner");
        return false;
    }

    // Process pending bio-async messages
    if (meta->bio_async_enabled && meta->bio_ctx) {
        bio_router_process_inbox(meta->bio_ctx, 5);
    }

    if (!brain) {
        set_error("NULL brain");
        return false;
    }

    if (!support_inputs || !support_labels) {
        set_error("NULL support set");
        return false;
    }

    if (num_support == 0) {
        set_error("Empty support set");
        return false;
    }

    if (!adapted_brain) {
        set_error("NULL output pointer for adapted_brain");
        return false;
    }

    // =========================================================================
    // STEP 1: Clone brain parameters (θ → θ')
    // =========================================================================
    // WHAT: Create independent copy of brain
    // WHY:  Inner loop modifies parameters without affecting original
    // HOW:  Deep copy network weights

    brain_t cloned = clone_brain_parameters(brain);
    if (!cloned) {
        set_error("Failed to clone brain for inner loop");
        return false;
    }

    // =========================================================================
    // STEP 2: Inner loop adaptation (K gradient steps)
    // =========================================================================
    // WHAT: Optimize cloned brain on support set
    // WHY:  Specialize to new task using few examples
    // HOW:  Gradient descent with inner_learning_rate

    for (uint32_t step = 0; step < meta->config.inner_steps; step++) {
        bool success = apply_gradient_step(cloned, support_inputs, support_labels,
                                          num_support, meta->config.inner_learning_rate);
        if (!success) {
            set_error("Inner loop gradient step %u failed", step);
            brain_destroy(cloned);
            return false;
        }

        // Optional: Early stopping if converged
        if (step > 0 && meta->config.track_adaptation_speed) {
            float loss = compute_loss(cloned, support_inputs, support_labels, num_support);
            if (fabsf(loss) < CONVERGENCE_THRESHOLD) {
                NIMCP_LOGGING_DEBUG("Inner loop converged at step %u (loss=%.6f)", step, loss);
                break;
            }
        }
    }

    // =========================================================================
    // RETURN: Adapted brain (θ')
    // =========================================================================

    *adapted_brain = cloned;

    NIMCP_LOGGING_DEBUG("Inner loop complete: %u steps, K=%u support examples",
                       meta->config.inner_steps, num_support);

    return true;
}

/**
 * @brief Perform MAML outer loop (meta-update)
 *
 * WHAT: Update meta-parameters θ for better adaptation
 * WHY:  Learn initialization that enables fast few-shot learning
 * HOW:  Backprop through inner loop to compute meta-gradient
 *
 * ALGORITHM:
 * meta_gradient ← 0
 * for each task T_i in batch:
 *     θ'_i ← inner_loop(θ, T_i.support)
 *     L_query ← loss(θ'_i, T_i.query)
 *     meta_gradient += ∇_θ L_query  (chain rule through inner loop)
 * θ ← θ - β * meta_gradient / |batch|
 *
 * NOTE: This is a simplified implementation. Full MAML requires
 * computing second-order derivatives (Hessian), which is expensive.
 * We use First-Order MAML (FOMAML) for efficiency.
 *
 * @param meta Meta-learner handle
 * @param brain Brain with meta-parameters θ
 * @param tasks Array of tasks (each has support + query sets)
 * @param num_tasks Task batch size
 * @return true on success, false on error
 *
 * COMPLEXITY: O(num_tasks * inner_steps * network_size)
 */
bool meta_maml_outer_loop(meta_learner_t meta, brain_t brain,
                          meta_task_t** tasks, uint32_t num_tasks)
{
    // =========================================================================
    // GUARD: Validate inputs
    // =========================================================================

    if (!meta || !brain || !tasks) {
        set_error("NULL parameter in meta_maml_outer_loop");
        return false;
    }

    if (num_tasks == 0) {
        set_error("Empty task batch");
        return false;
    }

    // =========================================================================
    // META-OPTIMIZATION LOOP (Reptile-style)
    // =========================================================================
    // WHAT: Update θ using parameter averaging from task adaptations
    // WHY:  Learn parameters that work well across task distribution
    // HOW:  Reptile algorithm: θ ← θ + ε(θ_adapted - θ)
    //
    // NOTE: This implements Reptile (Nichol et al., 2018), which is
    // computationally cheaper than full MAML but achieves similar performance.
    // Reptile: θ ← θ + β * (θ_task - θ)
    // where θ_task is the result of K gradient steps on task support set

    NIMCP_LOGGING_DEBUG("Meta outer loop: processing %u tasks (Reptile-style)", num_tasks);

    // For Reptile-style meta-learning, we would:
    // 1. Clone brain K times (one per task)
    // 2. Adapt each clone to its task
    // 3. Average the adapted parameters
    // 4. Move original brain toward average
    //
    // However, without direct parameter access, we implement a simplified version:
    // - Track adaptation success across tasks
    // - Update task history for transfer learning
    // - Return success to indicate readiness for meta-learning

    uint32_t successful_adaptations = 0;
    float total_task_loss = 0.0F;

    // Process each task and update statistics
    for (uint32_t i = 0; i < num_tasks; i++) {
        if (tasks[i]) {
            // Update task history for transfer learning
            add_task_to_history(meta, tasks[i]);

            // Track task difficulty
            total_task_loss += tasks[i]->average_loss;
            successful_adaptations++;

            // Update meta-learner statistics
            meta->num_tasks_seen++;
        }
    }

    if (successful_adaptations == 0) {
        set_error("No valid tasks in batch");
        return false;
    }

    // Log meta-learning progress
    float avg_task_loss = total_task_loss / successful_adaptations;
    NIMCP_LOGGING_DEBUG("Meta-learning: %u/%u tasks processed, avg_loss=%.4f",
                       successful_adaptations, num_tasks, avg_task_loss);

    // NOTE: Full Reptile implementation would update brain parameters here
    // This requires direct weight access, which will be added in future
    // training pipeline integration. For now, we track statistics for
    // adaptive learning rates and transfer learning.

    return true;
}

/**
 * @brief Evaluate adaptation performance
 *
 * WHAT: Measure adaptation quality on query set
 * WHY:  Quantify meta-learning effectiveness
 * HOW:  Compare loss/accuracy before vs after adaptation
 *
 * @param meta Meta-learner handle
 * @param brain Original brain (θ)
 * @param adapted_brain Adapted brain (θ')
 * @param query_inputs Query set inputs
 * @param query_labels Query set labels
 * @param num_query Number of query examples
 * @param stats Output: adaptation statistics
 * @return true on success
 *
 * COMPLEXITY: O(num_query * network_forward)
 */
bool meta_evaluate_adaptation(meta_learner_t meta, brain_t brain, brain_t adapted_brain,
                              const float** query_inputs, const uint32_t* query_labels,
                              uint32_t num_query, adaptation_stats_t* stats)
{
    // =========================================================================
    // GUARD: Validate inputs
    // =========================================================================

    if (!meta || !brain || !adapted_brain || !query_inputs || !query_labels || !stats) {
        set_error("NULL parameter in meta_evaluate_adaptation");
        return false;
    }

    if (num_query == 0) {
        set_error("Empty query set");
        return false;
    }

    // =========================================================================
    // COMPUTE: Loss before adaptation
    // =========================================================================

    float initial_loss = compute_loss(brain, query_inputs, query_labels, num_query);

    // =========================================================================
    // COMPUTE: Loss after adaptation
    // =========================================================================

    float final_loss = compute_loss(adapted_brain, query_inputs, query_labels, num_query);

    // =========================================================================
    // COMPUTE: Adaptation metrics
    // =========================================================================

    stats->initial_loss = initial_loss;
    stats->final_loss = final_loss;
    stats->steps_to_converge = meta->config.inner_steps;  // Simplified
    stats->adaptation_gain = (initial_loss > 0.0F) ?
                            (initial_loss - final_loss) / initial_loss : 0.0F;

    // =========================================================================
    // UPDATE: Meta-learner statistics
    // =========================================================================

    meta->total_adaptation_gain += stats->adaptation_gain;
    meta->total_adaptation_steps += stats->steps_to_converge;
    meta->num_adaptations++;

    NIMCP_LOGGING_DEBUG("Adaptation: initial_loss=%.4f, final_loss=%.4f, gain=%.2f%%",
                       initial_loss, final_loss, stats->adaptation_gain * 100.0F);

    return true;
}

//=============================================================================
// Public API: Task Similarity & Transfer Learning
//=============================================================================

/**
 * @brief Compute task similarity
 *
 * WHAT: Measure how similar two tasks are
 * WHY:  Decide whether to transfer learned features
 * HOW:  Cosine similarity of class prototypes
 *
 * ALGORITHM:
 * 1. For each class pair (i, j):
 *    similarity[i][j] = cos(prototype_a[i], prototype_b[j])
 * 2. Average over all pairs
 *
 * @param meta Meta-learner handle
 * @param task_a First task
 * @param task_b Second task
 * @return Similarity score [0.0 = different, 1.0 = identical]
 *
 * COMPLEXITY: O(num_classes * embedding_dim)
 */
float meta_compute_task_similarity(meta_learner_t meta,
                                   const meta_task_t* task_a,
                                   const meta_task_t* task_b)
{
    // =========================================================================
    // GUARD: Validate inputs
    // =========================================================================

    if (!meta || !task_a || !task_b) {
        return 0.0F;
    }

    if (!task_a->class_prototypes || !task_b->class_prototypes) {
        return 0.0F;
    }

    if (task_a->input_dim != task_b->input_dim) {
        return 0.0F;  // Incompatible tasks
    }

    // =========================================================================
    // COMPUTE: Average cosine similarity between class prototypes
    // =========================================================================

    uint32_t min_classes = (task_a->num_classes < task_b->num_classes) ?
                          task_a->num_classes : task_b->num_classes;

    float total_similarity = 0.0F;
    uint32_t num_pairs = 0;

    for (uint32_t i = 0; i < min_classes; i++) {
        const float* proto_a = &task_a->class_prototypes[i * task_a->input_dim];
        const float* proto_b = &task_b->class_prototypes[i * task_b->input_dim];

        float sim = nimcp_vector_cosine_similarity(proto_a, proto_b, task_a->input_dim);
        total_similarity += sim;
        num_pairs++;
    }

    return (num_pairs > 0) ? (total_similarity / num_pairs) : 0.0F;
}

/**
 * @brief Transfer knowledge between brains
 *
 * WHAT: Copy learned features from source to target
 * WHY:  Accelerate learning on similar tasks
 * HOW:  If tasks similar, copy early layer weights
 *
 * STRATEGY:
 * - Sensory layers (V1, A1): Copy if similarity > threshold
 * - Association layers (IT, STS): Partial copy
 * - Prefrontal (PFC): Keep random (task-specific)
 *
 * @param meta Meta-learner handle
 * @param source_brain Trained brain
 * @param target_brain Brain to initialize
 * @param similarity Task similarity (-1 to skip check)
 * @return true if transfer applied
 *
 * COMPLEXITY: O(network_size)
 */
bool meta_transfer_knowledge(meta_learner_t meta,
                             brain_t source_brain,
                             brain_t target_brain,
                             float similarity)
{
    // =========================================================================
    // GUARD: Validate inputs
    // =========================================================================

    if (!meta || !source_brain || !target_brain) {
        set_error("NULL parameter in meta_transfer_knowledge");
        return false;
    }

    // =========================================================================
    // CHECK: Task similarity threshold
    // =========================================================================

    if (similarity >= 0.0F && similarity < meta->config.similarity_threshold) {
        NIMCP_LOGGING_DEBUG("Transfer skipped: similarity %.2f < threshold %.2f",
                           similarity, meta->config.similarity_threshold);
        return false;
    }

    // =========================================================================
    // TRANSFER: Copy weights (implementation depends on brain API)
    // =========================================================================

    // TODO: Implement when brain weight copying API is available
    // For now, this is a placeholder

    NIMCP_LOGGING_DEBUG("Knowledge transfer: similarity=%.2f (would copy sensory/association layers)",
                       similarity);

    return true;
}

//=============================================================================
// Public API: Adaptive Learning Rates
//=============================================================================

/**
 * @brief Get learning rate for region
 *
 * COMPLEXITY: O(1)
 */
float meta_get_learning_rate(meta_learner_t meta, meta_region_type_t region)
{
    if (!meta || region >= META_REGION_COUNT) {
        return DEFAULT_INNER_LR;
    }

    return meta->learning_rates[region];
}

/**
 * @brief Adapt learning rate based on loss
 *
 * WHAT: Adjust LR using loss feedback
 * WHY:  Optimize per-region plasticity
 * HOW:  Bold driver heuristic (increase if improving, decrease if diverging)
 *
 * @param meta Meta-learner handle
 * @param region Brain region
 * @param loss Current loss
 * @return Updated learning rate
 *
 * COMPLEXITY: O(1)
 */
float meta_adapt_learning_rate(meta_learner_t meta,
                               meta_region_type_t region,
                               float loss)
{
    // =========================================================================
    // GUARD: Validate inputs
    // =========================================================================

    if (!meta || region >= META_REGION_COUNT) {
        return DEFAULT_INNER_LR;
    }

    if (!meta->config.enable_adaptive_lr) {
        return meta->learning_rates[region];
    }

    // =========================================================================
    // ADAPT: Learning rate based on loss trajectory
    // =========================================================================

    float current_lr = meta->learning_rates[region];
    float prev_loss = meta->previous_loss[region];

    if (!isinf(prev_loss)) {  // Have history
        if (loss < prev_loss) {
            // Loss improved → increase LR (bold driver)
            current_lr *= LR_INCREASE_FACTOR;
        } else {
            // Loss worsened → decrease LR (backtrack)
            current_lr *= LR_DECREASE_FACTOR;
        }

        // Clamp to bounds
        if (current_lr < LR_MIN) current_lr = LR_MIN;
        if (current_lr > LR_MAX) current_lr = LR_MAX;

        meta->learning_rates[region] = current_lr;
    }

    // Update history
    meta->previous_loss[region] = loss;

    return current_lr;
}

//=============================================================================
// Public API: Task Management
//=============================================================================

/**
 * @brief Create task representation
 *
 * COMPLEXITY: O(num_classes * input_dim)
 */
meta_task_t* meta_task_create(const char* name, uint32_t num_classes, uint32_t input_dim)
{
    if (!name || num_classes == 0 || input_dim == 0) {
        set_error("Invalid task parameters");
        return NULL;
    }

    meta_task_t* task = nimcp_calloc(1, sizeof(meta_task_t));
    if (!task) {
        set_error("Failed to allocate meta_task_t");
        return NULL;
    }

    strncpy(task->name, name, sizeof(task->name) - 1);
    task->num_classes = num_classes;
    task->input_dim = input_dim;

    // Allocate prototype embeddings
    task->class_prototypes = nimcp_calloc(num_classes * input_dim, sizeof(float));
    if (!task->class_prototypes) {
        set_error("Failed to allocate class prototypes");
        nimcp_free(task);
        return NULL;
    }

    task->average_loss = 0.0F;
    task->samples_seen = 0;

    return task;
}

/**
 * @brief Destroy task
 *
 * COMPLEXITY: O(1)
 */
void meta_task_destroy(meta_task_t* task)
{
    if (!task) {
        return;
    }

    if (task->class_prototypes) {
        nimcp_free(task->class_prototypes);
    }

    nimcp_free(task);
}

/**
 * @brief Update task prototypes
 *
 * WHAT: Incrementally update class centroids
 * WHY:  Refine task representation
 * HOW:  Running average of embeddings
 *
 * COMPLEXITY: O(num_examples * input_dim)
 */
bool meta_task_update_prototypes(meta_task_t* task,
                                 const float** inputs,
                                 const uint32_t* labels,
                                 uint32_t num_examples)
{
    if (!task || !inputs || !labels || num_examples == 0) {
        return false;
    }

    // Update class prototypes using running average
    for (uint32_t i = 0; i < num_examples; i++) {
        uint32_t label = labels[i];
        if (label >= task->num_classes) {
            continue;  // Invalid label
        }

        float* prototype = &task->class_prototypes[label * task->input_dim];
        const float* input = inputs[i];

        // Running average: proto = (proto * n + input) / (n + 1)
        for (uint32_t d = 0; d < task->input_dim; d++) {
            prototype[d] = (prototype[d] * task->samples_seen + input[d]) /
                          (task->samples_seen + 1);
        }
    }

    task->samples_seen += num_examples;
    return true;
}

//=============================================================================
// Public API: Statistics & Debugging
//=============================================================================

/**
 * @brief Get meta-learning statistics
 *
 * COMPLEXITY: O(1)
 */
bool meta_get_statistics(meta_learner_t meta,
                        uint32_t* num_tasks_seen,
                        float* avg_adaptation_gain,
                        float* avg_steps_to_converge)
{
    if (!meta) {
        return false;
    }

    if (num_tasks_seen) {
        *num_tasks_seen = meta->num_tasks_seen;
    }

    if (avg_adaptation_gain) {
        *avg_adaptation_gain = (meta->num_adaptations > 0) ?
                              (meta->total_adaptation_gain / meta->num_adaptations) : 0.0F;
    }

    if (avg_steps_to_converge) {
        *avg_steps_to_converge = (meta->num_adaptations > 0) ?
                                ((float)meta->total_adaptation_steps / meta->num_adaptations) : 0.0F;
    }

    return true;
}

/**
 * @brief Print meta-learning state
 *
 * COMPLEXITY: O(num_regions + num_tasks)
 */
void meta_print_state(meta_learner_t meta)
{
    if (!meta) {
        printf("NULL meta-learner\n");
        return;
    }

    printf("=== META-LEARNER STATE ===\n");
    printf("Algorithm: %s\n",
           meta->config.algorithm == META_ALGORITHM_MAML ? "MAML" :
           meta->config.algorithm == META_ALGORITHM_REPTILE ? "Reptile" : "FOMAML");
    printf("Few-shot K: %d\n", meta->config.few_shot_k);
    printf("Inner LR: %.5f, Outer LR: %.5f\n",
           meta->config.inner_learning_rate, meta->config.outer_learning_rate);
    printf("Tasks seen: %u\n", meta->num_tasks_seen);
    printf("Adaptations: %u\n", meta->num_adaptations);

    if (meta->num_adaptations > 0) {
        printf("Avg adaptation gain: %.2f%%\n",
               (meta->total_adaptation_gain / meta->num_adaptations) * 100.0F);
        printf("Avg steps to converge: %.1f\n",
               (float)meta->total_adaptation_steps / meta->num_adaptations);
    }

    printf("Learning rates:\n");
    printf("  Sensory: %.5f\n", meta->learning_rates[META_REGION_SENSORY]);
    printf("  Association: %.5f\n", meta->learning_rates[META_REGION_ASSOCIATION]);
    printf("  Prefrontal: %.5f\n", meta->learning_rates[META_REGION_PREFRONTAL]);
    printf("=========================\n");
}

//=============================================================================
// Internal Helper Functions
//=============================================================================

/**
 * @brief Compute loss on dataset
 *
 * WHAT: Evaluate cross-entropy loss
 * WHY:  Measure prediction quality
 * HOW:  Forward pass + loss calculation
 *
 * NOTE: Simplified placeholder - will use brain_decide() when integrated
 *
 * COMPLEXITY: O(num_samples * network_forward)
 */
static float compute_loss(brain_t brain, const float** inputs,
                         const uint32_t* labels, uint32_t num_samples)
{
    if (!brain || !inputs || !labels || num_samples == 0) {
        return INFINITY;
    }

    // Allocate decisions array for batch inference
    brain_decision_t* decisions = (brain_decision_t*)nimcp_calloc(
        num_samples, sizeof(brain_decision_t));
    if (!decisions) {
        return INFINITY;
    }

    // Run batch inference
    // Note: Assuming input dimension is 256 (standard brain input size)
    // In a production system, this would be queried from the brain config
    uint32_t features_per_input = 256;
    bool success = brain_decide_batch(brain, inputs, num_samples,
                                     features_per_input, decisions);
    if (!success) {
        nimcp_free(decisions);
        return INFINITY;
    }

    // Compute cross-entropy loss
    float total_loss = 0.0F;
    for (uint32_t i = 0; i < num_samples; i++) {
        // NOTE: Could track accuracy here by finding argmax(output_vector)
        // but we only need loss for MAML gradient computation

        // Cross-entropy loss: -log(p_correct)
        // Get probability of correct class
        uint32_t true_label = labels[i];
        if (true_label < decisions[i].output_size) {
            float p_correct = decisions[i].output_vector[true_label];
            // Clip to avoid log(0)
            p_correct = (p_correct < 1e-7F) ? 1e-7F : p_correct;
            total_loss += -logf(p_correct);
        } else {
            // Invalid label
            total_loss += 100.0F;  // Large penalty
        }

        // Free decision output vector
        if (decisions[i].output_vector) {
            nimcp_free(decisions[i].output_vector);
        }
        if (decisions[i].active_neuron_ids) {
            nimcp_free(decisions[i].active_neuron_ids);
        }
    }

    nimcp_free(decisions);
    return total_loss / num_samples;  // Average loss
}

/**
 * @brief Clone brain parameters
 *
 * WHAT: Create independent copy of brain
 * WHY:  Allow inner loop modifications without affecting original
 * HOW:  Use brain_clone() API
 *
 * COMPLEXITY: O(network_size)
 */
static brain_t clone_brain_parameters(brain_t source)
{
    if (!source) {
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "source is NULL");

        return NULL;
    }

    // Use brain's COW clone function for efficient parameter copying
    brain_t clone = brain_clone_cow(source);
    return clone;
}

/**
 * @brief Apply one gradient step
 *
 * WHAT: Update parameters using gradient descent
 * WHY:  Inner loop optimization
 * HOW:  θ ← θ - α * ∇_θ L
 *
 * NOTE: Placeholder - will integrate with training API
 *
 * COMPLEXITY: O(network_forward_backward)
 */
static bool apply_gradient_step(brain_t brain, const float** inputs,
                               const uint32_t* labels, uint32_t num_samples,
                               float learning_rate)
{
    // NOTE: learning_rate parameter currently unused - brain_learn_batch uses
    // brain's internal learning rate configuration from brain_config_t
    (void)learning_rate;

    if (!brain || !inputs || !labels || num_samples == 0) {
        return false;
    }

    // Build training examples
    brain_example_t* examples = (brain_example_t*)nimcp_calloc(
        num_samples, sizeof(brain_example_t));
    if (!examples) {
        return false;
    }

    // Convert inputs and labels to brain_example_t format
    for (uint32_t i = 0; i < num_samples; i++) {
        examples[i].features = (float*)inputs[i];  // Direct pointer (not owned)
        examples[i].num_features = 256;  // Standard input size

        // Convert label to string
        snprintf(examples[i].label, sizeof(examples[i].label), "%u", labels[i]);

        // Set confidence to 1.0 for supervised learning
        examples[i].confidence = 1.0F;
    }

    // Apply one gradient step using brain_learn_batch
    // Note: brain_learn_batch internally applies learning rate
    // We'd need to temporarily modify brain's learning rate
    // For now, we use the brain's configured learning rate
    float loss = brain_learn_batch(brain, examples, num_samples);

    nimcp_free(examples);

    // Return success if loss is finite
    return (loss < INFINITY);
}

/**
 * @brief Add task to history
 *
 * WHAT: Store task for similarity computation
 * WHY:  Enable transfer learning
 * HOW:  Circular buffer of recent tasks
 *
 * COMPLEXITY: O(1)
 */
static bool add_task_to_history(meta_learner_t meta, const meta_task_t* task)
{
    if (!meta || !task) {
        return false;
    }

    // If history full, remove oldest task
    if (meta->num_tasks_seen >= meta->task_history_capacity) {
        meta_task_destroy(meta->task_history[0]);
        // Shift array (simple implementation)
        for (uint32_t i = 1; i < meta->task_history_capacity; i++) {
            meta->task_history[i-1] = meta->task_history[i];
        }
        meta->num_tasks_seen--;
    }

    // Add new task (deep copy)
    meta_task_t* task_copy = meta_task_create(task->name, task->num_classes, task->input_dim);
    if (!task_copy) {
        return false;
    }

    memcpy(task_copy->class_prototypes, task->class_prototypes,
           task->num_classes * task->input_dim * sizeof(float));
    task_copy->average_loss = task->average_loss;
    task_copy->samples_seen = task->samples_seen;

    meta->task_history[meta->num_tasks_seen] = task_copy;
    meta->num_tasks_seen++;

    return true;
}

/* ============================================================================
 * Knowledge Graph Self-Awareness Integration
 * ============================================================================ */

int meta_learning_query_self_knowledge(kg_reader_t* kg) {
    if (!kg) return 0;

    const kg_entity_t* self = kg_reader_get_entity(kg, "Meta_Learning");
    if (self) {
        for (uint32_t i = 0; i < self->num_observations; i++) {
            (void)self->observations[i];
        }
    }

    kg_relation_list_t* connections = kg_reader_get_relations_from(kg, "Meta_Learning");
    if (connections) {
        kg_relation_list_destroy(connections);
    }

    kg_relation_list_t* incoming = kg_reader_get_relations_to(kg, "Meta_Learning");
    if (incoming) {
        kg_relation_list_destroy(incoming);
    }

    return self ? 1 : 0;
}
