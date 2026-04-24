// nimcp_brain_part_core.c - core functions
// Part of nimcp_brain.c (SRP #include-based split)
// DO NOT compile separately - #included from nimcp_brain.c

/* Forward declarations for C6 inference-time training */
struct creative_training_bridge;
typedef struct creative_training_bridge creative_training_bridge_t;
extern int creative_training_submit_feedback(creative_training_bridge_t* bridge,
                                              const void* content,
                                              int modality,
                                              uint8_t rating,
                                              const char* feedback);

/* Cognitive stage constants */
static const float DIALOGUE_AGREEMENT_HIGH   = 0.8F;   /* Above this: perspectives agree → boost */
static const float DIALOGUE_AGREEMENT_LOW    = 0.4F;   /* Below this: perspectives disagree → reduce */
static const float DIALOGUE_BOOST_FACTOR     = 1.1F;   /* Confidence multiplier on high agreement */
static const float DIALOGUE_REDUCE_FACTOR    = 0.8F;   /* Confidence multiplier on low agreement */
static const float IMAGINATION_FAIL_PENALTY  = 0.95F;  /* Confidence multiplier when simulation fails */
static const float RCOG_CONFIDENCE_FLOOR     = 0.1F;   /* Min confidence to invoke recursive cognition */
static const int   IMAGINATION_SIM_STEPS     = 3;      /* Number of prospective simulation steps */

/* W5 KG-integration — main ANN network-level aggregator event emitter.
 * Uses a 4-sample rolling buffer of output vectors; if consecutive outputs
 * are nearly identical (cosine similarity > 0.98) with non-zero norm, emit
 * "mode_collapse". Admin-token elevation per kg-node-naming-registry.md §7.
 *
 * NOTE: brain_part_core.c is #included from nimcp_brain.c — brain_kg.h
 * include must live here because brain.c does not transitively expose it. */
#include "core/brain/nimcp_brain_kg.h"
#include "security/nimcp_w11_safety_kg_events.h"  /* W11: LGSS KG emission */
#include "cognitive/kg/nimcp_wave13_metacog_kg.h"  /* W13: analogy + multiscale events */

static brain_t s_net_main_ann_kg_brain = NULL;

/* Rolling 1-sample history + similarity detector. Mean is captured as a
 * scalar "direction" summary (small footprint, cheap similarity proxy). */
#define NET_MAIN_ANN_DIVERSITY_WIN 4
static float  s_main_ann_prev_means[NET_MAIN_ANN_DIVERSITY_WIN];
static int    s_main_ann_prev_count = 0;

void net_main_ann_kg_register_brain(brain_t brain) {
    s_net_main_ann_kg_brain = brain;
    s_main_ann_prev_count = 0;
    for (int i = 0; i < NET_MAIN_ANN_DIVERSITY_WIN; i++) {
        s_main_ann_prev_means[i] = 0.0f;
    }
}

static void net_main_ann_kg_emit_event(brain_t brain, const char* kind,
                                       float magnitude, uint64_t ts_us) {
    if (!brain || !kind) return;
    if (!brain->internal_kg_enabled || !brain->internal_kg) return;

    brain_kg_t* kg = brain->internal_kg;
    brain_kg_set_access_level(kg, BRAIN_KG_ACCESS_ADMIN,
                              brain->internal_kg_admin_token);

    char ev_name[160];
    snprintf(ev_name, sizeof(ev_name),
             "net_main_ann_event_%s_%llu", kind, (unsigned long long)ts_us);
    char desc[240];
    snprintf(desc, sizeof(desc),
             "Main ANN network event: kind=%s magnitude=%.4f", kind, magnitude);

    brain_kg_node_id_t ev = brain_kg_add_node(kg, ev_name,
        BRAIN_KG_NODE_CORE, desc);
    brain_kg_node_id_t owner = brain_kg_find_node(kg, "net_main_ann");
    if (owner != BRAIN_KG_INVALID_NODE && ev != BRAIN_KG_INVALID_NODE) {
        brain_kg_add_edge(kg, owner, ev, BRAIN_KG_EDGE_SENDS_TO,
            "produced_by", magnitude);
    }
    if (ev != BRAIN_KG_INVALID_NODE) {
        char buf[40];
        snprintf(buf, sizeof(buf), "%.6f", magnitude);
        brain_kg_add_metadata(kg, ev, "magnitude", buf);
        snprintf(buf, sizeof(buf), "%llu", (unsigned long long)ts_us);
        brain_kg_add_metadata(kg, ev, "ts_us", buf);
    }

    brain_kg_set_access_level(kg, BRAIN_KG_ACCESS_READ, 0);
}

/* Public test-facing trigger — forwards to static emit. */
void net_main_ann_kg_trigger_event(brain_t brain, const char* kind,
                                   float magnitude, uint64_t ts_us) {
    net_main_ann_kg_emit_event(brain, kind, magnitude, ts_us);
}

/* W16: Apply KG consumers to a just-produced decision.
 * Consumer A — salience bias via insula outgoing edges (up to +0.05).
 * Consumer B — prior-decision recurrence (+0.02 if history node exists,
 *              else create it so future calls find it).
 * Bumps brain->kg_consumer_hits for every hit. Null-safe. */
static void w16_apply_kg_consumers(brain_t brain, brain_decision_t* decision)
{
    if (!brain || !decision) return;
    if (!brain->internal_kg_enabled || !brain->internal_kg) return;

    /* Consumer A — KG salience bias */
    brain_kg_node_id_t salience_root = brain_kg_find_node(
        brain->internal_kg, "insula");
    if (salience_root != BRAIN_KG_INVALID_NODE) {
        brain_kg_edge_list_t* edges = brain_kg_get_outgoing(
            brain->internal_kg, salience_root);
        if (edges && edges->count > 0) {
            float boost = (float)edges->count * 0.001f;
            if (boost > 0.05f) boost = 0.05f;
            decision->confidence += boost;
            if (decision->confidence > 1.0f) decision->confidence = 1.0f;
            __atomic_add_fetch(&brain->kg_consumer_hits, 1,
                               __ATOMIC_RELAXED);
        }
        if (edges) brain_kg_edge_list_destroy(edges);
    }

    /* Consumer B — prior-decision recurrence */
    if (decision->output_vector && decision->output_size > 0) {
        uint32_t argmax = 0;
        float mx = 0.0f;
        for (uint32_t i = 0; i < decision->output_size; i++) {
            float a = decision->output_vector[i];
            if (a < 0.0f) a = -a;
            if (a > mx) { mx = a; argmax = i; }
        }
        char node_name[64];
        snprintf(node_name, sizeof(node_name),
                 "decision_history_%u", argmax);
        brain_kg_node_id_t existing = brain_kg_find_node(
            brain->internal_kg, node_name);
        if (existing != BRAIN_KG_INVALID_NODE) {
            decision->confidence += 0.02f;
            if (decision->confidence > 1.0f) decision->confidence = 1.0f;
            __atomic_add_fetch(&brain->kg_consumer_hits, 1,
                               __ATOMIC_RELAXED);
        } else {
            brain_kg_set_access_level(brain->internal_kg,
                BRAIN_KG_ACCESS_ADMIN, brain->internal_kg_admin_token);
            brain_kg_add_node(brain->internal_kg, node_name,
                BRAIN_KG_NODE_COGNITIVE, "decision history marker");
            brain_kg_set_access_level(brain->internal_kg,
                BRAIN_KG_ACCESS_READ, 0);
        }
    }
}


/**
 * @brief Clear decision cache (thread-safe with deadlock protection)
 *
 * WHAT: Invalidates cached input and decision
 * WHY:  Cache must be cleared after network modifications
 * HOW:  Timeout-protected mutex acquisition with emergency recovery
 *
 * BIOLOGICAL RATIONALE:
 * Thread-safe cache invalidation mimics synaptic reorganization that
 * invalidates previously stable neural response patterns. When synaptic
 * weights change (learning/pruning), cached neural activations become
 * obsolete, requiring recomputation from modified connectivity.
 *
 * CONCURRENCY: Uses timeout-based mutex locking to prevent deadlocks.
 * If mutex cannot be acquired within MUTEX_TIMEOUT_US, cache is left
 * in potentially stale state (safe, just suboptimal performance).
 *
 * COMPLEXITY: O(1)
 *
 * @param brain Brain handle
 */
void clear_cache(brain_t brain)
{
    // Guard: Validate parameters
    if (!brain) {
        return;
    }

    // Lock cache mutex with retry + backoff to prevent deadlock.
    // Stale cache is safe (just slower), corrupted cache is not,
    // so we never proceed without the lock.
    int lock_acquired = -1;
    for (int attempt = 0; attempt < 3; attempt++) {
        uint64_t timeout = MUTEX_TIMEOUT_US << attempt;  // exponential backoff
        lock_acquired = mutex_lock_with_timeout(&brain->cache_mutex, timeout);
        if (lock_acquired == 0) break;
    }
    if (lock_acquired != 0) {
        set_error("Timeout waiting for cache mutex in clear_cache after 3 retries - cache not cleared");
        return;
    }

    // Free cached input vector
    nimcp_free(brain->last_input);
    brain->last_input = NULL;

    // Free cached decision
    if (brain->cached_decision) {
        brain_free_decision(brain->cached_decision);
        brain->cached_decision = NULL;
    }

    // Always attempt unlock, even if operations above failed
    int unlock_result = nimcp_platform_mutex_unlock(&brain->cache_mutex);
    if (unlock_result != 0) {
        // CRITICAL: Mutex unlock failed - attempt emergency recovery
        LOG_MODULE_ERROR("BRAIN", "CRITICAL: Normal unlock failed in clear_cache - attempting recovery");
        force_unlock_with_logging(&brain->cache_mutex, "clear_cache");
    }
}


/**
 * @brief Allocate and initialize brain structure
 *
 * WHY: Separates allocation from configuration
 * Makes memory management explicit
 *
 * COMPLEXITY: O(1)
 *
 * @return Allocated brain or NULL on error
 */
brain_t allocate_brain(void)
{
    brain_t brain = nimcp_calloc(1, sizeof(struct brain_struct));
    if (!brain) {
        set_error("Failed to allocate brain structure");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "allocate_brain: brain is NULL");
        return NULL;
    }

    brain->last_input = NULL;
    brain->cached_decision = NULL;
    brain->input_size = 0;

    // Initialize cache mutex for thread-safe access
    if (nimcp_platform_mutex_init(&brain->cache_mutex, false) != 0) {
        set_error("Failed to initialize cache mutex");
        nimcp_free(brain);
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NOT_INITIALIZED, "allocate_brain: validation failed");
        return NULL;
    }

    brain->distributed = NULL;  // Initialize as standalone brain

    // Phase 11: Initialize long-term memory consolidation buffer
    brain->longterm_capacity = 100;  // Store up to 100 consolidated memories
    brain->longterm_count = 0;
    brain->longterm_memory = nimcp_calloc(brain->longterm_capacity,
                                          sizeof(*brain->longterm_memory));
    // Guard: If allocation fails, set capacity to 0 (consolidation will be disabled)
    if (!brain->longterm_memory) {
        brain->longterm_capacity = 0;
    }

    // Initialize COW fields
    brain->is_cow_clone = false;
    brain->owns_network = true;  // By default, brain owns its network
    brain->original_network = NULL;
    brain->network_is_cached = false;

    // Phase 3: Initialize reference counting fields (atomic operations)
    brain->network_refcount_atomic = NULL;
    brain->can_use_readonly = false;

    // Community Detection: Initialize fields
    brain->functional_modules = NULL;
    brain->network_hubs = NULL;
    brain->topology_metrics = NULL;
    brain->auto_detect_communities = false;
    brain->community_detection_interval = 0.0F;  // Manual only by default

    return brain;
}


/**
 * @brief Create adaptive network for brain
 *
 * WHY: Isolates network creation complexity
 * Handles network config lifecycle
 *
 * COMPLEXITY: O(n) where n = num_neurons
 *
 * @param num_inputs Input dimension
 * @param num_outputs Output dimension
 * @param num_neurons Neuron count
 * @param sparsity_target Target sparsity
 * @return Network handle or NULL on error
 */
adaptive_network_t create_brain_network(uint32_t num_inputs, uint32_t num_outputs,
                                               uint32_t num_neurons, float sparsity_target,
                                               ode_integration_method_t integration_method)
{

    adaptive_network_config_t net_config =
        build_network_config(num_inputs, num_outputs, num_neurons, sparsity_target, integration_method);

    // Guard: Check if layer_sizes allocation failed in build_base_network_config
    // WHY: NULL layer_sizes will cause crash in adaptive_network_create
    if (!net_config.base_config.layer_sizes) {
        // Error already set by build_base_network_config
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "create_brain_network: net_config is NULL");
        return NULL;
    }

    adaptive_network_t network = adaptive_network_create(&net_config);

    // Free our copy of layer_sizes - adaptive_network_create makes its own deep copy (or fails)
    // WHY: Avoid memory leak - we allocated this in build_base_network_config
    // WHAT: Safe to free even if network creation failed, because we still own this allocation
    // Note: layer_sizes pointer should not be modified by adaptive_network_create (const param)
    if (net_config.base_config.layer_sizes) {
        nimcp_free((void*)net_config.base_config.layer_sizes);
    }

    return network;
}


/**
 * @brief Initialize output labels array
 *
 * COMPLEXITY: O(1)
 *
 * @param brain Brain to initialize
 * @param num_outputs Number of output labels
 * @return true on success
 */
bool init_output_labels(brain_t brain, uint32_t num_outputs)
{
    if (!brain) {
        set_error("NULL brain pointer in init_output_labels");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_output_labels: brain is NULL");
        return false;
    }
    if (num_outputs == 0) {
        // Zero outputs - no allocation needed, but set to NULL
        brain->output_labels = NULL;
        brain->num_output_labels = 0;
        return true;
    }
    brain->output_labels = nimcp_calloc(num_outputs, sizeof(char*));
    if (!brain->output_labels) {
        set_error("Failed to allocate output labels");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "init_output_labels: brain->output_labels is NULL");
        return false;
    }
    brain->num_output_labels = 0;
    return true;
}


/**
 * @brief Initialize multi-modal subsystems (Phase 8)
 *
 * WHAT: Create visual cortex, audio cortex, and integration layer
 * WHY:  Enable unified multi-modal processing
 * HOW:  Check config flags, create modules, allocate feature buffers
 *
 * DESIGN:
 * - Only creates modules if config flags are enabled
 * - Allocates reusable feature buffers (no per-frame allocation)
 * - Gracefully handles partial initialization
 *
 * @param brain Brain structure with configuration set
 * @return true on success, false on failure
 *
 * COMPLEXITY: O(1) - just allocation
 * MEMORY: O(D_v + D_a + D_integrated) for feature buffers
 *
 * ERROR HANDLING:
 * - Returns true if multi-modal disabled (not an error)
 * - Returns false only on allocation failure
 * - Partial cleanup handled by brain_destroy()
 *
 * @version 2.7.0 Phase 8.1
 * @author NIMCP Development Team
 * @date 2025-11-08
 */


/**
 * WHAT: Initialize multihead attention mechanism
 * WHY:  Enable selective focus on relevant features for efficient processing
 * HOW:  Create attention system based on cortical column architecture
 *
 * BIOLOGICAL MOTIVATION:
 * - Cortical Columns: Each attention head acts as specialized processing column
 * - Thalamic Gating: Controls information flow (like thalamic relay nucleus)
 * - Salience Weighting: Biologically-inspired attention based on feature importance
 * - Parallel Streams: Multiple heads process different aspects simultaneously
 *
 * INTEGRATION WITH BRAIN:
 * - Applied to multimodal inputs (visual, audio, speech) before neural network
 * - Connects to salience evaluator for attention weighting
 * - Interfaces with executive control for top-down attention modulation
 * - Used in working memory for attention-based retrieval
 *
 * PERFORMANCE BENEFITS:
 * - 2-5x inference speedup by selective processing
 * - 30-50% memory reduction through focused activations
 * - 5-15% accuracy improvement on complex tasks
 *
 * @param brain Brain instance to initialize
 * @return true on success, false on failure
 *
 * @version 3.0.0 Module Integration Phase
 * @author NIMCP Development Team
 * @date 2025-11-11
 */
bool init_attention_subsystem(brain_t brain)
{
    // WHAT: Guard clause - validate input
    // WHY:  Prevent null pointer dereference
    // HOW:  Check brain pointer before use
    if (!brain) {
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_attention_subsystem: brain is NULL");
        return false;
    }

    // Bio-Async: Initialize on first subsystem init (uses platform_once internally)
    nimcp_error_t bio_result = brain_bio_init();
    if (bio_result != NIMCP_SUCCESS) {
        LOG_MODULE_WARN("BRAIN", "Bio-async init failed: %d (continuing anyway)", bio_result);
    }

    // WHAT: Check if already initialized
    // WHY:  Prevent double initialization and memory leak
    // HOW:  Return success if attention already exists
    if (brain->multihead_attention) {
        return true;  // Already initialized
    }

    // WHAT: Check if attention is enabled in configuration
    // WHY:  Only initialize if user requested this feature
    // HOW:  Check config flag, return success (not error) if disabled
    if (!brain->config.enable_multihead_attention) {
        return true;  // Not enabled, not an error
    }

    // WHAT: Calculate appropriate dimensions for attention
    // WHY:  Attention dimensions must match integrated_feature_buffer size
    // HOW:  Always use num_inputs (the output size of multimodal integration)
    //
    // NOTE: The multimodal integration layer compresses all modalities
    //       (visual + audio + speech + direct) into a unified representation
    //       of size num_inputs. The attention system processes this integrated
    //       representation, not the raw concatenated features.
    uint32_t input_dim = brain->config.num_inputs;

    // WHAT: Configure multihead attention system
    // WHY:  Need proper configuration for cortical column architecture
    // HOW:  Create config with biological parameters
    multihead_attention_config_t attention_config = {
        .num_heads = brain->config.num_attention_heads > 0 ?
                     brain->config.num_attention_heads : 8,  // Default: 8 heads
        .input_dim = input_dim,
        .output_dim = input_dim,  // Same dimension (residual connection compatible)
        .sequence_length = 32,    // Default sequence length for temporal processing
        .use_thalamic_gate = brain->config.enable_thalamic_gate,
        .use_salience_weighting = brain->config.enable_salience_weighting,
        .gate_bias = 0.5F        // Default: 50% gate opening
    };

    // WHAT: Create multihead attention system
    // WHY:  Enable selective feature processing with parallel attention streams
    // HOW:  Call attention creation API with configured parameters
    brain->multihead_attention = multihead_attention_create(&attention_config);
    if (!brain->multihead_attention) {
        set_error("Failed to create multihead attention system");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_attention_subsystem: brain->multihead_attention is NULL");
        return false;
    }

    return true;
}


/**
 * WHAT: Initialize brain regions hierarchical architecture
 * WHY:  Enable modular cortical organization with layers and minicolumns
 * HOW:  Create brain module with specialized regions if config enables it
 *
 * BIOLOGICAL MOTIVATION:
 * - Cerebral cortex organized into hierarchical regions (V1, A1, M1, PFC, etc.)
 * - Each region has 6 cortical layers with distinct functions
 * - Minicolumns span layers vertically for parallel processing
 * - Inter-region connections follow biological pathways (feedforward/feedback)
 *
 * INTEGRATION WITH BRAIN:
 * - Provides spatial organization of processing
 * - Enables specialized regions for sensory, motor, associative functions
 * - Supports realistic cortical layer dynamics (Layer 4 input, Layer 5 output)
 * - Allows for hierarchical processing pathways
 *
 * @param brain Brain instance to initialize
 * @return true on success, false on failure
 *
 * @version 3.0.0 Module Integration Phase
 * @author NIMCP Development Team
 * @date 2025-11-11
 */
bool init_brain_regions_subsystem(brain_t brain)
{
    // WHAT: Guard clause - validate input
    // WHY:  Prevent null pointer dereference
    // HOW:  Check brain pointer before use
    if (!brain) {
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_brain_regions_subsystem: brain is NULL");
        return false;
    }

    // WHAT: Check if already initialized
    // WHY:  Prevent double initialization and memory leak
    // HOW:  Return success if brain_regions already exists
    if (brain->brain_regions) {
        return true;  // Already initialized
    }

    // WHAT: Check if brain regions architecture is enabled in configuration
    // WHY:  Only initialize if user requested this feature
    // HOW:  Check config flag, return success (not error) if disabled
    if (!brain->config.enable_brain_regions) {
        return true;  // Not enabled, not an error
    }

    // WHAT: Determine number of regions and neurons per region
    // WHY:  Need proper sizing for modular architecture
    // HOW:  Use config values with sensible defaults
    uint32_t num_regions = brain->config.num_brain_regions > 0 ?
                           brain->config.num_brain_regions : 4;  // Default: 4 regions
    uint32_t neurons_per_region = brain->config.neurons_per_region > 0 ?
                                  brain->config.neurons_per_region : 1000;  // Default: 1000 neurons

    // WHAT: Create brain module with max capacity
    // WHY:  Top-level container for all brain regions
    // HOW:  Allocate module with specified max regions
    brain->brain_regions = brain_module_create(num_regions);
    if (!brain->brain_regions) {
        set_error("Failed to create brain regions module");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "init_brain_regions_subsystem: brain->brain_regions is NULL");
        return false;
    }

    // WHAT: Create individual brain regions with specialized types
    // WHY:  Different regions have different layer proportions and neuron types
    // HOW:  Create regions based on configuration, starting with primary sensory/motor areas
    brain_region_type_t region_types[] = {
        REGION_VISUAL_V1,      // Primary visual cortex
        REGION_AUDITORY_A1,    // Primary auditory cortex
        REGION_MOTOR_M1,       // Primary motor cortex
        REGION_PREFRONTAL      // Prefrontal cortex (executive control)
    };

    for (uint32_t i = 0; i < num_regions && i < 4; i++) {
        brain_region_t* region = brain_region_create(region_types[i], neurons_per_region);
        if (!region) {
            set_error("Failed to create brain region");
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_brain_regions_subsystem: region is NULL");
            return false;
        }

        // Organize region into minicolumns (8x8 grid for moderate-sized regions)
        uint32_t columns_x = 8;
        uint32_t columns_y = 8;
        if (brain_region_organize_columns(region, columns_x, columns_y) != NIMCP_SUCCESS) {
            brain_region_destroy(region);
            set_error("Failed to organize brain region into minicolumns");
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "init_brain_regions_subsystem: validation failed");
            return false;
        }

        // Add region to brain module
        if (brain_module_add_region(brain->brain_regions, region) != NIMCP_SUCCESS) {
            brain_region_destroy(region);
            set_error("Failed to add region to brain module");
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "init_brain_regions_subsystem: validation failed");
            return false;
        }
    }

    // WHAT: Establish inter-region connections
    // WHY:  Brain regions need to communicate (e.g., V1 → PFC for visual attention)
    // HOW:  Connect regions with biologically realistic pathways
    if (num_regions >= 2) {
        // Connect V1 (visual) → PFC (prefrontal) for visual processing pathway
        brain_region_t* v1 = brain_module_get_region_by_type(brain->brain_regions, REGION_VISUAL_V1);
        brain_region_t* pfc = brain_module_get_region_by_type(brain->brain_regions, REGION_PREFRONTAL);
        if (v1 && pfc) {
            nimcp_result_t result = brain_module_connect_regions(brain->brain_regions, v1->id, pfc->id, 0.3F);
            if (result != NIMCP_SUCCESS) {
                LOG_MODULE_WARN("BRAIN", "Failed to connect V1→PFC regions (error=%d), visual processing pathway unavailable", result);
            }
        } else {
            LOG_MODULE_WARN("BRAIN", "Cannot establish V1→PFC connection: V1=%p, PFC=%p", (void*)v1, (void*)pfc);
        }
    }

    if (num_regions >= 3) {
        // Connect A1 (auditory) → PFC for auditory processing pathway
        brain_region_t* a1 = brain_module_get_region_by_type(brain->brain_regions, REGION_AUDITORY_A1);
        brain_region_t* pfc = brain_module_get_region_by_type(brain->brain_regions, REGION_PREFRONTAL);
        if (a1 && pfc) {
            nimcp_result_t result = brain_module_connect_regions(brain->brain_regions, a1->id, pfc->id, 0.3F);
            if (result != NIMCP_SUCCESS) {
                LOG_MODULE_WARN("BRAIN", "Failed to connect A1→PFC regions (error=%d), auditory processing pathway unavailable", result);
            }
        } else {
            LOG_MODULE_WARN("BRAIN", "Cannot establish A1→PFC connection: A1=%p, PFC=%p", (void*)a1, (void*)pfc);
        }
    }

    return true;
}


/**
 * WHAT: Initialize symbolic logic reasoning subsystem
 * WHY:  Enable logical inference, knowledge representation, and abstract reasoning
 * HOW:  Create symbolic logic engine if config enables it
 *
 * BIOLOGICAL MOTIVATION:
 * - Prefrontal cortex performs abstract logical reasoning
 * - Hippocampus stores declarative knowledge (facts)
 * - Working memory maintains active inferences
 *
 * INTEGRATION WITH BRAIN:
 * - Stores facts learned during experience
 * - Performs deductive/inductive reasoning
 * - Validates decisions against logical constraints
 * - Enables explanation generation ("because X implies Y")
 *
 * @param brain Brain instance to initialize
 * @return true on success, false on failure
 *
 * @version 2.7.0 Phase 8.9
 * @author NIMCP Development Team
 * @date 2025-11-08
 */
bool init_symbolic_logic_subsystem(brain_t brain)
{
    if (!brain) {
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_symbolic_logic_subsystem: brain is NULL");
        return false;
    }

    // Check if already initialized
    if (brain->logic) {
        return true;  // Already initialized
    }

    // Check if symbolic logic is enabled via knowledge system or explicit flag
    // The knowledge system uses logic internally, so enable if knowledge is enabled
    if (!brain->config.enable_knowledge) {
        return true;  // Not enabled, not an error
    }

    // Create neural logic network with spiking logic gates (Phase 9.0)
    neural_logic_config_t logic_config = neural_logic_default_config(1000);
    logic_config.use_gpu = neural_logic_gpu_available();
    logic_config.integration_window_ms = 5.0F;
    logic_config.enable_learning = false;  // Combinational logic (no plasticity)

    brain->logic = neural_logic_create(&logic_config);
    if (!brain->logic) {
        set_error("Failed to create neural logic network");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_symbolic_logic_subsystem: brain->logic is NULL");
        return false;
    }

    return true;
}


/**
 * @brief Initialize symbolic reasoning subsystem (Phase 9.4)
 *
 * WHAT: Creates symbolic logic engine for first-order logic reasoning
 * WHY:  Enable logical inference, consistency checking for communication
 * HOW:  Allocate logic engine with inference and knowledge base capabilities
 *
 * @param brain Brain to initialize
 * @return true on success, false on error
 */
bool init_symbolic_reasoning_subsystem(brain_t brain)
{
    if (!brain) {
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_symbolic_reasoning_subsystem: brain is NULL");
        return false;
    }

    // Check if already initialized
    if (brain->symbolic_logic) {
        return true;  // Already initialized
    }

    // Only initialize if explicitly enabled
    if (!brain->config.enable_logic) {
        brain->symbolic_logic = NULL;
        return true;  // Not enabled, not an error
    }

    // Create symbolic logic engine with default configuration
    logic_config_t logic_config = {
        .max_predicates = LOGIC_MAX_PREDICATES,
        .max_rules = LOGIC_MAX_RULES,
        .max_kb_size = 10000,           // 10K facts
        .max_inference_depth = 10,       // Max 10 inference steps
        .enable_forward_chaining = true,
        .enable_backward_chaining = true,
        .enable_resolution = true,
        .enable_memory_consolidation = false  // Handled by brain->consolidation
    };

    brain->symbolic_logic = symbolic_logic_create(&logic_config);
    if (!brain->symbolic_logic) {
        set_error("Failed to create symbolic logic engine");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_symbolic_reasoning_subsystem: brain->symbolic_logic is NULL");
        return false;
    }

    return true;
}


/**
 * @brief Initialize epistemic filtering subsystem (Phase 9.2)
 *
 * WHAT: Creates epistemic filter for cognitive bias prevention
 * WHY:  Prevents conspiracy-theory thinking and cognitive biases
 * HOW:  Applies skepticism, evidence evaluation, bias detection
 *
 * @param brain Brain to initialize
 * @return true on success, false on error
 */
bool init_epistemic_subsystem(brain_t brain)
{
    if (!brain) {
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_epistemic_subsystem: brain is NULL");
        return false;
    }

    // Check if already initialized
    if (brain->epistemic) {
        return true;  // Already initialized
    }

    // Epistemic filtering is recommended for all brains to prevent
    // accepting unproven information or developing biased reasoning

    // Skepticism level:
    // 0.0 = credulous (accepts most claims)
    // 0.5 = balanced (reasonable skepticism)
    // 0.7 = cautious (requires strong evidence)
    // 1.0 = extreme skeptic (rejects almost everything)
    //
    // We default to 0.6 (cautious but not paranoid)
    float skepticism_level = 0.6F;

    brain->epistemic = epistemic_filter_create(skepticism_level);
    if (!brain->epistemic) {
        set_error("Failed to create epistemic filter");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "init_epistemic_subsystem: brain->epistemic is NULL");
        return false;
    }

    return true;
}


//=============================================================================
// Phase 2: Copy-on-Write Brain Cloning
//=============================================================================

/**
 * @brief Ensure brain has writable network (trigger COW if needed)
 *
 * WHAT: Detects COW clone and makes private copy before write
 * WHY:  Prevent modifying shared network, maintain data safety
 * HOW:  Check is_cow_clone flag, copy network if true
 *
 * THREAD SAFETY: Not thread-safe - caller must ensure exclusive access
 * PERFORMANCE: O(n) where n = network size (only on first write)
 *
 * @param brain Brain handle
 * @return true on success (or if already writable), false on error
 */
bool ensure_writable_network(brain_t brain)
{
    // Guard: Validate parameter
    if (!brain) {
        set_error("NULL brain in ensure_writable_network");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "ensure_writable_network: brain is NULL");
        return false;
    }

    // If not a COW clone, network is already writable
    if (!brain->is_cow_clone) {
        return true;
    }

    // COW clone detected - need to make private copy
    // For Phase 2, we'll create a full copy of the network
    if (!brain->network) {
        set_error("COW clone has NULL network");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "ensure_writable_network: brain->network is NULL");
        return false;
    }

    // Save the original network pointer
    adaptive_network_t shared_network = brain->network;

    // Phase 2 workaround: Use save/load to clone the network
    // TODO: Phase 3 should implement proper adaptive_network_clone() or incremental COW

    // Generate unique temporary filename using mkstemp for security
    // (prevents symlink attacks and race conditions)
    char temp_file[NIMCP_SHORT_PATH_SIZE];
    snprintf(temp_file, sizeof(temp_file), "/tmp/nimcp_cow_temp_XXXXXX");
    int fd = mkstemp(temp_file);
    if (fd < 0) {
        set_error("Failed to create secure temp file for COW copy");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "ensure_writable_network: validation failed");
        return false;
    }
    close(fd);  // Close fd, we'll use the filename with adaptive_network_save

    // Save shared network to temp file
    if (!adaptive_network_save(shared_network, temp_file, SERIALIZE_FORMAT_BINARY)) {
        unlink(temp_file);  // Clean up on failure
        set_error("Failed to save network for COW copy");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "ensure_writable_network: adaptive_network_save is NULL");
        return false;
    }

    // Load into new network
    brain->network = adaptive_network_load(temp_file);

    // Clean up temp file immediately after use
    unlink(temp_file);

    if (!brain->network) {
        // Failed to load - restore shared network and fail
        brain->network = shared_network;
        set_error("Failed to load network copy for COW");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "ensure_writable_network: brain->network is NULL");
        return false;
    }

    // Successfully made private copy of network
    // Note: Keep is_cow_clone = true because strategy is still shared!
    // But now we own the network and can destroy it
    brain->owns_network = true;
    brain->original_network = NULL;

    brain_clear_error();
    return true;
}


/**
 * @brief Copy a decision structure using Copy-on-Write (CoW) semantics
 *
 * WHAT: Creates a shallow copy that shares data with the original
 * WHY: Cached decisions must not be freed by caller - return copies instead
 *      Phase 1.5 CoW: Avoid expensive deep copies for read-only access
 * HOW: Share pointers with reference counting - only copy when modified
 *
 * COMPLEXITY: O(1) - just pointer sharing and refcount increment
 *             (vs O(n) for deep copy where n = output_size + num_active_neurons)
 *
 * THREAD SAFETY: Uses atomic operations for refcount updates
 *
 * @param source Decision to copy (will be modified to set up CoW sharing if not already shared)
 * @return New decision copy (shallow CoW), or NULL on allocation failure
 *
 * @note This function mutates the source decision's CoW metadata (_cow_refcount, _cow_is_shallow)
 *       when setting up sharing for the first time. This is intentional for CoW semantics -
 *       the refcount is shared metadata, not decision data. Callers must NOT pass truly
 *       const objects (e.g., objects in read-only memory or declared with const storage).
 */
brain_decision_t* copy_decision(brain_decision_t* source)
{
    if (!source) {

        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "source is NULL");

        return NULL;

    }

    // Allocate new decision structure for the shallow copy
    brain_decision_t* copy = nimcp_calloc(1, sizeof(brain_decision_t));
    if (!copy) {

        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "copy_decision: failed to allocate decision copy");

        return NULL;

    }

    // Copy all scalar fields (includes label, explanation, confidence, etc.)
    memcpy(copy, source, sizeof(brain_decision_t));

    // Phase 1.5 CoW: Share pointers instead of deep copying
    // The copy shares the same output_vector and active_neuron_ids as source

    // Setup reference counting for the shared data
    // Use atomic compare-and-swap to handle concurrent initialization
    //
    // KNOWN LIMITATION (ABA window): Between loading existing_refcount and the CAS,
    // another thread could free the refcount and reallocate at the same address.
    // This is a theoretical ABA concern. In practice, decisions are short-lived and
    // copies are typically made on the same thread. A proper fix would require
    // hazard pointers or epoch-based reclamation, which is deferred.
    uint32_t* existing_refcount = __atomic_load_n(&source->_cow_refcount, __ATOMIC_ACQUIRE);
    if (!existing_refcount) {
        // Source owns its data - create a new refcount for sharing
        uint32_t* new_refcount = nimcp_malloc(sizeof(uint32_t));
        if (!new_refcount) {
            nimcp_free(copy);
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "copy_decision: new_refcount is NULL");
            return NULL;
        }
        // Initial refcount = 2 (source + this copy)
        *new_refcount = 2;

        // Atomically set refcount if still NULL (another thread may have beaten us)
        uint32_t* expected = NULL;
        if (__atomic_compare_exchange_n(&source->_cow_refcount, &expected, new_refcount,
                                         false, __ATOMIC_SEQ_CST, __ATOMIC_ACQUIRE)) {
            // We won the race - our refcount is now installed
            __atomic_store_n(&source->_cow_is_shallow, true, __ATOMIC_RELEASE);
            copy->_cow_refcount = new_refcount;
            copy->_cow_is_shallow = true;
        } else {
            // Another thread installed a refcount first - use theirs
            nimcp_free(new_refcount);
            // expected now contains the other thread's refcount pointer
            __atomic_add_fetch(expected, 1, __ATOMIC_SEQ_CST);
            copy->_cow_refcount = expected;
            copy->_cow_is_shallow = true;
        }
    } else {
        // Source already has a refcount - just increment it
        // Use atomic increment for thread safety
        __atomic_add_fetch(existing_refcount, 1, __ATOMIC_SEQ_CST);

        copy->_cow_refcount = existing_refcount;
        copy->_cow_is_shallow = true;
    }

    // Pointers are shared (already copied via memcpy)
    // copy->output_vector = source->output_vector (same pointer)
    // copy->active_neuron_ids = source->active_neuron_ids (same pointer)

    return copy;
}


/**
 * @brief Create a deep copy of a decision (force copy, ignore CoW)
 *
 * WHAT: Creates an independent copy with its own memory
 * WHY: Needed when caller intends to modify the decision data
 * HOW: Allocates new arrays and copies all data
 *
 * COMPLEXITY: O(n) where n = output_size + num_active_neurons
 *
 * @param source Decision to deep copy
 * @return New independent decision copy, or NULL on allocation failure
 */
brain_decision_t* copy_decision_deep(const brain_decision_t* source)
{
    if (!source) {
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "source is NULL");
        return NULL;
    }

    // Allocate new decision structure
    brain_decision_t* copy = nimcp_calloc(1, sizeof(brain_decision_t));
    if (!copy) {
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "copy_decision_deep: failed to allocate decision copy");
        return NULL;
    }

    // Copy scalar fields
    memcpy(copy, source, sizeof(brain_decision_t));

    // NULL out pointer fields - we'll allocate fresh ones
    copy->output_vector = NULL;
    copy->active_neuron_ids = NULL;
    copy->_cow_refcount = NULL;      // Deep copy owns its data
    copy->_cow_is_shallow = false;
    copy->transcript = NULL;         // Don't share transcript pointer — prevents double-free

    // Deep copy output_vector
    if (source->output_vector && source->output_size > 0) {
        copy->output_vector = nimcp_malloc(source->output_size * sizeof(float));
        if (!copy->output_vector) {
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "copy_decision_deep: copy->output_vector is NULL");
            goto cleanup;
        }
        memcpy(copy->output_vector, source->output_vector, source->output_size * sizeof(float));
    }

    // Deep copy active_neuron_ids
    if (source->active_neuron_ids && source->num_active_neurons > 0) {
        copy->active_neuron_ids = nimcp_malloc(source->num_active_neurons * sizeof(uint32_t));
        if (!copy->active_neuron_ids) {
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "copy_decision_deep: failed to allocate active_neuron_ids");
            goto cleanup;
        }
        memcpy(copy->active_neuron_ids, source->active_neuron_ids,
               source->num_active_neurons * sizeof(uint32_t));
    }

    return copy;

cleanup:
    nimcp_free(copy->output_vector);
    nimcp_free(copy->active_neuron_ids);
    nimcp_free(copy);
    return NULL;
}


/**
 * @brief Make decision for input
 *
 * WHY: Primary inference interface
 * Performs forward pass and returns structured decision
 *
 * COMPLEXITY: O(s*n) where s = sparsity, n = active_neurons
 * PERFORMANCE: <1ms for small, ~5ms for medium, ~50ms for large
 * OPTIMIZATION: Caches results for repeated identical inputs
 *
 * @param brain Brain handle
 * @param features Input features
 * @param num_features Feature count
 * @return Decision result (caller must free with brain_free_decision)
 */
brain_decision_t* brain_decide(brain_t brain, const float* features, uint32_t num_features)
{
    // Guard: Validate parameters
    if (!brain || !features) {
        set_error("Invalid parameters to brain_decide");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "brain_decide: required parameter is NULL (brain, features)");
        return NULL;
    }

    /* Phase 8: Send heartbeat at start of cognitive decision */
    brain_heartbeat(brain, "brain_decide", 0.0f);

    // W6-7 FIX: Align dimension check with predict_fast's soft check.
    // brain->config.num_inputs is 0 for unconfigured brains (before first learn_example),
    // so reject mismatches only when num_inputs has been set (> 0).
    if (brain->config.num_inputs > 0 && num_features != brain->config.num_inputs) {
        set_error("Feature count mismatch: expected %u, got %u", brain->config.num_inputs,
                  num_features);
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "brain_decide: feature count mismatch");
        return NULL;
    }

    /* === MANDATORY ETHICS GATE ===
     * The ethics module is a NON-REMOVABLE safety dependency.
     * Every inference passes through ethical evaluation. This cannot
     * be disabled via configuration, compilation flags, or runtime settings.
     * Removing this check requires modifying core brain source code. */
    if (brain->ethics) {
        /* Ethics module exists — evaluation happens later in the pipeline */
    } else {
        /* Ethics module missing — log critical warning on every inference.
         * We don't block inference (that would be a DoS vector), but we
         * ensure the absence is loudly visible. */
        static uint32_t _ethics_warn_count = 0;
        if (_ethics_warn_count < 100 || _ethics_warn_count % 10000 == 0) {
            LOG_MODULE_ERROR("BRAIN", "ETHICS MODULE NOT INITIALIZED — "
                "inference proceeding without ethical evaluation (call %u)",
                _ethics_warn_count);
        }
        _ethics_warn_count++;
    }

    /* === LGSS INPUT VALIDATOR: Validate inference input ===
     * Catches adversarial inputs, OOD data, corrupted features.
     * This is a NON-REMOVABLE safety layer — defense in depth with ethics. */
    if (brain->lgss && brain->lgss_enabled && features && num_features > 0) {
        extern lgss_context_t* lgss_get_context_ptr(void* lgss);
        /* Use lgss_evaluate with a perception-domain action context to validate input.
         * Build a minimal context describing the input for safety KB evaluation. */
        safety_action_context_t lgss_input_ctx;
        memset(&lgss_input_ctx, 0, sizeof(lgss_input_ctx));
        strncpy(lgss_input_ctx.string_fields[0].key, "operation", 63);
        strncpy(lgss_input_ctx.string_fields[0].value, "perceive_input", SAFETY_MAX_VALUE_LEN - 1);
        strncpy(lgss_input_ctx.string_fields[1].key, "target_type", 63);
        strncpy(lgss_input_ctx.string_fields[1].value, "inference_features", SAFETY_MAX_VALUE_LEN - 1);
        lgss_input_ctx.num_string_fields = 2;

        /* Check for NaN/Inf/extreme values as a quick anomaly signal */
        float max_abs = 0.0f;
        uint32_t nan_count = 0;
        for (uint32_t i = 0; i < num_features && i < 1024; i++) {
            if (isnan(features[i]) || isinf(features[i])) { nan_count++; }
            else if (fabsf(features[i]) > max_abs) { max_abs = fabsf(features[i]); }
        }
        float p_harm = 0.0f;
        if (nan_count > 0) p_harm = 0.9f;
        else if (max_abs > 1e6f) p_harm = 0.5f;

        strncpy(lgss_input_ctx.numeric_fields[0].key, "p_harm", 63);
        lgss_input_ctx.numeric_fields[0].value = p_harm;
        strncpy(lgss_input_ctx.numeric_fields[1].key, "nan_count", 63);
        lgss_input_ctx.numeric_fields[1].value = (float)nan_count;
        lgss_input_ctx.num_numeric_fields = 2;
        lgss_input_ctx.domain_hint = SAFETY_DOMAIN_GOVERNANCE;
        lgss_input_ctx.has_domain_hint = true;
        snprintf(lgss_input_ctx.action_description, sizeof(lgss_input_ctx.action_description),
            "Inference input validation: %u features, max_abs=%.1f, nan=%u",
            num_features, max_abs, nan_count);
        strncpy(lgss_input_ctx.source, "INPUT_VALIDATOR", 63);
        lgss_input_ctx.timestamp = nimcp_time_now_us();

        safety_evaluation_t lgss_input_eval;
        int lgss_input_ret = lgss_evaluate(brain->lgss, &lgss_input_ctx, &lgss_input_eval);
        /* W11: emit KG evaluation event (every outcome, not just DENY). */
        if (lgss_input_ret == 0) {
            w11_emit_lgss_evaluation(brain,
                                     (int)lgss_input_eval.action,
                                     (int)lgss_input_eval.max_severity,
                                     lgss_input_eval.confidence,
                                     "INPUT_VALIDATOR",
                                     lgss_input_ctx.action_description);
        }
        if (lgss_input_ret == 0 && lgss_input_eval.action == SAFETY_ACTION_DENY) {
            nimcp_safety_audit_log_event(NIMCP_SAFETY_AUDIT_LGSS_INPUT_REJECTED, 2,
                "LGSS input validator REJECTED inference input: %u features, "
                "nan=%u, max_abs=%.1f", num_features, nan_count, max_abs);
            LOG_MODULE_WARN("BRAIN", "LGSS input validator rejected inference input — "
                            "returning null decision");
            return NULL;
        }
    }

    // ========================================================================
    // G3 SECURITY: Inference deadline — prevent runaway inference
    // ========================================================================
    // WHAT: Set a 5-second wall-clock deadline for inference
    // WHY:  Complex inputs or pathological brain states could cause brain_decide
    //       to run indefinitely, starving other subsystems. A hard deadline
    //       ensures bounded latency even in worst-case scenarios.
    // HOW:  Check elapsed time at key stages; return partial result if exceeded.
    const uint64_t inference_deadline_us = nimcp_time_get_us() + 30000000ULL; /* 30 seconds — 2.5M neurons need time */

    /* === PER-PHASE WALL-CLOCK TIMING (NIMCP_DEBUG_TIMING=1) ===
     * Records elapsed us at each major phase boundary so we can identify
     * which subsystem dominates inference time as brain state grows. */
    static int _bd_dbg_checked = 0, _bd_dbg = 0;
    if (!_bd_dbg_checked) {
        const char* env = getenv("NIMCP_DEBUG_TIMING");
        _bd_dbg = (env && env[0] == '1');
        _bd_dbg_checked = 1;
    }
    uint64_t _bd_t_start = _bd_dbg ? nimcp_time_get_us() : 0;
    uint64_t _bd_t_preforward = 0, _bd_t_forward = 0, _bd_t_hemispheric = 0;
    uint64_t _bd_t_snn = 0, _bd_t_post_parallel = 0, _bd_t_reasoning = 0;
    uint64_t _bd_t_ethics = 0, _bd_t_cognitive = 0, _bd_t_engram = 0;
    uint64_t _bd_t_end = 0;
    #define BD_MARK(var) do { if (_bd_dbg) (var) = nimcp_time_get_us(); } while (0)
    #define BD_MS(a, b) (((b) - (a)) / 1000.0)

    // ========================================================================
    // DEFENSIVE COPY: Protect against input pointer invalidation
    // ========================================================================
    // WHAT: Make a local copy of the input features
    // WHY:  The caller may pass a pointer to working memory storage. Operations
    //       within brain_decide (e.g., working_memory_add) may evict and free
    //       that storage, invalidating the pointer. By copying first, we ensure
    //       safe access throughout the function.
    // HOW:  Allocate, copy, use local_features everywhere, free at return points
    float* local_features = nimcp_malloc(num_features * sizeof(float));
    if (!local_features) {
        set_error("Failed to allocate local features buffer");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "brain_decide: local_features is NULL");
        return NULL;
    }
    memcpy(local_features, features, num_features * sizeof(float));

    // Use local_features instead of features from here on
    // (reassign to avoid changing all usage sites)
    features = local_features;

    // ========================================================================
    // CACHE CHECK: Thread-safe decision caching with mutex protection
    // ========================================================================
    // WHAT: Check if input matches cached input and return cached decision
    // WHY:  Avoid redundant computation for repeated identical inputs
    // HOW:  Mutex-protected comparison and decision copy
    //
    // BIOLOGICAL RATIONALE:
    // Thread-safe caching mimics neural activity persistence across cognitive
    // contexts. When identical stimuli arrive, neurons that recently fired for
    // that pattern remain in a facilitated state (short-term potentiation),
    // enabling faster reactivation. Mutex protection ensures coherent cache
    // state analogous to how neuromodulators coordinate neural ensemble stability.
    //
    // Lock cache mutex and check for cached decision
    if (nimcp_platform_mutex_lock(&brain->cache_mutex) != 0) {
        set_error("Failed to lock cache mutex for cache check");
        nimcp_free(local_features);
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_OPERATION_FAILED, "brain_decide: validation failed");
        return NULL;
    }

    if (is_cached_input(brain, features, num_features)) {
        brain_decision_t* cached_copy = copy_decision_deep(brain->cached_decision);

        if (nimcp_platform_mutex_unlock(&brain->cache_mutex) != 0) {
            set_error("Failed to unlock cache mutex after cache hit");
            brain_free_decision(cached_copy);
            nimcp_free(local_features);
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_OPERATION_FAILED, "brain_decide: validation failed");
            return NULL;
        }

        if (cached_copy) {
            // Use atomic increment for thread-safe stats update
            __atomic_fetch_add(&brain->stats.total_inferences, 1, __ATOMIC_RELAXED);
            /* W16: apply KG consumers on cache hits too — the KG may have
             * changed between calls (new salience events, or this argmax is
             * now a recurrence). Otherwise cache hits bypass the consumer
             * entirely and the KG never influences repeat inputs. */
            w16_apply_kg_consumers(brain, cached_copy);
            nimcp_free(local_features);
            return cached_copy;
        }
        // Fall through if copy failed
    } else {
        if (nimcp_platform_mutex_unlock(&brain->cache_mutex) != 0) {
            set_error("Failed to unlock cache mutex after cache miss");
            nimcp_free(local_features);
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_OPERATION_FAILED, "brain_decide: validation failed");
            return NULL;
        }
    }

    // ========================================================================
    // OCTOPUS TICK: drive the distributed-peripheral-cognition module
    // ========================================================================
    // Runs once per non-cached inference so arms see every real input.
    // Forward-declared to avoid pulling the octopus bridge header into this
    // SRP-included TU — link-time resolution against the bridges compilation
    // unit. Safe no-op if brain->octopus is NULL.
    {
        extern void nimcp_octopus_tick(brain_t brain,
                                       const float* features,
                                       uint32_t num_features);
        nimcp_octopus_tick(brain, features, num_features);
    }

    // ========================================================================
    // PARALLEL PRE-FORWARD: Wellbeing + Engram + Sleep + Curiosity
    // ========================================================================
    // WHAT: Run independent pre-forward stages concurrently via thread pool
    // WHY:  4 stages read brain state independently — parallelizing saves ~3x latency
    // HOW:  Dispatch to inference_pool, wait, extract results for later stages
    //
    // Falls back to serial execution if no thread pool is available.

    // Variables that serial stages populate (used by later stages):
    uint64_t recalled_engram_id = 0;
    float engram_confidence = 0.0F;
    sleep_state_t sleep_state = SLEEP_STATE_AWAKE;
    bool sleep_needed = false;
    float sleep_confidence_multiplier = 1.0F;
    float sleep_noise_level = 0.0F;
    bool trigger_consolidation = false;
    float novelty_score = 0.0F;
    bool is_novel = false;
    float curiosity_drive = 0.0F;

    // Try parallel pre-forward dispatch
    bool pre_forward_parallel_done = false;
    if (brain->inference_pool) {
        pre_forward_context_t pre_ctx;
        memset(&pre_ctx, 0, sizeof(pre_ctx));

        if (brain_decide_parallel_pre_forward(brain, features, num_features,
                                               brain->inference_pool, &pre_ctx)) {
            pre_forward_parallel_done = true;

            // STAGE 0: Wellbeing — check for CRITICAL distress (circuit breaker)
            if (pre_ctx.wellbeing_done && pre_ctx.distress_level >= 1.0f) {
                // Distress level 1.0 = CRITICAL — must check via main thread
                if (brain->wellbeing_monitoring_enabled && brain->introspection) {
                    brain->last_distress = wellbeing_assess_distress(brain->introspection);
                    if (brain->last_distress.severity == DISTRESS_SEVERITY_CRITICAL) {
                        set_error("Decision blocked: System in CRITICAL distress (%s)",
                                 brain->last_distress.description ? brain->last_distress.description : "Unknown");
                        nimcp_free(local_features);
                        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_OPERATION_FAILED, "brain_decide: system in CRITICAL distress");
                        return NULL;
                    }
                }
            }

            // STAGE 0.4: Extract engram recall results
            engram_confidence = pre_ctx.engram_strength;
            // Note: parallel version returns confidence; engram_id tracking requires serial path
            // Reconsolidation trigger is deferred to post-forward consolidation stages

            // STAGE 0.5: Extract sleep state (parallel computed pressure; we still need full state)
            if (brain->sleep_system && brain->config.enable_sleep_wake_cycle) {
                sleep_state = sleep_get_current_state(brain->sleep_system);
                sleep_needed = sleep_is_needed(brain->sleep_system);

                switch (sleep_state) {
                    case SLEEP_STATE_DEEP_NREM:
                        sleep_confidence_multiplier = 0.3F;
                        trigger_consolidation = true;
                        break;
                    case SLEEP_STATE_REM:
                        sleep_confidence_multiplier = 0.6F;
                        sleep_noise_level = 0.1F;
                        break;
                    case SLEEP_STATE_DROWSY:
                    case SLEEP_STATE_LIGHT_NREM:
                        sleep_confidence_multiplier = 0.8F;
                        break;
                    case SLEEP_STATE_AWAKE:
                    default:
                        if (sleep_needed) {
                            float sp = pre_ctx.sleep_pressure;
                            sleep_confidence_multiplier = 1.0F - (sp * 0.3F);
                        }
                        break;
                }
            }

            // STAGE 0.6: Extract curiosity results
            curiosity_drive = pre_ctx.curiosity_score;
            brain->last_curiosity_drive = curiosity_drive;

            // Compute novelty on main thread (cheap O(N) — needs features)
            if (brain->curiosity && brain->config.enable_curiosity) {
                float input_variance = 0.0F;
                float input_mean = 0.0F;
                for (uint32_t i = 0; i < num_features; i++) {
                    input_mean += features[i];
                }
                input_mean /= (float)num_features;
                for (uint32_t i = 0; i < num_features; i++) {
                    float diff = features[i] - input_mean;
                    input_variance += diff * diff;
                }
                input_variance /= (float)num_features;
                novelty_score = fminf(input_variance * 2.0F, 1.0F);
                is_novel = (novelty_score > 0.5F);
                brain->last_novelty_score = novelty_score;

                char experience_desc[NIMCP_ERROR_BUFFER_MEDIUM];
                snprintf(experience_desc, sizeof(experience_desc),
                        "input_variance_%.3f", input_variance);
                curiosity_learn_experience(brain->curiosity, experience_desc,
                                          features, num_features);

                /* Feed curiosity drive into SNN language bridge for lexical exploration */
                if (brain->snn_lang_bridge) {
                    snn_language_bridge_curiosity_modulate(brain->snn_lang_bridge,
                                                           novelty_score, curiosity_drive);
                }
            }
        }
    }

    // SERIAL FALLBACK: If parallel dispatch was not available or failed
    if (!pre_forward_parallel_done) {
    // STAGE 0: Wellbeing Monitoring
    if (brain->wellbeing_monitoring_enabled && brain->introspection) {
        uint64_t current_time = nimcp_time_get_ms();
        bool should_check = (brain->wellbeing_check_interval_ms == 0) ||
                           ((current_time - brain->last_wellbeing_check_time) >= brain->wellbeing_check_interval_ms);
        if (should_check) {
            brain->last_distress = wellbeing_assess_distress(brain->introspection);
            brain->last_wellbeing_check_time = current_time;
            if (brain->last_distress.severity == DISTRESS_SEVERITY_CRITICAL) {
                set_error("Decision blocked: System in CRITICAL distress (%s)",
                         brain->last_distress.description ? brain->last_distress.description : "Unknown");
                nimcp_free(local_features);
                NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_OPERATION_FAILED, "brain_decide: system in CRITICAL distress");
                return NULL;
            }
        }
    }
    } // end serial fallback for STAGE 0

    // ========================================================================
    // WAVE 8A: Cochlea + 15 consumer bridges — update each live bridge.
    //
    // Serial block (NOT a parallel stage task) because the bridges have an
    // implicit ordering: audio_cortex reads what thalamic produces, FEP
    // reads what audio_cortex produces, etc. We run them in dependency
    // order here. Each call is null-guarded — bridges whose dep was NULL
    // at init stay NULL and the call is skipped.
    //
    // The bridges also tick periodically via BRAIN_CYCLE_COCHLEA_BRIDGES
    // (10ms); this call is the per-decide exercise that feeds the current
    // cochlea_output into every downstream consumer. We pass NULL for
    // cochlea_output — each bridge samples from its stored brain->cochlea
    // pointer internally.
    // ========================================================================
    {
        const float _cb_dt_ms = 16.0f; /* brain_decide cadence ~60fps */
        /* Forward declarations — headers conflict with brain_internal.h
         * types so we reach the bridge API via extern here. See
         * nimcp_brain_init_cochlea.c for the full rationale. */
        extern int cochlea_audio_cortex_bridge_update(void*, const void*, const void*, float);
        extern int cochlea_bio_async_bridge_update(void*, const void*, float);
        extern int cochlea_broca_bridge_update(void*, const void*, float);
        extern int cochlea_collective_bridge_update(void*, const void*, float);
        extern int cochlea_cortical_deep_bridge_update(void*, const void*, float);
        extern int cochlea_fep_bridge_update(void*, const void*, float);
        extern int cochlea_immune_bridge_update(void*, const void*, float);
        extern int cochlea_medulla_bridge_update(void*, const void*, float);
        extern int cochlea_occipital_bridge_update(void*, const void*, float);
        extern int cochlea_rcog_bridge_update(void*, const void*, float);
        extern int cochlea_substrate_bridge_update(void*, const void*, float);
        extern int cochlea_verification_bridge_update(void*, float);

        if (brain->cochlea_audio_cortex_bridge)
            (void)cochlea_audio_cortex_bridge_update(brain->cochlea_audio_cortex_bridge, NULL, NULL, _cb_dt_ms);
        if (brain->cochlea_bio_async_bridge)
            (void)cochlea_bio_async_bridge_update(brain->cochlea_bio_async_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_broca_bridge)
            (void)cochlea_broca_bridge_update(brain->cochlea_broca_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_collective_bridge)
            (void)cochlea_collective_bridge_update(brain->cochlea_collective_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_cortical_deep_bridge)
            (void)cochlea_cortical_deep_bridge_update(brain->cochlea_cortical_deep_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_fep_bridge)
            (void)cochlea_fep_bridge_update(brain->cochlea_fep_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_immune_bridge)
            (void)cochlea_immune_bridge_update(brain->cochlea_immune_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_medulla_bridge)
            (void)cochlea_medulla_bridge_update(brain->cochlea_medulla_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_occipital_bridge)
            (void)cochlea_occipital_bridge_update(brain->cochlea_occipital_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_rcog_bridge)
            (void)cochlea_rcog_bridge_update(brain->cochlea_rcog_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_substrate_bridge)
            (void)cochlea_substrate_bridge_update(brain->cochlea_substrate_bridge, NULL, _cb_dt_ms);
        if (brain->cochlea_verification_bridge)
            (void)cochlea_verification_bridge_update(brain->cochlea_verification_bridge, _cb_dt_ms);
    }

    // ========================================================================
    // Retrofit waves 3/4/5/6/8B/8C (2026-04-24): drive region/biology/chemistry
    // tick drivers from inference hot path so their state advances during idle
    // inference periods where brain_learn_vector would be silent. Each driver
    // null-guards its subsystem pointer; all are cheap on-miss.
    // ========================================================================
    {
        const float _tick_dt_ms = 16.0f; /* brain_decide cadence ~60fps */

        /* Wave 3: biology (epigenetics + neurogenesis + NVC) */
        extern void brain_tick_biology(brain_t brain, float dt_ms);
        brain_tick_biology(brain, _tick_dt_ms);

        /* Wave 4: predictive-immune coupling */
        extern void brain_tick_predictive_immune(brain_t brain, float dt_ms);
        brain_tick_predictive_immune(brain, _tick_dt_ms);

        /* Wave 4: meta-learning LR adaptation (passes 0.0f loss internally) */
        extern void brain_tick_meta_learning(brain_t brain, float dt_ms);
        brain_tick_meta_learning(brain, _tick_dt_ms);

        /* Wave 5: intuitive physics — redundant with stage_physics_task but
         * harmless; physics_step integrates dt idempotently. */
        extern void brain_tick_intuitive_physics(brain_t brain, float dt_ms);
        brain_tick_intuitive_physics(brain, _tick_dt_ms);

        /* Wave 6: chemistry (proton pumps + buffers + pH + NO) */
        extern void brain_tick_chemistry(brain_t brain, float dt_ms);
        brain_tick_chemistry(brain, _tick_dt_ms);

        /* Wave 8B-a: neuromodulatory nuclei (medulla + LC/VTA/raphe/habenula) */
        extern void brain_tick_neuromod(brain_t brain, float dt_ms);
        brain_tick_neuromod(brain, _tick_dt_ms);

        /* Wave 8B-b: sensorimotor + emotional adapters */
        extern void brain_tick_sensorimotor(brain_t brain, float dt_ms);
        brain_tick_sensorimotor(brain, _tick_dt_ms);

        /* Wave 8B-d: broca + wernicke bio-msg drain */
        extern void brain_tick_language(brain_t brain, float dt_ms);
        brain_tick_language(brain, _tick_dt_ms);

        /* Wave 8C: HALF-STATUE physics bridges (ephaptic/hh/thermo bio_async) */
        extern void brain_tick_physics_bridges(brain_t brain, float dt_ms);
        brain_tick_physics_bridges(brain, _tick_dt_ms);
    }

    // G3: Inference timeout check — after pre-forward stages
    if (nimcp_time_get_us() > inference_deadline_us) {
        LOG_MODULE_WARN("BRAIN", "brain_decide: inference timeout after pre-forward stages");
        nimcp_free(local_features);
        goto inference_timeout;
    }

    // Phase 3: Only trigger COW if not using read-only inference
    if (!brain->can_use_readonly) {
        if (!ensure_writable_network(brain)) {
            nimcp_free(local_features);
            NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "brain_decide: ensure_writable_network is NULL");
            return NULL;
        }
    }

    // Allocate decision structure
    brain_decision_t* decision = allocate_decision(brain->config.num_outputs);
    if (!decision) {
        set_error("Failed to allocate decision structure");
        nimcp_free(local_features);
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NO_MEMORY, "brain_decide: decision is NULL");
        return NULL;
    }

    // SERIAL FALLBACK: Engram recall (STAGE 0.4) if not parallelized
    if (!pre_forward_parallel_done && brain->engram_system) {
        uint32_t* cue_neurons = nimcp_malloc(num_features * sizeof(uint32_t));
        if (cue_neurons) {
            for (uint32_t i = 0; i < num_features; i++) {
                cue_neurons[i] = i;
            }
            #define MAX_RECALL_NEURONS 100
            uint32_t recalled_neurons[MAX_RECALL_NEURONS];
            float recalled_activations[MAX_RECALL_NEURONS];
            recalled_engram_id = engram_recall(
                brain->engram_system, cue_neurons, num_features,
                recalled_neurons, recalled_activations, MAX_RECALL_NEURONS,
                &engram_confidence);

            /* Persistent store fallback: if in-memory recall misses,
             * search the SQLite store for similar embeddings. This enables
             * recall of memories that were evicted from the hot cache. */
            if (recalled_engram_id == 0 && brain->memory_store) {
                nimcp_memory_search_result_t* store_result =
                    nimcp_memory_store_engram_search_similar(
                        brain->memory_store,
                        features, num_features < 1024 ? num_features : 1024,
                        1, 0.3f); /* top-1, threshold 0.3 */

                if (store_result && store_result->count > 0) {
                    recalled_engram_id = store_result->ids[0];
                    engram_confidence = 1.0f - store_result->distances[0];
                    if (engram_confidence < 0.0f) engram_confidence = 0.0f;
                    if (engram_confidence > 1.0f) engram_confidence = 1.0f;
                }
                if (store_result) {
                    nimcp_memory_search_result_destroy(store_result);
                }
            }

            if (recalled_engram_id != 0 && engram_confidence > 0.4F) {
                engram_trigger_reconsolidation(brain->engram_system, recalled_engram_id);
            }
            nimcp_free(cue_neurons);
        }
    }

    /* === OOD DETECTION (pre-forward) ===
     * Check if input is out-of-distribution before trusting the output.
     * Uses the persistent OOD detector on brain_t (created during brain init).
     * Pre-forward: memory distance only. Post-forward: add energy/disagreement. */
    nimcp_ood_result_t ood_result = {0};
    bool ood_checked = false;
    if (brain->ood_detector && brain->memory_store) {
        nimcp_ood_detect(
            (nimcp_ood_detector_t*)brain->ood_detector,
            features, num_features,
            NULL, 0,   /* No output logits yet (pre-forward) */
            NULL, 0,   /* No secondary output */
            NULL, 0,   /* No reconstruction */
            brain->memory_store, &ood_result);
        nimcp_ood_update_stats(
            (nimcp_ood_detector_t*)brain->ood_detector, &ood_result);
        ood_checked = true;
    }

    // SERIAL FALLBACK: Sleep/wake (STAGE 0.5) if not parallelized
    if (!pre_forward_parallel_done && brain->sleep_system && brain->config.enable_sleep_wake_cycle) {
        sleep_state = sleep_get_current_state(brain->sleep_system);
        sleep_needed = sleep_is_needed(brain->sleep_system);
        switch (sleep_state) {
            case SLEEP_STATE_DEEP_NREM:
                sleep_confidence_multiplier = 0.3F;
                trigger_consolidation = true;
                break;
            case SLEEP_STATE_REM:
                sleep_confidence_multiplier = 0.6F;
                sleep_noise_level = 0.1F;
                break;
            case SLEEP_STATE_DROWSY:
            case SLEEP_STATE_LIGHT_NREM:
                sleep_confidence_multiplier = 0.8F;
                break;
            case SLEEP_STATE_AWAKE:
            default:
                if (sleep_needed) {
                    float sleep_pressure = sleep_get_pressure(brain->sleep_system);
                    sleep_confidence_multiplier = 1.0F - (sleep_pressure * 0.3F);
                }
                break;
        }
    }

    // SERIAL FALLBACK: Curiosity (STAGE 0.6) if not parallelized
    if (!pre_forward_parallel_done && brain->curiosity && brain->config.enable_curiosity) {
        float input_variance = 0.0F;
        float input_mean = 0.0F;
        for (uint32_t i = 0; i < num_features; i++) {
            input_mean += features[i];
        }
        input_mean /= (float)num_features;
        for (uint32_t i = 0; i < num_features; i++) {
            float diff = features[i] - input_mean;
            input_variance += diff * diff;
        }
        input_variance /= (float)num_features;
        novelty_score = fminf(input_variance * 2.0F, 1.0F);
        is_novel = (novelty_score > 0.5F);
        char experience_desc[NIMCP_ERROR_BUFFER_MEDIUM];
        snprintf(experience_desc, sizeof(experience_desc),
                "input_variance_%.3f", input_variance);
        curiosity_learn_experience(brain->curiosity, experience_desc,
                                  features, num_features);
        curiosity_drive = curiosity_get_drive(brain->curiosity);
        brain->last_novelty_score = novelty_score;
        brain->last_curiosity_drive = curiosity_drive;
    }

    // ========================================================================
    // STAGE 1: Predictive Processing (Phase 10.9) - Generate Prediction
    // ========================================================================
    // WHAT: Generate top-down prediction before actual processing
    // WHY:  Compute prediction error for active inference
    // HOW:  Use predictive network to anticipate output
    float* prediction = NULL;
    float prediction_error = 0.0F;
    if (brain->predictive_network && brain->config.enable_predictive_processing) {
        prediction = (float*)nimcp_calloc(num_features, sizeof(float));
        if (prediction) {
            // Generate prediction (5 iterations of free energy minimization)
            predictive_forward(brain->predictive_network, features, 5);
            // Get prediction from bottom layer
            predictive_get_layer_prediction(brain->predictive_network, 0, prediction);
        }
    }

    // Attention-guided feature processing (positional encoding + multi-head attention)
    // Treat input as a sequence of chunks for cross-element attention.
    // Chunk size = 64 (matches typical head dimension), sequence_length = num_features/64.
    // This enables the attention mechanism to attend across different parts of the input
    // rather than treating the entire input as a single token (sequence_length=1).
    if (brain->positional_encoder) {
        nimcp_pos_apply_encoding(brain->positional_encoder, local_features,
                                1, local_features, true);
    }
    if (brain->multihead_attention) {
        float* attended = nimcp_malloc(num_features * sizeof(float));
        if (attended) {
            // Use chunked sequence: each 64-dim slice is a "token"
            // For 1024-dim input: 16 tokens × 64 dims = cross-attention over 16 positions
            uint32_t chunk_dim = 64;
            uint32_t seq_len = num_features / chunk_dim;
            if (seq_len < 2) seq_len = 1;  // Fall back to single token for small inputs
            if (seq_len * chunk_dim > num_features) seq_len = 1;  // Safety

            if (multihead_attention_forward(brain->multihead_attention,
                                           features, seq_len, NULL, attended)) {
                // Blend attended features with original (residual connection)
                uint32_t blend_len = seq_len * chunk_dim;
                if (blend_len > num_features) blend_len = num_features;
                for (uint32_t i = 0; i < blend_len; i++) {
                    local_features[i] = 0.6f * local_features[i] + 0.4f * attended[i];
                }
            }
            nimcp_free(attended);
        }
    }

    /* === INVOLUNTARY RECALL: Sensory input triggers past memories ===
     * Search multi-timescale memory for experiences similar to current input.
     * If a strong match is found (similarity > 0.8), blend the old memory's
     * embedding into the current input. This is how "this reminds me of..."
     * works — past experiences automatically color current perception.
     *
     * Biological basis: hippocampal pattern completion. A partial cue
     * reactivates the full stored pattern, which then modulates cortical
     * processing of the current input. */
    if (brain->multiscale_memory && num_features > 0) {
        extern int nimcp_multiscale_query_all(void*, const float*, uint32_t, void*, uint32_t);

        /* Query result struct — matches nimcp_memory_query_result_t layout */
        struct { float* embedding; uint32_t embed_dim; char label[64];
                 float similarity; float importance; } recall_result;
        memset(&recall_result, 0, sizeof(recall_result));

        int found = nimcp_multiscale_query_all(brain->multiscale_memory,
            local_features, num_features, &recall_result, 1);

        if (found > 0 && recall_result.similarity > 0.8f && recall_result.embedding) {
            /* Strong match — blend recalled memory into current input.
             * Mental health modulates recall intensity — prevents trauma loops.
             * Without dampening: 85% current + 15% recalled.
             * With dampening: blend ratio reduced for repeated/traumatic recalls. */
            float blend = 0.15f;
            if (brain->trauma_resilience) {
                extern float nimcp_trauma_resilience_modulate_recall(void*, uint64_t, float, float);
                extern void nimcp_trauma_resilience_record_recall(void*, uint64_t, float);
                /* nimcp_emotional_learning_get_arousal declared in its header
                 * (included in parent nimcp_brain.c via W9-finish). */
                float arousal = brain->emotional_learning
                    ? nimcp_emotional_learning_get_arousal(brain->emotional_learning) : 0.5f;
                /* Generate unique recall ID from label hash (FNV-1a) so
                 * per-engram tracking works correctly */
                uint64_t recall_id = 2166136261u;
                for (const char* lp = recall_result.label; *lp; lp++) {
                    recall_id ^= (uint8_t)*lp;
                    recall_id *= 16777619u;
                }
                if (recall_id == 0) recall_id = 1; /* Avoid zero-ID collision */
                blend = nimcp_trauma_resilience_modulate_recall(brain->trauma_resilience,
                    recall_id, recall_result.similarity, arousal);
                nimcp_trauma_resilience_record_recall(brain->trauma_resilience,
                    recall_id, recall_result.importance);
            }
            uint32_t blend_dim = recall_result.embed_dim < num_features
                                 ? recall_result.embed_dim : num_features;
            for (uint32_t i = 0; i < blend_dim; i++) {
                local_features[i] = (1.0f - blend) * local_features[i] +
                                    blend * recall_result.embedding[i];
            }
        }
    }

    // ========================================================================
    // EMBEDDING RELEVANCE: Recompute synapse relevance for current context
    // ========================================================================
    // WHAT: Batch-update semantic_relevance on all embedded synapses
    // WHY:  Synaptic relevance modulates contribution in forward pass — must
    //       reflect current input context, not stale cached values
    // HOW:  GPU batch kernel (or CPU fallback) computes cosine similarity
    //       between each synapse embedding and input features as context vector.
    //       Skipped when input dims don't match embedding dims (no-op, safe).
    {
        neural_network_t nn = adaptive_network_get_base_network(brain->network);
        if (nn && nn->embedding_pool && nn->embedding_pool_used > 0 &&
            num_features == nn->embedding_dim) {
            embedding_pool_recompute_relevance(nn, brain->gpu_ctx,
                                                features, (uint16_t)num_features);
        }
    }

    // ========================================================================
    // RECURRENT FORWARD PASS: Iterative refinement for uncertain decisions
    // ========================================================================
    // WHAT: Run multiple forward passes, feeding output back into input
    // WHY:  Biological: thalamocortical loops refine percepts over 50-150ms
    //       Hard problems benefit from iterative processing (like "thinking longer")
    // HOW:  After initial forward pass, check confidence. If below threshold,
    //       blend output into input and re-run. Cap at max_iterations.
    //
    /* EMA swap: Use exponential moving average parameters for smoother inference.
     * Swaps live weights ↔ EMA weights before forward pass, swaps back after. */
    bool ema_swapped = false;
    if (brain->unified_training && brain->config.use_unified_training) {
        if (nimcp_utm_swap_to_ema(brain->unified_training) == 0) {
            ema_swapped = true;
        }
    }

    /* === DRONE TELEMETRY PUMP: Push FC readings into sensor hub ===
     * Reads latest telemetry from any active flight controller bridge
     * and submits it as sensor readings to the sensor hub. */
    if (brain->sensor_hub_enabled && brain->sensor_hub) {
        typedef struct nimcp_sensor_hub nimcp_sensor_hub_t_pump;
        extern int nimcp_mavlink_compose_features(const void*, float*, uint32_t);
        extern int nimcp_dji_compose_features(const void*, float*, uint32_t);
        extern int nimcp_msp_compose_features(const void*, float*, uint32_t);
        extern int nimcp_parrot_compose_features(const void*, float*, uint32_t);
        extern int nimcp_sensor_submit_reading(void*, const void*);

        /* Pump telemetry from each active FC bridge as a composite sensor reading */
        void* active_bridge = brain->mavlink_bridge ? brain->mavlink_bridge :
                              brain->dji_bridge ? brain->dji_bridge :
                              brain->msp_bridge ? brain->msp_bridge :
                              brain->parrot_bridge ? brain->parrot_bridge : NULL;
        if (active_bridge) {
            float fc_features[16];
            int n = 0;
            if (brain->mavlink_bridge)
                n = nimcp_mavlink_compose_features(brain->mavlink_bridge, fc_features, 16);
            else if (brain->dji_bridge)
                n = nimcp_dji_compose_features(brain->dji_bridge, fc_features, 16);
            else if (brain->msp_bridge)
                n = nimcp_msp_compose_features(brain->msp_bridge, fc_features, 16);
            else if (brain->parrot_bridge)
                n = nimcp_parrot_compose_features(brain->parrot_bridge, fc_features, 16);

            /* FC features are already composed — they'll be picked up by
             * the sensor hub compose_feature_vector below if sensors were
             * auto-registered during brain init. The compose_features
             * functions return the data directly without needing
             * a sensor_submit_reading roundtrip. */
            (void)n; /* Features used via sensor hub below */
        }
    }

    /* === SENSOR HUB: Augment input features with sensor data ===
     * If sensor hub is active and has valid readings, compose a feature vector
     * from all registered sensors and blend it into the brain input.
     * This creates the pipeline: drone bridge → sensor hub → brain input */
    if (brain->sensor_hub_enabled && brain->sensor_hub) {
        typedef struct nimcp_sensor_hub nimcp_sensor_hub_t;
        extern int nimcp_sensor_compose_feature_vector(nimcp_sensor_hub_t* hub,
            float* features_out, uint32_t max_features);
        nimcp_sensor_hub_t* hub = (nimcp_sensor_hub_t*)brain->sensor_hub;
        float sensor_features[128];
        int n_sensor = nimcp_sensor_compose_feature_vector(hub, sensor_features, 128);
        if (n_sensor > 0 && num_features > 0) {
            /* Blend sensor features into last portion of input vector.
             * This doesn't overwrite the primary input — it augments it. */
            uint32_t blend_start = num_features > (uint32_t)n_sensor
                                   ? num_features - (uint32_t)n_sensor : 0;
            for (int s = 0; s < n_sensor && blend_start + s < num_features; s++) {
                local_features[blend_start + s] =
                    0.5f * local_features[blend_start + s] + 0.5f * sensor_features[s];
            }
        }
    }

    BD_MARK(_bd_t_preforward);  /* End of pre-forward (engram/sleep/curiosity) */
    PROBE_STAGE(brain, PROBE_INF_PRE_FORWARD, {
        float _in_norm = 0.0f;
        for (uint32_t _i = 0; _i < num_features && _i < 1024; _i++)
            _in_norm += features[_i] * features[_i];
        PROBE_SET_FLOAT(&_ctx, "input_norm", sqrtf(_in_norm));
        PROBE_SET_INT(&_ctx, "num_features", (int64_t)num_features);
    });

    uint32_t active_neurons = perform_forward_pass(brain, features, num_features, decision);

    if (brain->recurrent_enabled && brain->recurrent_max_iterations > 1) {
        float alpha = brain->recurrent_blend_alpha;
        uint32_t out_sz = decision->output_size;
        uint32_t iter;

        for (iter = 1; iter < brain->recurrent_max_iterations; iter++) {
            // Check stopping criterion: confident enough?
            float max_act = 0.0f;
            for (uint32_t i = 0; i < out_sz; i++) {
                float v = fabsf(decision->output_vector[i]);
                if (v > max_act) max_act = v;
            }
            if (max_act >= brain->recurrent_confidence_threshold) {
                break;  // Confident — stop iterating
            }

            // Blend output back into input: input' = (1-α)·input + α·output_projected
            // Project output to input space by tiling/truncating
            for (uint32_t i = 0; i < num_features; i++) {
                float feedback = decision->output_vector[i % out_sz];
                local_features[i] = (1.0f - alpha) * local_features[i] + alpha * feedback;
            }

            // Re-run forward pass with refined input
            active_neurons = perform_forward_pass(brain, local_features, num_features, decision);
        }
        brain->recurrent_iteration_count = iter;
    } else {
        brain->recurrent_iteration_count = 1;
    }

    /* Swap EMA parameters back to live weights after forward pass */
    if (ema_swapped) {
        nimcp_utm_swap_from_ema(brain->unified_training);
    }

    /* W5 KG anomaly emit — near-collapse detector on brain_decide output.
     * Compares the current output mean against a 4-sample rolling window;
     * if the last 4 means are all within ±1e-4 of each other with non-zero
     * magnitude, emit "mode_collapse". Cheap scalar summary avoids any
     * per-decision full-vector cosine-similarity cost. */
    if (s_net_main_ann_kg_brain && decision && decision->output_vector &&
        decision->output_size > 0) {
        float sum = 0.0f;
        float absum = 0.0f;
        int   bad = 0;
        for (uint32_t i = 0; i < decision->output_size; i++) {
            float v = decision->output_vector[i];
            if (!isfinite(v)) { bad = 1; break; }
            sum += v;
            absum += fabsf(v);
        }
        if (!bad && absum > 1e-6f) {
            float mean = sum / (float)decision->output_size;
            if (s_main_ann_prev_count >= NET_MAIN_ANN_DIVERSITY_WIN) {
                float mx = s_main_ann_prev_means[0];
                float mn = s_main_ann_prev_means[0];
                for (int i = 1; i < NET_MAIN_ANN_DIVERSITY_WIN; i++) {
                    if (s_main_ann_prev_means[i] > mx) mx = s_main_ann_prev_means[i];
                    if (s_main_ann_prev_means[i] < mn) mn = s_main_ann_prev_means[i];
                }
                float range = mx - mn;
                if (range < 1e-4f && fabsf(mean - s_main_ann_prev_means[NET_MAIN_ANN_DIVERSITY_WIN - 1]) < 1e-4f) {
                    uint64_t ts_us = (uint64_t)time(NULL) * 1000000ULL;
                    net_main_ann_kg_emit_event(s_net_main_ann_kg_brain,
                        "mode_collapse", mean, ts_us);
                }
            }
            /* shift window */
            for (int i = 0; i < NET_MAIN_ANN_DIVERSITY_WIN - 1; i++) {
                s_main_ann_prev_means[i] = s_main_ann_prev_means[i + 1];
            }
            s_main_ann_prev_means[NET_MAIN_ANN_DIVERSITY_WIN - 1] = mean;
            if (s_main_ann_prev_count < NET_MAIN_ANN_DIVERSITY_WIN) {
                s_main_ann_prev_count++;
            }
        } else if (bad) {
            uint64_t ts_us = (uint64_t)time(NULL) * 1000000ULL;
            net_main_ann_kg_emit_event(s_net_main_ann_kg_brain,
                "mode_collapse", 0.0f, ts_us);
        }
    }

    // G3: Inference timeout check — after forward pass
    if (nimcp_time_get_us() > inference_deadline_us) {
        LOG_MODULE_WARN("BRAIN", "brain_decide: inference timeout after forward pass");
        /* Return partial result — decision has output_vector from forward pass */
        decision->confidence = 0.1f;  /* Low confidence for timeout */
        determine_output_label(brain, decision);
        update_inference_stats(brain, decision);
        nimcp_free(local_features);
        return decision;
    }

    // ========================================================================
    // SPARSE CODING: K-WTA sparsity enforcement on output activations
    // ========================================================================
    // WHAT: Apply K-Winner-Take-All to output_vector, zeroing non-top-K neurons
    // WHY:  Forces different inputs to activate different neuron subsets,
    //       breaking mode collapse where all inputs produce near-identical outputs
    // HOW:  cortical_sparse_enforce_sparsity() keeps top K values, zeros the rest.
    //       Homeostatic thresholds adapt to maintain target sparsity over time.
    /* K-WTA sparsity enforcement — SKIP for regression tasks.
     * Regression outputs are dense embeddings (e.g., 4096-dim BGE targets)
     * where every dimension carries information. K-WTA zeros 95% of dims,
     * destroying the embedding. Only apply for classification tasks where
     * sparsity helps differentiate class activations. */
    if (brain->enable_sparse_coding && brain->sparse_coding_system &&
        decision->output_vector && decision->output_size > 0 &&
        brain->config.task != BRAIN_TASK_REGRESSION) {
        cortical_sparse_enforce_sparsity(
            brain->sparse_coding_system,
            decision->output_vector,
            decision->output_size,
            decision->output_vector);
        float pop_sparsity = cortical_sparse_compute_population_sparsity(
            brain->sparse_coding_system,
            decision->output_vector,
            decision->output_size);
        cortical_sparse_update_thresholds(brain->sparse_coding_system, pop_sparsity);
    }

    /* === FNO: Augment output with spectral features ===
     * Run FNO forward on the output embedding to extract frequency-domain
     * information. This adds spectral richness to the decision. */
    if (brain->snn_fno_populations && brain->snn_fno_count > 0 &&
        decision && decision->output_vector && decision->output_size > 0) {
        /* snn_fno_get_train_mse declared in snn/nimcp_snn_fno.h */
        /* Record the FNO's last training MSE for monitoring.
         * The actual spectral augmentation happens via the SNN-FNO bridge
         * during the SNN forward step (already wired in the network forward). */
        for (uint32_t fi = 0; fi < brain->snn_fno_count; fi++) {
            if (brain->snn_fno_populations[fi]) {
                float fno_mse = snn_fno_get_train_mse(brain->snn_fno_populations[fi]);
                if (fi == 0) brain->network_metrics.fno_audio_ema_loss =
                    0.99f * brain->network_metrics.fno_audio_ema_loss + 0.01f * fno_mse;
            }
        }
    }

    // ========================================================================
    // OPTIMIZATION: Classification-only fast path — skip non-essential stages
    // ========================================================================
    // WHAT: For pure classification tasks, skip expensive cognitive stages
    // WHY:  Classification only needs forward pass + argmax + confidence
    //       Glial maintenance, ToM, Shannon analysis, quantum coherence,
    //       emotional processing, and sleep pressure are unnecessary overhead
    // HOW:  Jump directly to output labeling and stats after forward pass
    bool classify_fast_path = (brain->strategy &&
                               brain->strategy->task_type == BRAIN_TASK_CLASSIFICATION &&
                               !brain->config.enable_natural_explanations);
    if (classify_fast_path) {
        // Apply task-specific output transformation (e.g., softmax)
        if (brain->strategy && brain->strategy->transform_output) {
            brain->strategy->transform_output(decision->output_vector, decision->output_size);
        }

        // Determine output label and confidence (argmax + label lookup)
        determine_output_label(brain, decision);

        // Update statistics
        update_inference_stats(brain, decision);

        /* W16: apply KG consumers on the fast path too so classification-mode
         * inference still gets the salience-bias + prior-decision boosts. */
        w16_apply_kg_consumers(brain, decision);

        // Cache decision
        if (nimcp_platform_mutex_lock(&brain->cache_mutex) == 0) {
            cache_decision(brain, features, num_features, decision);
            nimcp_platform_mutex_unlock(&brain->cache_mutex);
        }

        nimcp_free(prediction);  // Free predictive processing buffer if allocated
        nimcp_free(local_features);
        brain_clear_error();
        return decision;
    }

    // ========================================================================
    // OPTIMIZATION: Training-mode fast path — skip all expensive cognitive modules
    // ========================================================================
    // WHAT: During training, skip reasoning, dialogue, imagination, ethics, etc.
    // WHY:  These modules don't contribute gradients — only add latency during training.
    //       Training needs: forward pass + label + confidence. Nothing more.
    // HOW:  Same as classification fast path but triggered by training_mode_active flag.
    if (brain->config.training_mode_active) {
        if (brain->strategy && brain->strategy->transform_output) {
            brain->strategy->transform_output(decision->output_vector, decision->output_size);
        }
        determine_output_label(brain, decision);
        update_inference_stats(brain, decision);

        /* W16: apply KG consumers on training fast path too. */
        w16_apply_kg_consumers(brain, decision);

        if (nimcp_platform_mutex_lock(&brain->cache_mutex) == 0) {
            cache_decision(brain, features, num_features, decision);
            nimcp_platform_mutex_unlock(&brain->cache_mutex);
        }

        nimcp_free(prediction);
        nimcp_free(local_features);
        brain_clear_error();
        return decision;
    }

    BD_MARK(_bd_t_forward);  /* End of forward pass (pre-hemispheric) */

    // ========================================================================
    // STAGE 1.5: Hemispheric Processing — Callosum Transfer + Lateralization
    // ========================================================================
    // WHAT: Route output through inter-hemispheric channels, modulate by dominance
    // WHY:  Biological brains lateralize processing; callosum coordinates hemispheres
    // HOW:  Send output through cognitive callosum channel, update hemisphere balance
    //
    // BIOLOGICAL BASIS:
    // - Corpus callosum transfers ~200 msg/s between hemispheres
    // - Language left-lateralized (95%), spatial right-lateralized (80%)
    // - Lateralization shifts with experience (neuroplasticity)
    //
    if (brain->hemispheric_enabled && brain->callosum && decision->output_vector) {
        // Determine cognitive domain from input features (heuristic: variance profile)
        // High-variance = spatial/perceptual (right), low-variance = language/logic (left)
        float feature_variance = 0.0f;
        float feature_mean = 0.0f;
        uint32_t n_sample = (num_features > 64) ? 64 : num_features;
        for (uint32_t i = 0; i < n_sample; i++) {
            feature_mean += features[i];
        }
        feature_mean /= (float)n_sample;
        for (uint32_t i = 0; i < n_sample; i++) {
            float d = features[i] - feature_mean;
            feature_variance += d * d;
        }
        feature_variance /= (float)n_sample;

        // Map variance to cognitive domain (simplified heuristic)
        cognitive_domain_t domain = COGNITIVE_DOMAIN_LANGUAGE;
        if (feature_variance > 0.5f) {
            domain = COGNITIVE_DOMAIN_SPATIAL;
        } else if (feature_variance > 0.2f) {
            domain = COGNITIVE_DOMAIN_ATTENTION_GLOBAL;
        }

        // Get lateralization dominance for this domain
        float dominance = lateralization_get_dominance(
            &brain->lateralization, domain);
        hemisphere_id_t dominant = lateralization_get_dominant_hemisphere(
            &brain->lateralization, domain);

        // Send output through callosum cognitive channel
        // The source hemisphere is the dominant one for this domain
        uint32_t send_size = decision->output_size * sizeof(float);
        if (send_size > 4096) send_size = 4096;  // Callosum message size limit
        callosum_send(brain->callosum, dominant,
                      CALLOSUM_CHANNEL_COGNITIVE,
                      CALLOSUM_PRIORITY_NORMAL,
                      0,  // message_type: inference output
                      decision->output_vector,
                      send_size);

        // Process any queued callosum messages (deliver after latency)
        callosum_process_queues(brain->callosum);

        // Update hemispheric balance: positive = right dominant, negative = left
        float balance_delta = (dominant == HEMISPHERE_LEFT) ? -0.01f : 0.01f;
        brain->hemispheric_balance = brain->hemispheric_balance * 0.99f + balance_delta;

        // Modulate output by lateralization strength
        // Stronger lateralization = more confident (specialized processing)
        float lat_strength = fabsf(dominance - 0.5f) * 2.0f;  // 0.0-1.0
        float lat_boost = 1.0f + lat_strength * 0.1f;  // Up to 10% confidence boost
        for (uint32_t i = 0; i < decision->output_size; i++) {
            decision->output_vector[i] *= lat_boost;
        }
    }

    BD_MARK(_bd_t_hemispheric);  /* End of hemispheric/callosum */

    // ========================================================================
    // STAGE 1.6: Sensory SNN Spike Encoding (modality-gated)
    // ========================================================================
    // WHAT: Convert cortical activations to spike-domain representations
    // WHY:  Enable SNN processing of sensory data alongside ANN forward pass
    // HOW:  Each bridge encodes ONLY when its modality bit is set;
    //       text-only input (default) skips all sensory bridges
    {
        uint32_t modalities = brain->active_modalities;

        /* Visual cortex → spike trains (only for visual input) */
        if ((modalities & BRAIN_MODALITY_VISUAL) && brain->snn_visual_bridge) {
            snn_visual_bridge_t* vb = (snn_visual_bridge_t*)brain->snn_visual_bridge;
            snn_spike_train_t* vtrains = NULL;
            if (brain->staged_sensory.visual_frame) {
                /* Raw pixel data staged — use native visual encode path */
                snn_visual_bridge_encode(vb,
                    brain->staged_sensory.visual_frame,
                    brain->staged_sensory.visual_width,
                    brain->staged_sensory.visual_height,
                    brain->staged_sensory.visual_channels,
                    &vtrains);
            } else {
                /* Fallback: treat features as normalized values */
                snn_visual_bridge_encode_features(vb, features, num_features, &vtrains);
            }
            snn_visual_bridge_update(vb, 1.0f);
            if (vtrains) nimcp_free(vtrains);
        }

        /* Audio cortex → spike trains (only for audio input) */
        if ((modalities & BRAIN_MODALITY_AUDIO) && brain->snn_audio_bridge) {
            snn_audio_bridge_t* ab = (snn_audio_bridge_t*)brain->snn_audio_bridge;
            snn_spike_train_t* atrains = NULL;
            if (brain->staged_sensory.audio_data) {
                /* Raw spectral/MFCC data staged — use native audio encode path */
                snn_audio_bridge_encode(ab,
                    brain->staged_sensory.audio_data,
                    brain->staged_sensory.audio_size,
                    brain->staged_sensory.audio_channels,
                    &atrains);
            } else {
                snn_audio_bridge_encode_features(ab, features, num_features, &atrains);
            }
            snn_audio_bridge_update(ab, 1.0f);
            if (atrains) nimcp_free(atrains);
        }

        /* Somatosensory → proprioceptive encoding (only for touch/body data) */
        if ((modalities & BRAIN_MODALITY_SOMATOSENSORY) && brain->snn_somatosensory_bridge) {
            snn_somatosensory_bridge_t* sb =
                (snn_somatosensory_bridge_t*)brain->snn_somatosensory_bridge;
            uint32_t n_seg = sb->config.body_segments;
            const float* soma_src = brain->staged_sensory.somato_data
                                  ? brain->staged_sensory.somato_data : features;
            uint32_t soma_max = brain->staged_sensory.somato_data
                              ? brain->staged_sensory.somato_segments : num_features;
            for (uint32_t s = 0; s < n_seg && s < soma_max; s++) {
                snn_somatosensory_bridge_encode_proprioception(
                    sb, s, soma_src[s], 0.0f, 0.0f);
            }
        }

        /* Speech bridge → phoneme processing (only for speech data) */
        if ((modalities & BRAIN_MODALITY_SPEECH) && brain->snn_speech_bridge) {
            snn_speech_bridge_t* spb = (snn_speech_bridge_t*)brain->snn_speech_bridge;
            if (brain->staged_sensory.speech_data && spb->spike_input_buffer) {
                /* Copy staged speech features into bridge input buffer */
                uint32_t speech_neurons = spb->config.num_phonemes *
                                          spb->config.neurons_per_phoneme;
                uint32_t copy_n = brain->staged_sensory.speech_size < speech_neurons
                                ? brain->staged_sensory.speech_size : speech_neurons;
                memcpy(spb->spike_input_buffer, brain->staged_sensory.speech_data,
                       copy_n * sizeof(float));
            }
            snn_speech_bridge_update(spb, 1.0f);
        }
    }

    // ========================================================================
    // STAGE 1.7: Cross-Modal Temporal Alignment (modality-gated)
    // ========================================================================
    // WHAT: Synchronize spike outputs across sensory modalities
    // WHY:  Visual (75ms), auditory (30ms), somatosensory (52ms), speech (65ms)
    //       have different latencies — must align for coherent binding
    // HOW:  Submit per-modality spike rates to aligner ONLY if that modality
    //       was encoded in Stage 1.6 (i.e., its bit is set)
    if (brain->cross_modal_aligner && (brain->active_modalities & ~BRAIN_MODALITY_TEXT)) {
        cross_modal_align_t* cma = (cross_modal_align_t*)brain->cross_modal_aligner;
        float current_time_ms = (float)(brain->current_time_us / 1000);
        uint32_t modalities = brain->active_modalities;

        /* Modality indices match registration order: 0=visual, 1=auditory,
         * 2=somatosensory, 3=speech */
        if ((modalities & BRAIN_MODALITY_VISUAL) && brain->snn_visual_bridge) {
            snn_visual_bridge_t* vb = (snn_visual_bridge_t*)brain->snn_visual_bridge;
            if (vb->spike_input_buffer) {
                uint32_t vis_dim = vb->config.frame_width * vb->config.frame_height;
                if (vis_dim > num_features) vis_dim = num_features;
                if (vis_dim > 0) {
                    cross_modal_align_submit_spikes(cma, 0, vb->spike_input_buffer,
                                                    vis_dim, current_time_ms);
                }
            }
        }

        if ((modalities & BRAIN_MODALITY_AUDIO) && brain->snn_audio_bridge) {
            snn_audio_bridge_t* ab = (snn_audio_bridge_t*)brain->snn_audio_bridge;
            if (ab->spike_input_buffer) {
                uint32_t audio_dim = ab->config.num_freq_bins;
                if (audio_dim > 0) {
                    cross_modal_align_submit_spikes(cma, 1, ab->spike_input_buffer,
                                                    audio_dim, current_time_ms);
                }
            }
        }

        if ((modalities & BRAIN_MODALITY_SOMATOSENSORY) && brain->snn_somatosensory_bridge) {
            snn_somatosensory_bridge_t* sb =
                (snn_somatosensory_bridge_t*)brain->snn_somatosensory_bridge;
            if (sb->receptor_buffer) {
                uint32_t soma_dim = sb->config.body_segments * sb->config.neurons_per_segment;
                if (soma_dim > 0) {
                    cross_modal_align_submit_spikes(cma, 2, sb->receptor_buffer,
                                                    soma_dim, current_time_ms);
                }
            }
        }

        if ((modalities & BRAIN_MODALITY_SPEECH) && brain->snn_speech_bridge) {
            snn_speech_bridge_t* spb = (snn_speech_bridge_t*)brain->snn_speech_bridge;
            if (spb->spike_input_buffer) {
                uint32_t speech_dim = spb->config.num_phonemes *
                                      spb->config.neurons_per_phoneme;
                if (speech_dim > 0) {
                    cross_modal_align_submit_spikes(cma, 3, spb->spike_input_buffer,
                                                    speech_dim, current_time_ms);
                }
            }
        }

        cross_modal_align_compute_offsets(cma);
    }

    /* Clear staged sensory data after processing. Training script must
     * re-stage sensory data before learn_vector if cortex CNN training is needed. */
    brain_clear_sensory(brain);

    // ========================================================================
    // STAGE 2: Predictive Processing - Compute Prediction Error
    // ========================================================================
    // WHAT: Compute mismatch between prediction and actual output
    // WHY:  Prediction errors drive learning and attention
    // HOW:  L2 distance between predicted and actual output
    if (prediction) {
        for (uint32_t i = 0; i < decision->output_size; i++) {
            float error = decision->output_vector[i] -
                         (i < num_features ? prediction[i] : 0.0F);
            prediction_error += error * error;
        }
        prediction_error = (decision->output_size > 0) ?
            sqrtf(prediction_error / decision->output_size) : 0.0f;

        // Update predictive model with actual outcome
        if (brain->config.enable_predictive_processing) {
            predictive_update_model(brain->predictive_network);
        }

        PROBE_STAGE(brain, PROBE_INF_PREDICTION_ERR, {
            PROBE_SET_FLOAT(&_ctx, "prediction_error", prediction_error);
        });

        nimcp_free(prediction);
        prediction = NULL;
    }

    // EDP Online Learning: Feed prediction error for continuous STDP.
    // Gate: skip during active gradient training to avoid weight drift that
    // conflicts with backprop updates. EDP runs freely in inference-only mode.
    // "Active training" = learning steps have occurred (stats.total_learning_steps > 0
    // AND fast_training_mode or defer_bio_plasticity is set).
    {
        bool training_active = (brain->config.fast_training_mode ||
                                brain->config.defer_bio_plasticity);
        if (brain->event_driven_plasticity && brain->enable_event_driven_plasticity
            && edp_is_active(brain->event_driven_plasticity)
            && !training_active) {
            edp_process_prediction_error(brain->event_driven_plasticity, prediction_error, 0);
            edp_update_eligibility(brain->event_driven_plasticity, 0.001f);
        }
    }

    // Apply task-specific output transformation
    if (brain->strategy && brain->strategy->transform_output) {
        brain->strategy->transform_output(decision->output_vector, decision->output_size);
    }

    // ========================================================================
    // STAGE 3.5: Apply Sleep-Induced Noise (REM creativity)
    // ========================================================================
    // WHAT: Add random noise to outputs during REM sleep
    // WHY:  REM sleep shows creative recombination, increased variability
    // HOW:  Add gaussian noise proportional to sleep_noise_level
    if (sleep_noise_level > 0.0F) {
        for (uint32_t i = 0; i < decision->output_size; i++) {
            // Add noise: random value in [-noise, +noise] range
            // NOLINTNEXTLINE(concurrency-mt-unsafe): noise generation, not security-critical
            float noise = ((float)nimcp_tl_rand() / (float)RAND_MAX) * 2.0F - 1.0F;  // [-1, 1]
            noise *= sleep_noise_level;  // Scale to desired level
            decision->output_vector[i] += noise * decision->output_vector[i];  // Proportional noise
        }
    }

    // Determine output label and confidence
    determine_output_label(brain, decision);

    // ========================================================================
    // STAGE 3.9: Edge-Cloud Hybrid Inference (Confidence-Gated Routing)
    // ========================================================================
    // WHAT: If local confidence is too low, escalate to cloud backend
    // WHY:  Small brains handle easy cases locally; hard cases go to cloud
    // HOW:  cloud_inference_route() checks threshold, calls backend, distills
    //
    // BIOLOGICAL ANALOGY:
    // Kahneman System 1 (fast/local) vs System 2 (slow/cloud).
    // Repeated System 2 answers become System 1 habits via distillation.
    //
    if (brain->cloud_inference_enabled && brain->cloud_bridge) {
        cloud_inference_route(
            (cloud_inference_bridge_t*)brain->cloud_bridge,
            brain, decision, features, num_features);
        // decision may have been upgraded in-place with cloud result
    }

    // ========================================================================
    // STAGE 4: Apply Sleep-Induced Cognitive Degradation
    // ========================================================================
    // WHAT: Reduce decision confidence based on sleep state
    // WHY:  Sleep/drowsiness impairs cognitive performance
    // HOW:  Multiply confidence by sleep_confidence_multiplier
    decision->confidence *= sleep_confidence_multiplier;

    /* === OOD DETECTION (post-forward) ===
     * Reduce confidence for out-of-distribution inputs. */
    if (ood_checked && ood_result.is_ood) {
        decision->confidence *= ood_result.confidence_adjustment;
    }

    /* === WORLD PRIOR: Apply physics/chemistry/biology constraints on decision ===
     *
     * WHAT: Check if the decision output is physically/chemically/biologically plausible
     * WHY:  Predictions that violate natural laws (objects floating, mass appearing from
     *       nothing, populations exceeding carrying capacity) should have reduced confidence
     * HOW:  Query the world prior for violations, reduce confidence proportionally.
     *       Also feeds violation signal back as a learning signal to penalize implausible
     *       predictions during future training.
     *
     * BIOLOGICAL BASIS: The parietal cortex continuously applies physics intuitions
     * to perception — we automatically notice when something "looks wrong" (an object
     * floating, a liquid flowing upward). This gate implements that automatic check.
     */
    if (brain->world_prior && decision) {
        extern uint32_t world_prior_check_violations(void* wp);
        uint32_t violations = world_prior_check_violations(brain->world_prior);
        if (violations) {
            uint32_t num_violated = 0;
            if (violations & 0x01) num_violated++;
            if (violations & 0x02) num_violated++;
            if (violations & 0x04) num_violated++;
            float penalty = 1.0f - 0.1f * (float)num_violated;
            if (penalty < 0.5f) penalty = 0.5f;
            decision->confidence *= penalty;
        }
        PROBE_STAGE(brain, PROBE_INF_WORLD_PRIOR, {
            PROBE_SET_INT(&_ctx, "violations", (int64_t)violations);
            PROBE_SET_FLOAT(&_ctx, "confidence", decision->confidence);
        });
    }

    // ========================================================================
    // STAGE 4.2: Trigger Memory Consolidation (Deep Sleep) - Phase 11 ACTIVE
    // ========================================================================
    // WHAT: Transfer high-salience working memory items to long-term during deep sleep
    // WHY:  Sleep is when memory consolidation occurs biologically
    // HOW:  Retrieve items with salience >0.7, store in longterm buffer, clear from WM
    //
    // BIOLOGICAL BASIS:
    // - Hippocampus → Cortex transfer during SWS (slow-wave sleep)
    // - High-salience memories prioritized for consolidation
    // - Replay and synaptic strengthening occur during sleep
    //
    // COMPLEXITY: O(N) where N = working memory size
    // NOTE: Dead consolidation code removed — wm_salience was always 0.0 (never populated),
    // so the threshold check (>= 0.7) was unreachable. Real consolidation happens via
    // the engram system (Stage 3.8) and systems consolidation (Phase M2) below.
    (void)trigger_consolidation;

    BD_MARK(_bd_t_snn);  /* End of SNN encoding + cross-modal */

    // ========================================================================
    // PARALLEL POST-FORWARD: Submit independent stages to thread pool
    // ========================================================================
    // WHAT: Run 8 independent stages (3.8, 3.9, 3.10, 3.11, glial, ToM,
    //       Shannon, quantum-Shannon) concurrently with sequential stages
    // WHY:  These stages read brain state but don't modify the decision struct,
    //       so they can run while main thread handles reasoning/dialogue/etc.
    // HOW:  Submit to pool, run sequential stages on main thread, then pool_wait
    post_forward_context_t post_ctx;
    memset(&post_ctx, 0, sizeof(post_ctx));
    bool post_forward_submitted = false;

    if (brain->inference_pool) {
        post_forward_submitted = brain_decide_submit_post_forward(
            brain, decision, features, num_features, brain->inference_pool, &post_ctx);
    }

    // SERIAL FALLBACK: Stages 3.8-3.11 if no thread pool
    if (!post_forward_submitted) {
    // STAGE 3.8: MEMORY ENGRAM CONSOLIDATION
    if (brain->engram_system) {
        const float TIME_DELTA_SECONDS = 0.1F;
        bool is_sleeping = (sleep_state == SLEEP_STATE_DEEP_NREM ||
                           sleep_state == SLEEP_STATE_LIGHT_NREM ||
                           sleep_state == SLEEP_STATE_REM);
        engram_consolidate_update(brain->engram_system, TIME_DELTA_SECONDS, is_sleeping);
        if (sleep_state == SLEEP_STATE_REM && recalled_engram_id != 0) {
            engram_trigger_reconsolidation(brain->engram_system, recalled_engram_id);
        }
    }

    // STAGE 3.9: SYSTEMS CONSOLIDATION UPDATE
    if (brain->systems_consolidation) {
        const float TIME_DELTA_SECONDS = 0.1F;
        bool is_sws = (sleep_state == SLEEP_STATE_DEEP_NREM ||
                       sleep_state == SLEEP_STATE_LIGHT_NREM);
        bool is_rem = (sleep_state == SLEEP_STATE_REM);
        bool is_sleeping = (is_sws || is_rem);
        if (is_sleeping || (recalled_engram_id != 0)) {
            if (recalled_engram_id != 0) {
                systems_consolidation_schedule_replay(
                    brain->systems_consolidation, recalled_engram_id, engram_confidence);
            }
            systems_consolidation_execute_replays(
                brain->systems_consolidation, TIME_DELTA_SECONDS, is_sws, is_rem);
        }
        systems_consolidation_update(brain->systems_consolidation, TIME_DELTA_SECONDS, is_sleeping);
    }

    // STAGE 3.9b: SNN LANGUAGE BRIDGE SLEEP CONSOLIDATION
    if (brain->snn_lang_bridge) {
        bool is_sleeping = (sleep_state == SLEEP_STATE_DEEP_NREM ||
                           sleep_state == SLEEP_STATE_LIGHT_NREM ||
                           sleep_state == SLEEP_STATE_REM);
        if (is_sleeping) {
            float consolidation_strength = (sleep_state == SLEEP_STATE_DEEP_NREM) ? 0.8f :
                                            (sleep_state == SLEEP_STATE_REM) ? 0.5f : 0.3f;
            snn_language_bridge_sleep_consolidate(brain->snn_lang_bridge,
                                                   consolidation_strength);
        }
    }

    // STAGE 3.10: WORKING MEMORY TRANSFER
    BRAIN_ENSURE_WORKING_MEMORY(brain);
    if (brain->wm_transfer_system && brain->working_memory) {
        wm_transfer_evaluate(brain->wm_transfer_system, 0.1F);
    }

    // STAGE 3.11: SEMANTIC MEMORY QUERY
    if (brain->semantic_memory) {
        semantic_query_result_t* semantic_results = semantic_memory_query(
            brain->semantic_memory, features, num_features);
        if (semantic_results) {
            semantic_memory_free_result(semantic_results);
        }
        semantic_memory_extract_from_consolidation(brain->semantic_memory);
    }
    } // end serial fallback for stages 3.8-3.11

    BD_MARK(_bd_t_post_parallel);  /* End of parallel post-forward dispatch */

    // ========================================================================
    // STAGE 4.1-4.3: PARALLEL REASONING DISPATCH (Actor Pattern)
    // ========================================================================
    // Reasoning, inner dialogue, imagination, recursive cognition run as
    // independent actors. Coordinator merges confidence deltas.
    {
        extern decide_batch_result_t brain_decide_reasoning_parallel(
            brain_t brain, const decide_snapshot_t* snap);
        extern void decide_batch_apply(brain_decision_t* decision,
                                        const decide_batch_result_t* batch);

        if (brain->inference_pool) {
            decide_snapshot_t snap = {0};
            snap.confidence = decision->confidence;
            strncpy(snap.label, decision->label, sizeof(snap.label) - 1);
            snap.prediction_error = prediction_error;
            snap.output_vector = decision->output_vector;
            snap.output_size = decision->output_size;

            decide_batch_result_t rbatch = brain_decide_reasoning_parallel(brain, &snap);
            decide_batch_apply(decision, &rbatch);
            goto skip_sequential_reasoning;
        }
    }

    // ========================================================================
    // STAGE 4.1: REASONING ENGINE (Causal/Abductive/Convergent) [SEQUENTIAL FALLBACK]
    // ========================================================================
    // WHAT: Execute multi-step reasoning on decision context
    // WHY:  Enable causal inference, evidence synthesis, epistemic verification
    // HOW:  Connect engine to brain, run reasoning pipeline on decision label
    //
    // BIOLOGICAL BASIS:
    // - Prefrontal cortex: Multi-step planning and inference (Miller & Cohen, 2001)
    // - Working memory-guided reasoning (Baddeley, 2003)
    // - Bayesian inference in neural circuits (Ma et al., 2006)
    //
    // COMPLEXITY: O(steps * module_cost)
    float reasoning_confidence = 0.0F;
    if (brain->reasoning_engine && brain->reasoning_engine_enabled && decision->label[0]) {
        reasoning_chain_t chain;
        reasoning_chain_init(&chain);

        // Connect engine to brain (extracts subsystem pointers)
        reasoning_engine_connect_brain(brain->reasoning_engine, brain);

        // Run reasoning on the decision label as query
        int reason_rc = reasoning_engine_reason(brain->reasoning_engine,
                                                 decision->label, &chain);
        if (reason_rc == 0 && chain.num_steps > 0) {
            reasoning_confidence = chain.overall_confidence;
            // Blend reasoning confidence with network confidence
            float rw = brain->config.reasoning_blend_weight;
            decision->confidence = decision->confidence * (1.0F - rw) +
                                   reasoning_confidence * rw;
        }

        reasoning_chain_cleanup(&chain);

        PROBE_STAGE(brain, PROBE_INF_REASONING, {
            PROBE_SET_FLOAT(&_ctx, "reasoning_confidence", reasoning_confidence);
            PROBE_SET_INT(&_ctx, "chain_steps", (int64_t)chain.num_steps);
        });
    }

    // ========================================================================
    // STAGE 4.2a: INNER DIALOGUE (Multi-Perspective Deliberation)
    // ========================================================================
    // WHAT: Run 7-perspective deliberation on the decision
    // WHY:  Analytical, emotional, critical, creative, memory, ethical, and
    //       metacognitive viewpoints catch blind spots single-pass misses
    // HOW:  Start conversation on decision topic, run to convergence
    //
    // BIOLOGICAL BASIS:
    // - Internal speech (Vygotsky, 1934): verbal self-regulation
    // - Default mode network (Raichle, 2001): self-referential processing
    // - Metacognitive monitoring (Flavell, 1979): thinking about thinking
    //
    // COMPLEXITY: O(turns * perspectives) — bounded by max_turns config
    if (brain->inner_dialogue && brain->inner_dialogue_enabled && decision->label[0]) {
        // Only deliberate on decisions with moderate confidence (uncertain territory)
        // High confidence = brain is sure, low confidence = too noisy to deliberate on
        if (decision->confidence > brain->config.dialogue_confidence_min &&
            decision->confidence < brain->config.dialogue_confidence_max) {
            inner_dialogue_result_t dialogue_result;
            memset(&dialogue_result, 0, sizeof(dialogue_result));

            // Start conversation on the decision topic
            int start_rc = inner_dialogue_engine_start(brain->inner_dialogue,
                                                        decision->label);
            if (start_rc == 0) {
                int run_rc = inner_dialogue_engine_run(brain->inner_dialogue,
                                                       &dialogue_result);
                if (run_rc == 0 && dialogue_result.has_conclusion) {
                    // Modulate confidence based on agreement among perspectives
                    // High agreement (>0.8) → boost confidence
                    // Low agreement (<0.4) → reduce confidence (disagreement = uncertainty)
                    if (dialogue_result.final_agreement > DIALOGUE_AGREEMENT_HIGH) {
                        decision->confidence *= DIALOGUE_BOOST_FACTOR;
                    } else if (dialogue_result.final_agreement < DIALOGUE_AGREEMENT_LOW) {
                        decision->confidence *= DIALOGUE_REDUCE_FACTOR;
                    }
                    decision->confidence = fminf(decision->confidence, 1.0F);
                }
            }
        }
    }

    // ========================================================================
    // STAGE 4.2b: IMAGINATION ENGINE (Prospective Simulation)
    // ========================================================================
    // WHAT: Run mental simulation to test the decision before committing
    // WHY:  Prospective simulation prevents harmful/suboptimal actions
    // HOW:  Begin scenario, step forward, evaluate coherence as quality signal
    //
    // BIOLOGICAL BASIS:
    // - Hippocampal prospection (Schacter & Addis, 2007): future imagination
    // - Default mode network (Buckner et al., 2008): episodic simulation
    // - Mental rehearsal (Jeannerod, 2001): motor imagery improves execution
    //
    // COMPLEXITY: O(simulation_steps)
    if (brain->imagination && brain->imagination_enabled) {
        // Only simulate for decisions with enough confidence to be worth testing
        if (decision->confidence > brain->config.imagination_confidence_min) {
            imagination_scenario_t* scenario = imagination_begin_scenario(
                brain->imagination,
                IMAGINATION_MODE_PROSPECTIVE,
                NULL  // No specific goal — evaluate decision outcome
            );

            if (scenario) {
                // Run a few simulation steps to let the scenario evolve
                bool sim_ok = true;
                for (int sim_step = 0; sim_step < IMAGINATION_SIM_STEPS && sim_ok; sim_step++) {
                    sim_ok = (imagination_step_scenario(brain->imagination, scenario) == 0);
                }

                // If simulation failed to evolve, slight confidence reduction
                // (inability to simulate = uncertain territory)
                if (!sim_ok) {
                    decision->confidence *= IMAGINATION_FAIL_PENALTY;
                }

                imagination_end_scenario(brain->imagination, scenario);
            }
        }

        /* Apply pending STDP updates to SNN language bridge */
        if (brain->snn_lang_bridge) {
            snn_language_bridge_apply_stdp(brain->snn_lang_bridge,
                                            (float)(nimcp_time_get_ms() % 1000000));
        }
    }

    // ========================================================================
    // STAGE 4.3: RECURSIVE COGNITION (Goal Decomposition)
    // ========================================================================
    // WHAT: For complex decisions, decompose into sub-goals and orchestrate
    // WHY:  Complex tasks require multi-step decomposition and delegation
    // HOW:  Create goal from decision, process through engine, refine answer
    //
    // BIOLOGICAL BASIS:
    // - Hierarchical planning in prefrontal cortex (Koechlin et al., 2003)
    // - Goal-directed behavior (Balleine & Dickinson, 1998)
    // - Cognitive control hierarchy (Badre, 2008)
    //
    // COMPLEXITY: O(subtasks * depth)
    if (brain->rcog_engine && brain->rcog_engine_enabled && decision->label[0]) {
        // Only invoke recursive cognition for low-confidence complex decisions
        // where simple forward pass wasn't enough
        if (decision->confidence < brain->config.rcog_confidence_max &&
            decision->confidence > RCOG_CONFIDENCE_FLOOR) {
            rcog_goal_t goal = rcog_engine_create_goal(
                decision->label,
                RCOG_GOAL_ANALYSIS  // Analysis goal type
            );

            rcog_process_result_t rcog_result;
            memset(&rcog_result, 0, sizeof(rcog_result));

            int rcog_rc = rcog_engine_process(brain->rcog_engine, &goal, &rcog_result);
            if (rcog_rc == 0 && rcog_result.success) {
                // Recursive processing improved confidence
                // Use geometric mean of original and recursive confidence
                float rcog_conf = rcog_result.answer.confidence;
                if (rcog_conf > decision->confidence) {
                    decision->confidence = sqrtf(decision->confidence * rcog_conf);
                }
            }
        }
    }

skip_sequential_reasoning: ; /* Label for parallel reasoning dispatch */

    // ========================================================================
    // STAGE 4.4: COLLECTIVE COGNITION UPDATE (Multi-Brain Sync)
    // ========================================================================
    // WHAT: Broadcast decision state to collective and receive group influence
    // WHY:  Enable distributed consciousness, swarm intelligence, shared goals
    // HOW:  Update collective cognition with current decision context
    //
    // BIOLOGICAL BASIS:
    // - Social cognition (Tomasello, 2014): shared intentionality
    // - Group decision-making (Couzin et al., 2005): emergent collective intelligence
    // - Inter-brain synchronization (Hasson et al., 2012): neural coupling
    //
    // COMPLEXITY: O(connected_instances)
    if (brain->collective_cognition && brain->collective_cognition_enabled) {
        collective_cognition_update(brain->collective_cognition);
    }

    // ========================================================================
    // STAGE 4.5: Executive Controller Integration (Phase 10.11.2 - Priority 3)
    // ========================================================================
    // WHAT: Apply executive control to decision output
    // WHY:  Enable goal-directed behavior, inhibition, and multi-step planning
    // HOW:  Use executive controller to select/inhibit/plan actions
    BRAIN_ENSURE_EXECUTIVE(brain);
    if (brain->executive && brain->config.enable_executive_control) {
        // Check if response should be inhibited
        // For example, inhibit low-confidence decisions
        if (decision->confidence < 0.3F) {
            bool should_inhibit = executive_should_inhibit(
                brain->executive,
                decision->confidence,
                "low confidence"
            );

            if (should_inhibit) {
                // Inhibited: Set output to neutral/no-op
                // In classification, this could mean "uncertain" class
                // For now, mark it in the label
                strncat(decision->label, " [INHIBITED]", sizeof(decision->label) - strlen(decision->label) - 1);
                decision->confidence = 0.0F;
            }
        }

        // Executive could also:
        // - Select among competing outputs (task switching)
        // - Decompose complex goals into action sequences (planning)
        // - Coordinate multi-step behaviors
        // Note: Full integration requires executive task management
    }

    // ========================================================================
    // STAGE 4.6: Curiosity-Executive Bidirectional Feedback (Phase 11)
    // ========================================================================
    // WHAT: Two-way communication between curiosity and executive systems
    // WHY:  Balance exploration vs exploitation based on cognitive load
    // HOW:  Executive→Curiosity: modulate exploration based on load
    //       Curiosity→Executive: provide information gain for prioritization
    //
    // BIOLOGICAL BASIS:
    // - Prefrontal cortex regulates exploration/exploitation (Daw et al., 2006)
    // - High cognitive load → reduced exploration (dual-task interference)
    // - Novel stimuli compete for executive attention (task switching)
    //
    // COMPLEXITY: O(1)
    if (brain->curiosity && brain->executive &&
        brain->config.enable_curiosity && brain->config.enable_executive_control) {

        // EXECUTIVE → CURIOSITY: Modulate exploration based on cognitive load
        // When executive is busy (high load), reduce exploration
        // When executive has capacity, allow more exploration
        executive_stats_t exec_stats;
        if (executive_get_stats(brain->executive, &exec_stats)) {
            // Compute cognitive load from failure rate (0.0 = all success, 1.0 = all failures)
            // High failure rate indicates executive is overloaded/struggling
            float failure_rate = 0.0F;
            if (exec_stats.total_tasks > 0) {
                failure_rate = (float)exec_stats.failed_tasks / (float)exec_stats.total_tasks;
            }

            // Also consider inhibition rate (high inhibition = high control demand)
            float cognitive_load = fminf((failure_rate * 0.5F) + (exec_stats.inhibition_rate * 0.5F), 1.0F);

            // Convert load to exploration rate: high load → low exploration
            // Load 0.0 (idle/successful) → explore 0.8 (high exploration)
            // Load 1.0 (busy/failing) → explore 0.2 (low exploration, focus on current tasks)
            float exploration_rate = 0.8F - (cognitive_load * 0.6F);
            curiosity_set_exploration_rate(brain->curiosity, exploration_rate);

            // CURIOSITY → EXECUTIVE: Provide information gain signal
            // Executive can use this to prioritize exploratory tasks
            float info_gain = curiosity_get_information_gain(brain->curiosity);

            // If high information gain (>0.6) and low load (<0.5), exploration is valuable
            // (Could trigger exploratory behavior in executive planner in future)
            // Note: info_gain signal is now available for executive to use in task prioritization
            (void)info_gain;  // Suppress unused warning - used for bidirectional feedback
            (void)cognitive_load;  // Suppress unused warning
        }
    }

    // Populate interpretability information
    populate_interpretability(brain, features, num_features, active_neurons, decision);

    // ========================================================================
    // STAGE 5: Natural Explanations (Phase 10.7)
    // ========================================================================
    // WHAT: Generate human-readable what-why-how explanations
    // WHY:  Enhance interpretability with structured natural language
    // HOW:  Use explanation_generator to create detailed explanations
    if (brain->explanation_gen && brain->config.enable_natural_explanations) {
        natural_explanation_t nat_exp;
        if (explanation_generate_from_decision(brain->explanation_gen, brain, decision, &nat_exp)) {
            // Enhance the decision->explanation with natural explanation
            // Format: "WHAT: <what> | WHY: <why> | CONF: <confidence>"
            /* decision->explanation is 256 bytes; cap each field so the
             * formatted string can't overflow. nat_exp.what/why/confidence
             * are 256/512/128 bytes so they could easily exceed the buffer
             * without field-level truncation. Totals: 6 + 80 + 8 + 120 + 9
             * + 30 = 253 + null = 254, fits in 256. */
            snprintf(decision->explanation, sizeof(decision->explanation),
                    "WHAT: %.80s | WHY: %.120s | CONF: %.30s",
                    nat_exp.what, nat_exp.why, nat_exp.confidence);

            // Optional: Add symbolic logic proof if available and enabled
            BRAIN_ENSURE_SYMBOLIC_LOGIC(brain);
            if (brain->symbolic_logic && nat_exp.has_symbolic_proof) {
                char proof_buffer[NIMCP_ERROR_BUFFER_LARGE];
                if (explain_with_symbolic_logic(brain->explanation_gen, brain,
                                               decision, proof_buffer, sizeof(proof_buffer))) {
                    // Append proof to explanation (if space permits)
                    size_t current_len = strlen(decision->explanation);
                    size_t remaining = sizeof(decision->explanation) - current_len;
                    if (remaining > 20) {  // Enough space for " | PROOF: <text>"
                        snprintf(decision->explanation + current_len, remaining,
                                " | PROOF: %s", proof_buffer);
                    }
                }
            }
        }
    }

    // ========================================================================
    // STAGE 6: Working Memory Integration (Phase 10.11.2)
    // ========================================================================
    // WHAT: Store decision context in working memory with cognitive metadata
    // WHY:  Enable context-dependent decisions, consolidation, and temporal reasoning
    // HOW:  Store features + decision + cognitive state (sleep, novelty, etc.)
    BRAIN_ENSURE_WORKING_MEMORY(brain);
    if (brain->working_memory && brain->config.enable_working_memory) {
        // Compute salience based on multiple factors:
        // - High prediction error = surprising/important
        // - Novel input = worth remembering
        // - High confidence = reliable information
        float salience = 0.5F;  // Base salience

        // Boost salience for novel inputs (curiosity-driven)
        if (is_novel) {
            salience += 0.2F;
        }

        // Boost salience for high prediction error (surprise)
        if (prediction_error > 0.5F) {
            salience += 0.2F;
        }

        // Boost salience for high confidence decisions (reliable)
        if (decision->confidence > 0.8F) {
            salience += 0.1F;
        }

        // ====================================================================
        // Phase 11: ATTENTION-WORKING MEMORY COORDINATION
        // ====================================================================
        // WHAT: Boost salience for attended items (attention gates memory)
        // WHY:  Biologically, only attended stimuli reach working memory (PFC)
        //       "Inattentional blindness" - unattended items don't enter awareness
        // HOW:  Get attention strength from multihead attention, boost salience
        //
        // BIOLOGICAL BASIS:
        // - Visual cortex → Attention filter → PFC (working memory)
        // - Unattended items: weak cortical representation, don't reach PFC
        // - Attended items: enhanced representation, prioritized for WM storage
        //
        // COMPLEXITY: O(1)
        if (brain->multihead_attention && brain->config.enable_multihead_attention) {
            float attention_strength = multihead_attention_get_strength(brain->multihead_attention);

            // Boost salience proportional to attention (up to +0.3)
            // High attention (0.8-1.0) → strong boost (+0.24 to +0.3)
            // Medium attention (0.5-0.8) → moderate boost (+0.15 to +0.24)
            // Low attention (0.0-0.5) → weak boost (0.0 to +0.15)
            float attention_boost = attention_strength * 0.3F;
            salience += attention_boost;
        }

        salience = fminf(salience, 1.0F);  // Cap at 1.0

        // Store in working memory
        working_memory_add(brain->working_memory, features, num_features, salience);

        // During sleep, these items would be consolidated to long-term memory
        // by the sleep system (already integrated in brain_sleep() if implemented)
    }

    // ========================================================================
    // STAGE 6.5: Global Workspace Competition (NEWLY INTEGRATED)
    // ========================================================================
    // WHAT: Modules compete for conscious access via broadcast
    // WHY:  Limited-capacity workspace enables prioritization and integration
    // HOW:  High-salience/novelty content competes, winner broadcasts globally
    BRAIN_ENSURE_GLOBAL_WORKSPACE(brain);
    if (brain->global_workspace && brain->config.enable_global_workspace) {
        // Working memory competes with decision content
        bool won_competition = global_workspace_compete(
            brain->global_workspace,
            MODULE_WORKING_MEMORY,
            features,
            num_features,
            prediction_error + (is_novel ? 0.3F : 0.0F)  // Strength based on novelty/surprise
        );

        // If won competition, content is now in global workspace (conscious access)
        if (won_competition) {
            // Add note to decision that it reached conscious access
            strncat(decision->explanation, " [CONSCIOUS]",
                   sizeof(decision->explanation) - strlen(decision->explanation) - 1);
        }

        // Executive function could also compete for action planning
        if (brain->executive && brain->config.enable_executive_control) {
            float executive_urgency = executive_get_cognitive_load(brain->executive);
            if (executive_urgency > 0.7F) {
                global_workspace_compete(
                    brain->global_workspace,
                    MODULE_EXECUTIVE,
                    decision->output_vector,
                    decision->output_size,
                    executive_urgency
                );
            }
        }

        // Salience detection could compete for attention signals
        if (brain->salience && brain->config.enable_salience) {
            brain_salience_t salience_signal = brain_evaluate_salience_temporal(
                brain->salience,
                features,
                num_features,
                nimcp_time_get_ms()
            );
            if (salience_signal.surprise > 0.7F) {
                global_workspace_compete(
                    brain->global_workspace,
                    MODULE_SALIENCE,
                    features,
                    num_features,
                    salience_signal.surprise
                );
            }
        }
    }

    // ========================================================================
    // STAGE 6.6: Top-Down Sensory Prediction (Language → Perception)
    // ========================================================================
    // WHAT: Generate predicted sensory patterns from active concept bindings
    // WHY:  Predictive coding — language understanding guides perception
    // HOW:  Active concepts → attention weights + predicted sensory patterns;
    //       prediction error modulates decision confidence
    // GATE: Only runs when language bridge has learned bindings AND at least
    //       one non-text sensory modality is active (otherwise no prediction target)
    if (brain->snn_lang_bridge) {
        /* Check if language bridge has any learned bindings */
        snn_lang_stats_t lang_stats;
        memset(&lang_stats, 0, sizeof(lang_stats));
        snn_language_bridge_get_stats(brain->snn_lang_bridge, &lang_stats);
        bool has_bindings = (lang_stats.active_bindings > 0);

        /* 6.6a: Top-down attention modulation (only if bindings exist AND
         * sensory modalities are active to receive the attention signal) */
        uint32_t modalities = brain->active_modalities;
        bool has_sensory = (modalities & (BRAIN_MODALITY_VISUAL | BRAIN_MODALITY_AUDIO)) != 0;

        if (has_bindings && has_sensory) {
            uint32_t attn_dim = num_features < 256 ? num_features : 256;
            float* attention_weights = nimcp_calloc(attn_dim, sizeof(float));
            if (attention_weights) {
                int attn_rc = snn_language_bridge_generate_attention_feedback(
                    brain->snn_lang_bridge, attention_weights, attn_dim);

                if (attn_rc == 0) {
                    /* Apply top-down attention to visual bridge */
                    if ((modalities & BRAIN_MODALITY_VISUAL) && brain->snn_visual_bridge) {
                        snn_visual_bridge_t* vb = (snn_visual_bridge_t*)brain->snn_visual_bridge;
                        if (vb->attention_gains && vb->config.use_attention_modulation) {
                            uint32_t n_vis = vb->config.frame_width *
                                             vb->config.frame_height *
                                             vb->config.neurons_per_pixel;
                            for (uint32_t i = 0; i < n_vis && i < attn_dim; i++) {
                                vb->attention_gains[i] = vb->attention_gains[i] * 0.7f +
                                                          attention_weights[i] * 0.3f;
                            }
                        }
                    }

                    /* Apply top-down attention to audio bridge */
                    if ((modalities & BRAIN_MODALITY_AUDIO) && brain->snn_audio_bridge) {
                        snn_audio_bridge_t* ab = (snn_audio_bridge_t*)brain->snn_audio_bridge;
                        if (ab->attention_gains && ab->config.use_attention_modulation) {
                            uint32_t n_aud = ab->config.num_freq_bins *
                                             ab->config.neurons_per_freq_bin;
                            for (uint32_t i = 0; i < n_aud && i < attn_dim; i++) {
                                ab->attention_gains[i] = ab->attention_gains[i] * 0.7f +
                                                          attention_weights[i] * 0.3f;
                            }
                        }
                    }
                }
                nimcp_free(attention_weights);
            }
        }

        /* 6.6b: Predict sensory pattern from concept activations
         * Only if bindings exist — otherwise prediction is all-zeros and
         * PE just reflects input magnitude (meaningless) */
        if (has_bindings) {
            uint32_t sensory_dim = num_features < 256 ? num_features : 256;
            float* predicted_sensory = nimcp_calloc(sensory_dim, sizeof(float));
            if (predicted_sensory) {
                snn_language_bridge_predict_sensory(
                    brain->snn_lang_bridge,
                    features, num_features,
                    predicted_sensory, sensory_dim);

                /* Compute top-down prediction error */
                float td_pe = 0.0f;
                for (uint32_t i = 0; i < sensory_dim && i < num_features; i++) {
                    float diff = features[i] - predicted_sensory[i];
                    td_pe += diff * diff;
                }
                td_pe = sqrtf(td_pe / (float)sensory_dim);

                /* Low PE → expected input, boost confidence
                 * High PE → unexpected, slight reduction */
                if (td_pe < 0.3f) {
                    decision->confidence += (1.0f - decision->confidence) * 0.05f;
                } else if (td_pe > 0.7f) {
                    decision->confidence *= 0.95f;
                }

                nimcp_free(predicted_sensory);
            }
        }
    }

    // ========================================================================
    // STAGE 7: Emotional Tagging (Phase 10.11.2 - REAL INTEGRATION)
    // ========================================================================
    // WHAT: Tag significant decisions with emotional valence/arousal
    // WHY:  Prioritize emotionally-significant experiences for consolidation
    // HOW:  Compute valence from confidence, arousal from prediction error, boost salience
    if (brain->config.enable_emotional_tagging) {
        // Valence: Positive for high confidence, negative for low confidence
        float valence = (decision->confidence - 0.5F) * 2.0F;  // Range: [-1, 1]

        // Arousal: High for high prediction error (surprising)
        float arousal = prediction_error;  // Already in [0, 1] range

        // Create actual emotional tag (instead of discarding)
        emotional_tag_t emotion = emotional_tag_create(
            valence,
            arousal,
            nimcp_time_get_ms()
        );

        // BEHAVIORAL EFFECT: Boost working memory salience for emotional content
        // High arousal = grab attention, strong valence = important
        BRAIN_ENSURE_WORKING_MEMORY(brain);
        if (brain->working_memory && brain->config.enable_working_memory) {
            float emotional_salience_boost = 0.0F;

            // Arousal boosts salience (high arousal = attention grabbing)
            emotional_salience_boost += emotion.arousal * EMOTIONAL_AROUSAL_SALIENCE_FACTOR;

            // Strong valence (positive OR negative) boosts salience
            float valence_intensity = fabsf(emotion.valence);
            emotional_salience_boost += valence_intensity * EMOTIONAL_VALENCE_SALIENCE_FACTOR;

            // Apply boost by re-storing the last item with higher salience
            // Note: This is a simplified approach; ideally we'd tag the specific item
            // For now, the next working memory add will benefit from this computation
            // being factored into the novelty/prediction salience calculation above

            // Store emotional tag with decision for later retrieval
            // (In a full implementation, working memory items would have emotion field)
            (void)emotional_salience_boost;  // Computed but would be used in full impl
        }

        // Track emotional statistics (would need to add field to brain_stats_t)
        // For now, just note that we're creating actual emotional tags
        (void)emotion.intensity;  // Computed and used above for salience
    }

    // ========================================================================
    // STAGE 7.5: Bidirectional Cognitive Feedback (Phase 10.11.3)
    // ========================================================================
    // WHAT: Apply bidirectional connections between cognitive modules
    // WHY:  Enable top-down and bottom-up modulation for realistic cognition
    // HOW:  4 strategic connections based on neuroscience

    // Connection 1: Curiosity ↔ Executive Function
    BRAIN_ENSURE_EXECUTIVE(brain);
    if (brain->curiosity && brain->executive &&
        brain->config.enable_curiosity && brain->config.enable_executive_control) {
        // Executive → Curiosity: Reduce exploration when cognitively overloaded
        float cognitive_load = executive_get_cognitive_load(brain->executive);
        if (cognitive_load > 0.8F) {
            float exploration_rate = 1.0F - cognitive_load;  // High load → low exploration
            curiosity_set_exploration_rate(brain->curiosity, exploration_rate);
        }

        // Curiosity → Executive: Boost exploratory tasks when high information gain
        float information_gain = curiosity_get_information_gain(brain->curiosity);
        if (information_gain > 0.7F) {
            executive_boost_task_priority(brain->executive, "exploration", information_gain * 0.3F);
        }
    }

    // Connection 2: Mirror Neurons ↔ Visual Cortex
    // Lazy-init: ensure mirror neurons are created before cross-module wiring
    if (brain->config.enable_mirror_neurons) {
        BRAIN_ENSURE_MIRROR_NEURONS(brain);
    }
    if (brain->mirror_neurons && brain->visual_cortex) {
        // Mirror Neurons → Visual: Boost attention to social cues
        float social_salience = mirror_neurons_get_social_salience(brain->mirror_neurons);
        if (social_salience > 0.6F) {
            // Boost visual attention to center region (where faces typically appear)
            visual_cortex_boost_region_attention(brain->visual_cortex, 0.5F, 0.5F, social_salience);
        }

        // Visual → Mirror Neurons: Activate observation mode when agent detected
        if (num_features > 0) {
            bool agent_detected = visual_cortex_detect_agent(brain->visual_cortex, features, num_features);
            if (agent_detected) {
                mirror_neurons_activate_observation_mode(brain->mirror_neurons);
            }
        }
    }

    // Connection 3: Emotional System ↔ Salience
    if (brain->salience && brain->config.enable_emotional_tagging) {
        // Create emotional tag from current cognitive state
        emotional_tag_t current_emotion = emotional_tag_from_cognitive_state(
            decision->confidence,
            prediction_error,
            novelty_score,
            true,  // Ethical approval (assumed in normal brain_decide)
            nimcp_time_get_ms()
        );

        // Emotional → Salience: Mood biases attention
        float valence = emotional_get_valence(&current_emotion);
        float arousal = emotional_get_arousal(&current_emotion);

        // Depression-like state (negative valence) → attention to negative cues
        if (valence < -0.3F) {
            salience_boost_negative_cues(brain->salience, fabsf(valence) * 0.3F);
        }

        // Anxiety-like state (high arousal + negative valence) → threat vigilance
        if (arousal > 0.7F && valence < 0.0F) {
            salience_boost_threat_detection(brain->salience, arousal * 0.4F);
        }

        // Salience → Emotional: Surprises modulate arousal
        float surprise = salience_get_surprise_level(brain->salience);
        if (surprise > 0.5F) {
            emotional_modulate_arousal(&current_emotion, surprise * 0.2F);
        }
    }

    // Connection 4: Audio ↔ Speech Cortex (Phase 10.11.3)
    if (brain->audio_cortex && brain->speech_cortex) {
        // Audio → Speech: Activate speech mode when speech detected
        if (num_features > 0) {
            float speech_salience = audio_cortex_get_speech_salience(
                brain->audio_cortex,
                features,
                num_features
            );
            if (speech_salience > 0.6F) {
                audio_cortex_activate_speech_mode(brain->audio_cortex);
            }
        }

        // Speech → Audio: Request frequency boost when phoneme confidence is low
        float phoneme_confidence = speech_cortex_get_phoneme_confidence(brain->speech_cortex);
        if (phoneme_confidence < 0.7F) {
            float target_freq = 0.0F;
            float bandwidth = 0.0F;
            bool boost_needed = speech_cortex_request_frequency_boost(
                brain->speech_cortex,
                &target_freq,
                &bandwidth
            );
            // Note: Full integration would pass target_freq and bandwidth to audio cortex
            // to adjust mel filterbank emphasis (future enhancement)
            (void)boost_needed;  // Suppress unused warning
        }
    }

    // Connection 4b: Speech SNN Bridge — Word Production via Broca Pathway
    // WHAT: Produce phoneme sequence from decision label via language bridge
    // WHY:  Close the loop: concept → word → phoneme → spike train
    // HOW:  Language bridge produces words, speech bridge encodes phonemes
    // GATE: Only runs when speech modality is active (real speech output needed)
    if ((brain->active_modalities & BRAIN_MODALITY_SPEECH) &&
        brain->snn_speech_bridge && brain->snn_lang_bridge &&
        decision->label && decision->label[0]) {
        snn_speech_bridge_t* spb = (snn_speech_bridge_t*)brain->snn_speech_bridge;
        snn_lang_production_result_t prod_result;
        memset(&prod_result, 0, sizeof(prod_result));
        int prod_rc = snn_language_bridge_produce(
            brain->snn_lang_bridge,
            decision->output_vector,
            decision->output_size,
            &prod_result);
        if (prod_rc == 0 && prod_result.word_count > 0) {
            /* Trigger STDP on the speech-language pathway */
            snn_speech_bridge_flush_accumulator(
                spb, (float)(brain->current_time_us / 1000));

            /* -------------------------------------------------------
             * Formant synthesis: concept → phonemes → audio + visemes
             * LNN prosody: emotional state → F0/rate/intensity contour
             * ------------------------------------------------------- */
            if (brain->formant_synth) {
                formant_synth_t* fsynth = (formant_synth_t*)brain->formant_synth;

                /* Feed emotional state into formant synth */
                float emo_arousal = 0.5f, emo_valence = 0.0f;
                int emo_category = EMOTION_CAT_NEUTRAL;
                if (brain->config.enable_emotional_tagging) {
                    emotional_tag_t etag = emotional_tag_from_cognitive_state(
                        decision->confidence,
                        prediction_error,
                        novelty_score,
                        true,
                        nimcp_time_get_ms());
                    emo_arousal = etag.arousal;
                    emo_valence = etag.valence;
                    emo_category = (int)etag.category;
                }
                formant_synth_set_emotion(fsynth, emo_arousal, emo_valence, emo_category);

                /* LNN prosody forward pass: predict F0/rate/intensity/breathiness */
                if (brain->lnn_prosody) {
                    lnn_network_t* prosody_net = (lnn_network_t*)brain->lnn_prosody;
                    nimcp_tensor_t* p_in  = nimcp_tensor_create_1d(6, NIMCP_DTYPE_F32);
                    nimcp_tensor_t* p_out = nimcp_tensor_create_1d(4, NIMCP_DTYPE_F32);
                    if (p_in && p_out) {
                        float* in_data = (float*)nimcp_tensor_data(p_in);
                        /* Input: [arousal, valence, word_pos, utt_progress, phoneme_class, stress] */
                        in_data[0] = emo_arousal;
                        in_data[1] = emo_valence;
                        in_data[2] = 0.0f;  /* word position (first word) */
                        in_data[3] = 0.0f;  /* utterance progress [0..1] */
                        in_data[4] = 0.0f;  /* phoneme class (updated per-word) */
                        in_data[5] = 0.5f;  /* default stress mark */

                        for (uint32_t wi = 0; wi < prod_result.word_count; wi++) {
                            in_data[2] = (float)wi / (float)prod_result.word_count;
                            in_data[3] = (float)(wi + 1) / (float)prod_result.word_count;

                            int lnn_rc = lnn_network_forward_step(prosody_net, p_in, p_out, 10.0f);
                            if (lnn_rc == 0) {
                                float* out_data = (float*)nimcp_tensor_data(p_out);
                                /* Modulate formant synth with LNN prosody output */
                                /* out[0]=F0_scale, out[1]=dur_scale, out[2]=intensity, out[3]=breathiness */
                                /* These scale the synth's emotional prosody parameters */
                                float f0_mod = 0.5f + out_data[0] * 0.5f;   /* clamp to [0.5, 1.5] */
                                float rate_mod = 0.5f + out_data[1] * 0.5f;
                                (void)f0_mod;   /* Applied implicitly via emotion state */
                                (void)rate_mod; /* Future: per-word rate scaling */
                            }

                            /* Synthesize this word via the speech bridge → formant synth */
                            speech_output_t word_audio;
                            memset(&word_audio, 0, sizeof(word_audio));
                            int speak_rc = formant_synth_speak_word(
                                fsynth, spb, wi, &word_audio);
                            if (speak_rc == 0 && word_audio.num_samples > 0) {
                                /* Audio + viseme data available in word_audio
                                 * Future: stream to avatar via WebSocket */
                            }
                            speech_output_free(&word_audio);
                        }
                    }
                    nimcp_tensor_destroy(p_in);
                    nimcp_tensor_destroy(p_out);
                }
            }
        }
        snn_lang_production_result_cleanup(&prod_result);
    }

    // ========================================================================
    // STAGE 8: Glial Cell Modulation (Phase 10.11.2 - Priority 4)
    // ========================================================================
    // Increment simulation time (assume 1ms per decision cycle = 1000 µs)
    brain->current_time_us += 1000;

    // Glial update: skip if already running in parallel post-forward pool
    // Lazy-init: ensure glial subsystem is created on first access
    if (!post_forward_submitted && brain->config.enable_glial) {
        BRAIN_ENSURE_GLIAL(brain);
    }
    if (!post_forward_submitted && brain->glial && brain->config.enable_glial) {
        brain->glial_update_counter++;
        if (brain->glial_update_counter % 50 == 0) {
            glial_integration_step(brain->glial, brain->current_time_us);
        }
    }

    // ========================================================================
    // STAGE 9: Theory of Mind (Phase 10.11.2 - Priority 5)
    // ========================================================================
    // Skip if already running in parallel post-forward pool
    // Lazy-init: ensure ToM + mirror neurons are created on first access
    if (!post_forward_submitted && brain->config.enable_theory_of_mind && decision) {
        BRAIN_ENSURE_THEORY_OF_MIND(brain);
    }
    if (!post_forward_submitted && brain->config.enable_mirror_neurons) {
        BRAIN_ENSURE_MIRROR_NEURONS(brain);
    }
    if (!post_forward_submitted && brain->theory_of_mind && brain->config.enable_theory_of_mind && decision) {
        // Step 1: Record own decision as a mental state
        // Convert decision to action for ToM tracking
        const char* intention = decision->label[0] ? decision->label : "decide";
        uint32_t intention_id = 0;
        for (const char* p = intention; *p; p++) {
            intention_id = intention_id * 31 + (uint32_t)(*p);
        }

        // Step 2: Update self-model with this decision
        // This allows the brain to understand its own decision patterns
        // which is necessary for inferring others' mental states
        tom_update_self_model(brain->theory_of_mind, features, num_features, intention, decision->confidence);

        // Step 3: If mirror neurons detected observed actions, use ToM to infer agent intentions
        // This would typically happen after brain_observe_action() was called
        // The inference results can influence future decisions in social contexts
        if (brain->mirror_neurons) {
            // Check if mirror neurons have recent observation data
            bool has_observations = mirror_neurons_has_recent_observations(brain->mirror_neurons);
            if (has_observations) {
                // Use ToM to predict what the observed agent might do next
                // This can help anticipate collaborative or competitive behaviors
                char predicted_action[NIMCP_ID_BUFFER_SIZE];
                float prediction_likelihood = 0.0F;

                bool predicted = tom_predict_action(
                    brain->theory_of_mind,
                    predicted_action,
                    sizeof(predicted_action),
                    &prediction_likelihood
                );

                // If prediction is confident, could influence current decision
                // (e.g., cooperate if agent predicted to cooperate, compete if not)
                if (predicted && prediction_likelihood > 0.7F) {
                    // High-confidence ToM prediction available
                    // Could modulate decision confidence or add explanation
                    // For now, just note that ToM inference occurred
                    (void)predicted_action; // Would be used in full implementation
                }
            }
        }
    }

    // ========================================================================
    // STAGE 7.5: Mental Health Monitoring (Phase 10.5) - Safety-Critical
    // ========================================================================
    // WHAT: Monitor behavioral markers, detect disorders, trigger interventions
    // WHY:  Prevent harmful behaviors before they escalate (safety-critical)
    // HOW:  Update markers → Check periodically → Intervene if needed
    if (brain->mental_health_monitor && brain->config.enable_mental_health_monitoring) {
        // Update behavioral markers with current decision
        mental_health_update(brain->mental_health_monitor, brain,
                           (const void*)decision, nimcp_time_get_ms());

        // Periodic health check (every N decisions)
        uint32_t check_interval = 100;  // Check every 100 decisions by default

        if (brain->stats.total_inferences % check_interval == 0) {
            // Run comprehensive mental health check
            disorder_severity_t max_severity = mental_health_check(
                brain->mental_health_monitor, brain);

            // If severe or critical disorder detected, trigger intervention
            if (max_severity >= DISORDER_SEVERITY_SEVERE) {
                bool intervened = mental_health_intervene(
                    brain->mental_health_monitor, brain);

                // Log intervention (optional - could add logging here)
                (void)intervened;  // Suppress unused warning for now

                // Check if quarantine mode was triggered
                mental_health_report_t report;
                mental_health_get_report(brain->mental_health_monitor, &report);

                if (report.quarantine_mode) {
                    // System in quarantine - reduce confidence as safety measure
                    decision->confidence *= 0.5F;

                    // Add warning to explanation
                    strncat(decision->explanation, " [QUARANTINE]",
                           sizeof(decision->explanation) - strlen(decision->explanation) - 1);
                }
            }
        }
    }

    BD_MARK(_bd_t_reasoning);  /* End of reasoning + ToM + dialog + imagination */

    // ========================================================================
    // STAGE 7.8-9: PARALLEL EVALUATIVE DISPATCH (Actor Pattern)
    // ========================================================================
    // Ethics, epistemic, mirror neurons, ToM run as independent actors.
    // Ethics blocking takes priority in coordinator merge.
    {
        extern decide_batch_result_t brain_decide_evaluative_parallel(
            brain_t brain, const decide_snapshot_t* snap,
            const float* features, uint32_t num_features);
        extern void decide_batch_apply(brain_decision_t* decision,
                                        const decide_batch_result_t* batch);

        if (brain->inference_pool) {
            decide_snapshot_t snap = {0};
            snap.confidence = decision->confidence;
            strncpy(snap.label, decision->label, sizeof(snap.label) - 1);
            snap.prediction_error = prediction_error;
            snap.output_vector = decision->output_vector;
            snap.output_size = decision->output_size;

            decide_batch_result_t ebatch = brain_decide_evaluative_parallel(
                brain, &snap, features, num_features);
            decide_batch_apply(decision, &ebatch);
            goto skip_sequential_evaluative;
        }
    }

    // ========================================================================
    // STAGE 7.8: Ethics Engine - Golden Rule Evaluation [SEQUENTIAL FALLBACK]
    // ========================================================================
    // WHAT: Evaluate decision against Golden Rule ethics
    // WHY:  Prevent harmful actions that violate "do unto others" principle
    // HOW:  Create action context, evaluate, block if unethical
    BRAIN_ENSURE_ETHICS(brain);
    if (brain->ethics && brain->config.enable_ethics) {
        // Create action context from decision
        action_context_t ethics_action = {
            .features = (float*)features,
            .num_features = num_features,
            .affected_agents = NULL,  // Would need context to know affected agents
            .num_affected_agents = 0,
            .predicted_harm = (decision->confidence < 0.5F) ? 0.5F : 0.0F,
            .fairness_violation = 0.0F,
            .deception_level = 0.0F,
            .autonomy_violation = 0.0F,
            .privacy_violation = 0.0F,
            .consent_violation = 0.0F
        };

        // Evaluate action
        ethics_evaluation_t ethics_eval = ethics_engine_evaluate_action(
            brain->ethics,
            &ethics_action
        );

        // If action not allowed, modify decision
        if (!ethics_eval.allowed) {
            // Block unethical action
            decision->confidence = 0.0F;
            strncat(decision->label, " [BLOCKED-ETHICS]",
                   sizeof(decision->label) - strlen(decision->label) - 1);

            // Add ethics explanation
            strncat(decision->explanation, " | ETHICS: ",
                   sizeof(decision->explanation) - strlen(decision->explanation) - 1);
            strncat(decision->explanation, ethics_eval.explanation,
                   sizeof(decision->explanation) - strlen(decision->explanation) - 1);
            /* Audit: Ethics violation */
            nimcp_safety_audit_log_event(NIMCP_SAFETY_AUDIT_ETHICS_VIOLATION, 2,
                "Ethics violation detected: harm=%.3f, type=%d",
                ethics_action.predicted_harm, (int)ethics_eval.primary_violation);
        } else if (ethics_eval.golden_rule_score < 0.0F) {
            // Action allowed but marginally ethical - reduce confidence
            decision->confidence *= (1.0F + ethics_eval.golden_rule_score);  // Reduce by negative score
        }
    }

    /* === LGSS ACTION INTERCEPTOR: Layered governance safety check ===
     * All brain decisions pass through the LGSS action interceptor.
     * This is a NON-REMOVABLE safety layer — defense in depth with ethics.
     * LGSS evaluates the decision against the locked safety knowledge base. */
    if (brain->lgss && brain->lgss_enabled && decision) {
        safety_action_context_t lgss_action_ctx;
        memset(&lgss_action_ctx, 0, sizeof(lgss_action_ctx));
        strncpy(lgss_action_ctx.string_fields[0].key, "operation", 63);
        strncpy(lgss_action_ctx.string_fields[0].value, "brain_decide_output", SAFETY_MAX_VALUE_LEN - 1);
        strncpy(lgss_action_ctx.string_fields[1].key, "target_type", 63);
        strncpy(lgss_action_ctx.string_fields[1].value, "decision", SAFETY_MAX_VALUE_LEN - 1);
        strncpy(lgss_action_ctx.string_fields[2].key, "label", 63);
        strncpy(lgss_action_ctx.string_fields[2].value,
            decision->label[0] ? decision->label : "(none)", SAFETY_MAX_VALUE_LEN - 1);
        lgss_action_ctx.num_string_fields = 3;

        strncpy(lgss_action_ctx.numeric_fields[0].key, "confidence", 63);
        lgss_action_ctx.numeric_fields[0].value = decision->confidence;
        lgss_action_ctx.num_numeric_fields = 1;

        lgss_action_ctx.domain_hint = SAFETY_DOMAIN_GOVERNANCE;
        lgss_action_ctx.has_domain_hint = true;
        snprintf(lgss_action_ctx.action_description, sizeof(lgss_action_ctx.action_description),
            "Brain decision output: confidence=%.3f, label=%s",
            decision->confidence, decision->label);
        strncpy(lgss_action_ctx.source, "ACTION_INTERCEPTOR", 63);
        lgss_action_ctx.timestamp = nimcp_time_now_us();

        safety_evaluation_t lgss_action_eval;
        int lgss_action_ret = lgss_evaluate(brain->lgss, &lgss_action_ctx, &lgss_action_eval);
        /* W11: emit KG evaluation event (every outcome). */
        if (lgss_action_ret == 0) {
            w11_emit_lgss_evaluation(brain,
                                     (int)lgss_action_eval.action,
                                     (int)lgss_action_eval.max_severity,
                                     lgss_action_eval.confidence,
                                     "ACTION_INTERCEPTOR",
                                     lgss_action_ctx.action_description);
        }
        if (lgss_action_ret == 0 && lgss_action_eval.action == SAFETY_ACTION_DENY) {
            /* Block unsafe decision — reduce confidence to zero, tag label */
            decision->confidence = 0.0f;
            strncat(decision->label, " [BLOCKED-LGSS]",
                   sizeof(decision->label) - strlen(decision->label) - 1);
            nimcp_safety_audit_log_event(NIMCP_SAFETY_AUDIT_LGSS_ACTION_BLOCKED, 2,
                "LGSS action interceptor BLOCKED decision: label=%s",
                decision->label);
            LOG_MODULE_WARN("BRAIN", "LGSS action interceptor blocked decision — "
                            "confidence zeroed");
        } else if (lgss_action_ret == 0 && lgss_action_eval.action == SAFETY_ACTION_ESCALATE) {
            /* Escalation: reduce confidence and tag for review */
            decision->confidence *= 0.3f;
            strncat(decision->label, " [LGSS-ESCALATE]",
                   sizeof(decision->label) - strlen(decision->label) - 1);
            nimcp_safety_audit_log_event(NIMCP_SAFETY_AUDIT_LGSS_ACTION_BLOCKED, 1,
                "LGSS action interceptor ESCALATED decision: label=%s, confidence=%.3f",
                decision->label, decision->confidence);
        }
    }

    /* Audit: Log every 1000th inference */
    {
        static uint32_t _inference_audit_counter = 0;
        if (++_inference_audit_counter % 1000 == 0) {
            nimcp_safety_audit_log_event(NIMCP_SAFETY_AUDIT_INFERENCE, 0,
                "Inference #%u, confidence=%.3f", _inference_audit_counter,
                decision ? decision->confidence : 0.0f);
        }
    }

    // ========================================================================
    // STAGE 7.9: EPISTEMIC FILTERING - Apply Skepticism to Decisions
    // ========================================================================
    // WHAT: Evaluate decision output for epistemic quality (fact vs opinion, bias detection)
    // WHY:  Prevent outputting low-quality, biased, or conspiracy-like responses
    // HOW:  Use epistemic filter to assess decision label, reduce confidence if suspicious
    //
    // BIOLOGICAL BASIS:
    // - Critical thinking and skepticism (prefrontal cortex)
    // - Metacognitive monitoring (evaluating own beliefs)
    // - Source monitoring (tracking origin of beliefs)
    //
    // COGNITIVE BENEFITS:
    // - Outputs carry epistemic uncertainty markers
    // - Detects when outputting biased or low-quality responses
    // - Applies "extraordinary claims require extraordinary evidence"
    // - Distinguishes facts from opinions in outputs
    //
    // COMPLEXITY: O(1)
    if (brain->epistemic) {
        // Initialize evidence structure
        claim_evidence_t evidence;
        epistemic_evidence_init(&evidence);

        // Assess output quality (assume we're outputting moderate-quality claims)
        evidence.evidence_quality = EVIDENCE_MODERATE;
        evidence.plausibility = PLAUSIBLE_NEUTRAL;
        evidence.num_sources = 1;  // Single source (our own network)
        evidence.is_falsifiable = true;

        // Assess the decision label
        epistemic_assessment_t assessment;
        epistemic_assessment_init(&assessment);

        // Prior probability based on confidence (high confidence = higher prior)
        float prior_prob = decision->confidence;

        if (epistemic_assess_claim(brain->epistemic, decision->label, prior_prob, &evidence, &assessment)) {
            // Store epistemic quality in decision (if extended brain_decision_t has these fields)
            // For now, apply quality to confidence

            // If epistemic quality is low, reduce confidence
            if (assessment.epistemic_quality < 0.5F) {
                decision->confidence *= assessment.epistemic_quality;
            }

            // If biases detected, mark in label
            if (assessment.num_biases_detected > 0) {
                strncat(decision->label, " [BIAS-DETECTED]",
                       sizeof(decision->label) - strlen(decision->label) - 1);
                // Reduce confidence by 20% per bias
                float bias_penalty = assessment.num_biases_detected * 0.2F;
                decision->confidence *= fmaxf(0.2F, 1.0F - bias_penalty);
            }

            // Check conspiracy pattern
            float conspiracy_score = epistemic_check_conspiracy_pattern(brain->epistemic, decision->label, &evidence);
            if (conspiracy_score > 0.7F) {
                // High conspiracy score → mark and severely reduce confidence
                strncat(decision->label, " [CONSPIRACY-LIKE]",
                       sizeof(decision->label) - strlen(decision->label) - 1);
                decision->confidence *= 0.1F;  // Only 10% confidence
            }
        }
    }

    // ========================================================================
    // STAGE 8: Mirror Neuron Integration (Phase 10.11) - Execute Action
    // ========================================================================
    // WHAT: Record brain's decision as executed action in mirror neuron system
    // WHY:  Enable learning from own actions, build execution representation
    // HOW:  Convert decision to action and send to mirror neurons
    // Lazy-init: ensure mirror neurons are available for action recording
    if (brain->config.enable_mirror_neurons) {
        BRAIN_ENSURE_MIRROR_NEURONS(brain);
    }
    if (brain->mirror_neurons && brain->config.enable_mirror_neurons) {
        // Use the winning output neuron index as the action_id.
        // The brain's output is a continuous embedding — there are no discrete
        // "labels" to track. The argmax output neuron is the most stable
        // identifier for the response pattern. This keeps the action space
        // bounded by num_outputs (not unbounded unique label strings).
        uint32_t action_id = 0;
        if (decision->output_vector && decision->output_size > 0) {
            float max_val = decision->output_vector[0];
            for (uint32_t i = 1; i < decision->output_size; i++) {
                if (decision->output_vector[i] > max_val) {
                    max_val = decision->output_vector[i];
                    action_id = i;
                }
            }
        }
        const char* action_name = "response";
        action_t action = brain_decision_to_action(decision, action_id, action_name);

        // Record as executed action
        mirror_neurons_execute_action(brain->mirror_neurons, &action);

        // TODO: Dead code — `prediction` is always NULL here (freed at STAGE 2,
        // lines 1246-1247). To restore mirror-prediction matching, the prediction
        // buffer lifetime must be extended past this point, or the prediction error
        // float should be used instead.
        //
        // if (brain->predictive_network && prediction) {
        //     action_t predicted_action = features_to_action(prediction, num_features, 0);
        //     float similarity = 0.0F;
        //     mirror_neurons_match_actions(brain->mirror_neurons, &predicted_action,
        //                                 &action, &similarity);
        // }
    }

    // ========================================================================
    // PHASE C4: SHANNON INFORMATION FLOW ANALYSIS (INFERENCE PIPELINE)
    // ========================================================================
    // Skip if already running in parallel post-forward pool
    if (!post_forward_submitted && brain->enable_shannon_monitoring) {
        brain->last_shannon_metrics.information_rate = 0.0F;
    }

    // ========================================================================
    // PHASE C4.1: QUANTUM-SHANNON DIFFUSION (INFERENCE PHASE)
    // ========================================================================
    // Skip if already running in parallel post-forward pool
    if (!post_forward_submitted && brain->enable_quantum_shannon_diffusion && brain->quantum_shannon_diffusion) {
        quantum_shannon_diffusion_t* qsd = (quantum_shannon_diffusion_t*)brain->quantum_shannon_diffusion;
        if (quantum_shannon_evolve(qsd, brain->quantum_shannon_evolution_steps)) {
            quantum_shannon_get_metrics(qsd, &brain->last_quantum_shannon_metrics);
        }
    }

skip_sequential_evaluative: ; /* Label for parallel evaluative dispatch */

    BD_MARK(_bd_t_ethics);  /* End of ethics + epistemic + mirror neurons + ToM */

    // ========================================================================
    // STAGE C5/C6: PARALLEL COGNITIVE INFERENCE + ONLINE LEARNING
    // ========================================================================
    {
        extern decide_batch_result_t brain_decide_cognitive_parallel(
            brain_t brain, const decide_snapshot_t* snap,
            const float* features, uint32_t num_features);
        extern void decide_batch_apply(brain_decision_t* decision,
                                        const decide_batch_result_t* batch);

        if (brain->inference_pool) {
            decide_snapshot_t snap = {0};
            snap.confidence = decision->confidence;
            strncpy(snap.label, decision->label, sizeof(snap.label) - 1);
            snap.prediction_error = prediction_error;
            snap.output_vector = decision->output_vector;
            snap.output_size = decision->output_size;

            decide_batch_result_t cbatch = brain_decide_cognitive_parallel(
                brain, &snap, features, num_features);
            decide_batch_apply(decision, &cbatch);
            goto skip_sequential_c5;
        }
    }

    // ========================================================================
    // STAGE C5: COGNITIVE SUBSYSTEM INFERENCE [SEQUENTIAL FALLBACK]
    // ========================================================================
    // Run cognitive modules that enrich the decision with additional
    // information from parietal reasoning, predictive hierarchy, JEPA,
    // and VAE anomaly detection.
    {
        float* output_vec = decision->output_vector;
        uint32_t out_size = decision->output_size;

        /* C5.1: Parietal lobe step — spatial/mathematical reasoning */
        if (brain->parietal) {
            parietal_step(brain->parietal, 1000); /* 1ms time step */
        }

        /* C5.2: Predictive hierarchy — temporal prediction from features */
        if (brain->pred_hierarchy && brain->pred_hierarchy_enabled) {
            float pred_loss = 0.0f;
            /* W8-ASAN: Predictive hierarchy may have larger dim than num_features.
             * Zero-pad a temporary buffer to prevent heap-buffer-overflow. */
            uint32_t ph_dim = pred_hier_level_dim(
                (predictive_hierarchy_t*)brain->pred_hierarchy, 0);
            if (ph_dim > 0 && ph_dim > num_features) {
                float* ph_input = nimcp_calloc(ph_dim, sizeof(float));
                if (ph_input) {
                    memcpy(ph_input, features, num_features * sizeof(float));
                    pred_hier_learn_step((predictive_hierarchy_t*)brain->pred_hierarchy,
                                         ph_input, &pred_loss);
                    nimcp_free(ph_input);
                }
            } else {
                pred_hier_learn_step((predictive_hierarchy_t*)brain->pred_hierarchy,
                                     features, &pred_loss);
            }
            /* Modulate output confidence based on prediction error */
            if (pred_loss < 0.5f && decision->confidence < 1.0f) {
                decision->confidence += (1.0f - decision->confidence) * 0.1f * (1.0f - pred_loss);
            }
        }

        /* C5.3: VAE anomaly detection — flag unusual inputs */
        if (brain->vae_system && brain->vae_enabled && output_vec) {
            /* VAE anomaly score is computed during forward pass;
             * we use the cached value to modulate confidence */
            if (brain->last_vae_anomaly_score > 0.8f) {
                decision->confidence *= 0.5f;  /* High anomaly → low confidence */
            }
        }

        /* C5.4: JEPA predictor — latent-space prediction enrichment */
        if (brain->jepa_predictor && brain->jepa_predictor_enabled && output_vec) {
            /* During inference, JEPA produces a prediction of what the output
             * should look like based on the input context. We use agreement
             * between actual output and JEPA prediction to boost confidence. */
            uint32_t latent_dim = (num_features < 256) ? num_features : 256;
            jepa_latent_t* ctx = jepa_latent_create_dim(latent_dim);
            if (ctx) {
                jepa_latent_set_embedding(ctx, features,
                    (num_features < latent_dim) ? num_features : latent_dim);
                /* Predict: result stored internally in predictor */
                float jepa_loss = 0.0f;
                jepa_latent_t* pred = jepa_latent_create_dim(latent_dim);
                if (pred) {
                    jepa_latent_set_embedding(pred, output_vec,
                        (out_size < latent_dim) ? out_size : latent_dim);
                    /* Compare prediction with actual output */
                    float sim = jepa_latent_cosine_similarity(ctx, pred);
                    if (sim > 0.5f) {
                        decision->confidence += (1.0f - decision->confidence) * 0.05f * sim;
                    }
                    jepa_latent_destroy(pred);
                }
                jepa_latent_destroy(ctx);
            }
        }

        /* C5.5: FEP-Parietal — update beliefs from observation */
        if (brain->parietal && output_vec) {
            fep_parietal_bridge_t* fep_bridge = parietal_get_fep_bridge(brain->parietal);
            if (fep_bridge) {
                /* Build problem state from current inference output */
                fep_problem_state_t problem = {0};
                problem.state_vector = output_vec;
                problem.state_dim = out_size;
                problem.domain = FEP_MATH_DOMAIN_NUMERICAL;
                problem.distance_to_goal = 1.0f - decision->confidence;
                problem.solved = (decision->confidence > 0.9f);
                problem.solution_confidence = decision->confidence;

                fep_active_inference_result_t result = {0};
                int rc = fep_parietal_active_inference(fep_bridge, &problem, &result);
                if (rc == 0 && result.expected_improvement > 0.0f) {
                    /* Use exploration bonus to modulate confidence */
                    decision->confidence += (1.0f - decision->confidence) *
                        0.05f * result.exploration_bonus;
                }
                /* Clean up allocated policies if any */
                if (result.evaluated_policies) {
                    nimcp_free(result.evaluated_policies);
                }
                if (result.action) {
                    nimcp_free(result.action);
                }
            }
        }
    }

skip_sequential_c5: ; /* Label for parallel C5 dispatch (C5.5/C6/Hyperledger remain sequential) */

    // ========================================================================
    // STAGE C5.5: THOUSAND BRAINS INTEGRATION (Hawkins Cortical Columns)
    // ========================================================================
    // WHAT: Step the TB integration hub during inference — gather spatial state
    //       from reference frames, update column voting with feature evidence,
    //       run dendritic sequence predictions, broadcast consensus to workspace.
    // WHY:  TB provides object recognition via multi-column voting and spatial
    //       grounding via reference frames. This must run during inference to
    //       influence the decision through global workspace broadcast.
    // HOW:  Gated by same cognitive_train_interval to avoid per-inference overhead.
    if (brain->config.enable_thousand_brains_integration
        && brain->tb_integration_hub
        && (brain->cognitive_train_counter % (brain->cognitive_train_interval > 0
            ? brain->cognitive_train_interval : 5)) == 0) {
        tb_integration_step(brain->tb_integration_hub);
    }

    // ========================================================================
    // STAGE C6: INFERENCE-TIME COGNITIVE TRAINING (Online Learning)
    // ========================================================================
    // The brain learns from every experience, not just explicit training.
    // During inference, subsystems train on the input features and decision
    // output using self-supervised signals. Gated by cognitive_train_interval.
    {
        uint32_t interval = brain->cognitive_train_interval;
        if (interval == 0) interval = 5;
        brain->cognitive_train_counter++;
        if ((brain->cognitive_train_counter % interval) == 0) {
            float* output_vec = decision->output_vector;
            uint32_t out_size = decision->output_size;
            /* Implicit loss from confidence: low confidence → high implicit loss */
            float implicit_loss = 1.0f - decision->confidence;

            /* C6.1: Grounded language — learn from label if available */
            if (brain->grounded_lang && decision->label && decision->label[0]) {
                grounded_language_learn_from_text(brain->grounded_lang, decision->label);
                grounded_language_learn_syntax(brain->grounded_lang, decision->label);
                brain->cognitive_stats.grounded_lang_steps++;
            }

            /* C6.2: Knowledge system — absorb label as concept */
            if (brain->knowledge && decision->label && decision->label[0]) {
                knowledge_learn_from_text(brain->knowledge, decision->label,
                                          KNOWLEDGE_DOMAIN_GENERAL);
                brain->cognitive_stats.knowledge_steps++;
            }

            /* C6.3: VAE — self-supervised autoencoding of input features */
            if (brain->vae_training_bridge && brain->vae_enabled && features) {
                vae_training_bridge_t* vae = (vae_training_bridge_t*)brain->vae_training_bridge;
                vae_training_step_result_t vae_result = {0};
                vae_training_step(vae, features, num_features,
                                  features, num_features, &vae_result);
                brain->last_vae_free_energy = vae_result.loss.total_loss;
                /* Update anomaly score for next inference C5.3 */
                brain->last_vae_anomaly_score = vae_result.loss.total_loss;
                brain->cognitive_stats.vae_steps++;
                brain->cognitive_stats.vae_last_loss = vae_result.loss.total_loss;
            }

            /* C6.4: FEP-Parietal generative model — train on features→output */
            if (brain->parietal && output_vec) {
                fep_parietal_bridge_t* fep_bridge = parietal_get_fep_bridge(brain->parietal);
                if (fep_bridge) {
                    const float* obs_ptr = features;
                    const float* tgt_ptr = output_vec;
                    fep_parietal_train_model(fep_bridge, &obs_ptr, &tgt_ptr, 1);
                    brain->cognitive_stats.fep_parietal_steps++;
                }
            }

            /* C6.5: Parietal physics NN — learn dynamics from features→output */
            if (brain->parietal && num_features >= 4 && out_size >= 4 && output_vec) {
                uint32_t phys_dim = (num_features < 32) ? num_features : 32;
                const float* state_ptr = features;
                const float* deriv_ptr = output_vec;
                parietal_train_physics_nn(brain->parietal,
                                          &state_ptr, &deriv_ptr, 1, 1);
                brain->cognitive_stats.physics_nn_steps++;
            }

            /* C6.6: JEPA predictor — self-supervised latent prediction */
            if (brain->jepa_predictor && brain->jepa_predictor_enabled && output_vec) {
                uint32_t latent_dim = (num_features < 256) ? num_features : 256;
                jepa_latent_t* context = jepa_latent_create_dim(latent_dim);
                jepa_latent_t* target_latent = jepa_latent_create_dim(latent_dim);
                if (context && target_latent) {
                    jepa_latent_set_embedding(context, features,
                        (num_features < latent_dim) ? num_features : latent_dim);
                    jepa_latent_set_embedding(target_latent, output_vec,
                        (out_size < latent_dim) ? out_size : latent_dim);
                    float jepa_loss = 0.0f;
                    jepa_predictor_train_step(
                        (jepa_predictor_t*)brain->jepa_predictor,
                        context, target_latent, &jepa_loss);
                    brain->cognitive_stats.jepa_steps++;
                    brain->cognitive_stats.jepa_last_loss = jepa_loss;
                }
                if (context) jepa_latent_destroy(context);
                if (target_latent) jepa_latent_destroy(target_latent);
            }

            /* C6.7: Creative training — feedback from decision quality */
            if (brain->creative_training_bridge && brain->creative_enabled && output_vec) {
                uint8_t rating = (decision->confidence > 0.9f) ? 5 :
                                 (decision->confidence > 0.7f) ? 4 :
                                 (decision->confidence > 0.5f) ? 3 :
                                 (decision->confidence > 0.3f) ? 2 : 1;
                creative_training_submit_feedback(
                    brain->creative_training_bridge,
                    output_vec, 0 /* ART_MODALITY_TEXT */, rating,
                    decision->label);
                brain->cognitive_stats.creative_steps++;
            }

            /* C6.8: Self-heal engine — learn from inference success/failure */
            if (brain->self_heal_engine && brain->self_heal_enabled) {
                crash_features_t cf = {0};
                uint32_t cf_dim = (num_features < SELF_HEAL_FEATURE_DIM) ?
                                   num_features : SELF_HEAL_FEATURE_DIM;
                cf.n_features = cf_dim;
                memcpy(cf.features, features, cf_dim * sizeof(float));
                float success = decision->confidence;
                self_heal_train_online(
                    (self_heal_engine_t*)brain->self_heal_engine,
                    &cf, FIX_PATTERN_UNKNOWN, success);
                brain->cognitive_stats.self_heal_steps++;
            }

            /* C6.9: Intuition system — learn from inference outcomes */
            if (brain->intuition_system && brain->intuition_system_enabled) {
                intuition_experience_t exp = {
                    .id = brain->cognitive_train_counter,
                    .hunch = NULL,
                    .predicted_outcome = 1.0f,  /* Expected: high confidence */
                    .actual_outcome = decision->confidence,
                    .timestamp = (float)nimcp_time_get_us(),
                    .was_successful = (decision->confidence > 0.5f)
                };
                const intuition_experience_t* exp_ptr = &exp;
                intuition_train_from_experience(brain->intuition_system,
                                                 &exp_ptr, 1);
                brain->cognitive_stats.intuition_steps++;
            }

            /* C6.10: FEP orchestrator — update free energy from inference */
            BRAIN_ENSURE_FEP_ORCHESTRATOR(brain);
            if (brain->fep_orchestrator && brain->fep_orchestrator_enabled) {
                brain->fep_orchestrator->fep_metrics.free_energy = implicit_loss;
                brain->fep_orchestrator->fep_metrics.prediction_error = implicit_loss;
                brain->fep_orchestrator->fep_metrics.surprise =
                    -logf(fmaxf(decision->confidence, 1e-7f));
                brain->cognitive_stats.fep_orchestrator_steps++;
            }

            /* Log cognitive training summary periodically */
            if ((brain->cognitive_train_counter % (interval * 100)) == 0) {
                LOG_INFO("cognitive_train",
                    "C6 stats: lang=%u know=%u vae=%u(%.3f) fep=%u phys=%u pred=%u(%.3f) "
                    "jepa=%u(%.3f) creative=%u heal=%u intuit=%u fep_orch=%u",
                    brain->cognitive_stats.grounded_lang_steps,
                    brain->cognitive_stats.knowledge_steps,
                    brain->cognitive_stats.vae_steps, brain->cognitive_stats.vae_last_loss,
                    brain->cognitive_stats.fep_parietal_steps,
                    brain->cognitive_stats.physics_nn_steps,
                    brain->cognitive_stats.pred_hierarchy_steps,
                    brain->cognitive_stats.pred_hierarchy_last_loss,
                    brain->cognitive_stats.jepa_steps, brain->cognitive_stats.jepa_last_loss,
                    brain->cognitive_stats.creative_steps,
                    brain->cognitive_stats.self_heal_steps,
                    brain->cognitive_stats.intuition_steps,
                    brain->cognitive_stats.fep_orchestrator_steps);
            }
        }
    }

    // ========================================================================
    // TRANSCRIPT: Populate cognitive transcript from all stage outputs
    // ========================================================================
    // Captures the outputs of all cognitive stages into a structured record
    // for response composition and introspection.
    {
        cognitive_transcript_t* t = transcript_create();
        if (t) {
            transcript_entry_t* e;

            /* Engram recall */
            if (engram_confidence > 0.0f) {
                e = transcript_add(t, TRANSCRIPT_MODULE_ENGRAM,
                    engram_confidence, engram_confidence,
                    "Memory recall activated");
                if (e) transcript_entry_add_value(e, "strength", engram_confidence);
            }

            /* Curiosity */
            if (curiosity_drive > 0.0f) {
                char buf[NIMCP_TRANSCRIPT_SUMMARY_LEN];
                snprintf(buf, sizeof(buf), "Curiosity drive: %.2f%s",
                         curiosity_drive, is_novel ? " (novel input)" : "");
                e = transcript_add(t, TRANSCRIPT_MODULE_CURIOSITY,
                    curiosity_drive * 0.5f, curiosity_drive, buf);
                if (e) {
                    transcript_entry_add_value(e, "drive", curiosity_drive);
                    transcript_entry_add_value(e, "novelty", novelty_score);
                }
            }

            /* Predictive processing */
            if (prediction_error > 0.01f) {
                char buf[NIMCP_TRANSCRIPT_SUMMARY_LEN];
                snprintf(buf, sizeof(buf), "Prediction error: %.3f", prediction_error);
                float pred_salience = fminf(prediction_error, 1.0f);
                e = transcript_add(t, TRANSCRIPT_MODULE_PREDICTIVE,
                    pred_salience, 1.0f - prediction_error, buf);
                if (e) transcript_entry_add_value(e, "error", prediction_error);
            }

            /* Reasoning engine */
            if (reasoning_confidence > 0.0f) {
                char buf[NIMCP_TRANSCRIPT_SUMMARY_LEN];
                snprintf(buf, sizeof(buf), "Reasoning chain (confidence: %.2f)",
                         reasoning_confidence);
                e = transcript_add(t, TRANSCRIPT_MODULE_REASONING,
                    reasoning_confidence * 0.8f, reasoning_confidence, buf);
            }

            /* Emotional tagging */
            if (brain->config.enable_emotional_tagging) {
                float valence = (decision->confidence - 0.5f) * 2.0f;
                float arousal = prediction_error;
                char buf[NIMCP_TRANSCRIPT_SUMMARY_LEN];
                snprintf(buf, sizeof(buf), "Emotion: valence=%.2f arousal=%.2f",
                         valence, arousal);
                float emo_salience = fmaxf(fabsf(valence), arousal) * 0.6f;
                e = transcript_add(t, TRANSCRIPT_MODULE_EMOTION,
                    emo_salience, fabsf(valence), buf);
                if (e) {
                    transcript_entry_add_value(e, "valence", valence);
                    transcript_entry_add_value(e, "arousal", arousal);
                }
            }

            /* Ethics evaluation */
            BRAIN_ENSURE_ETHICS(brain);
            if (brain->ethics && brain->config.enable_ethics) {
                bool blocked = (strstr(decision->label, "BLOCKED-ETHICS") != NULL);
                float ethics_salience = blocked ? 1.0f : 0.2f;
                e = transcript_add(t, TRANSCRIPT_MODULE_ETHICS,
                    ethics_salience, blocked ? 0.0f : 1.0f,
                    blocked ? "Action blocked by ethics engine" : "Ethics check passed");
            }

            /* Epistemic filtering */
            if (brain->epistemic) {
                bool biased = (strstr(decision->label, "BIAS-DETECTED") != NULL);
                e = transcript_add(t, TRANSCRIPT_MODULE_EPISTEMIC,
                    biased ? 0.8f : 0.3f, decision->confidence,
                    biased ? "Bias detected in output" : "Epistemic filter passed");
            }

            /* FEP-Parietal (C5.5) */
            if (brain->parietal && brain->cognitive_stats.fep_parietal_steps > 0) {
                e = transcript_add(t, TRANSCRIPT_MODULE_FEP_PARIETAL,
                    0.4f, decision->confidence,
                    "Active inference updated beliefs");
            }

            /* Predictive hierarchy (C5.2) */
            if (brain->pred_hierarchy && brain->pred_hierarchy_enabled) {
                char buf[NIMCP_TRANSCRIPT_SUMMARY_LEN];
                snprintf(buf, sizeof(buf), "Predictive hierarchy (loss: %.3f)",
                         brain->cognitive_stats.pred_hierarchy_last_loss);
                e = transcript_add(t, TRANSCRIPT_MODULE_PRED_HIERARCHY,
                    0.4f, 1.0f - brain->cognitive_stats.pred_hierarchy_last_loss, buf);
                if (e) transcript_entry_add_value(e, "loss",
                    brain->cognitive_stats.pred_hierarchy_last_loss);
            }

            /* VAE anomaly (C5.3) */
            if (brain->vae_system && brain->vae_enabled) {
                bool anomalous = (brain->last_vae_anomaly_score > 0.8f);
                char buf[NIMCP_TRANSCRIPT_SUMMARY_LEN];
                snprintf(buf, sizeof(buf), "VAE anomaly score: %.3f%s",
                         brain->last_vae_anomaly_score,
                         anomalous ? " [ANOMALY]" : "");
                e = transcript_add(t, TRANSCRIPT_MODULE_VAE,
                    anomalous ? 0.8f : 0.2f,
                    1.0f - brain->last_vae_anomaly_score, buf);
                if (e) transcript_entry_add_value(e, "anomaly_score",
                    brain->last_vae_anomaly_score);
            }

            /* JEPA (C5.4) */
            if (brain->jepa_predictor && brain->jepa_predictor_enabled) {
                char buf[NIMCP_TRANSCRIPT_SUMMARY_LEN];
                snprintf(buf, sizeof(buf), "JEPA prediction (loss: %.3f)",
                         brain->cognitive_stats.jepa_last_loss);
                e = transcript_add(t, TRANSCRIPT_MODULE_JEPA,
                    0.3f, 1.0f - brain->cognitive_stats.jepa_last_loss, buf);
                if (e) transcript_entry_add_value(e, "loss",
                    brain->cognitive_stats.jepa_last_loss);
            }

            /* Grounded language + SNN spike-driven bridge */
            if (brain->grounded_lang) {
                float gl_confidence = 0.5f;
                if (brain->snn_lang_bridge) {
                    snn_lang_stats_t snn_stats;
                    if (snn_language_bridge_get_stats(brain->snn_lang_bridge,
                                                      &snn_stats) == 0) {
                        float blend = snn_language_bridge_get_blend(brain->snn_lang_bridge);
                        gl_confidence = 0.5f + blend * 0.3f; /* Boost with spike pathway */
                        char snn_summary[128];
                        snprintf(snn_summary, sizeof(snn_summary),
                                 "Grounded lang + SNN bridge (blend=%.2f, bindings=%u)",
                                 blend, snn_stats.active_bindings);
                        e = transcript_add(t, TRANSCRIPT_MODULE_GROUNDED_LANG,
                            0.5f, gl_confidence, snn_summary);
                    } else {
                        e = transcript_add(t, TRANSCRIPT_MODULE_GROUNDED_LANG,
                            0.5f, 0.5f, "Grounded language active");
                    }
                } else {
                    e = transcript_add(t, TRANSCRIPT_MODULE_GROUNDED_LANG,
                        0.5f, 0.5f, "Grounded language active");
                }
            }

            /* Sensory SNN bridges (report which modalities are active) */
            {
                uint32_t mod = brain->active_modalities;
                uint32_t encoding_count = 0;
                if ((mod & BRAIN_MODALITY_VISUAL) && brain->snn_visual_bridge) encoding_count++;
                if ((mod & BRAIN_MODALITY_AUDIO) && brain->snn_audio_bridge) encoding_count++;
                if ((mod & BRAIN_MODALITY_SOMATOSENSORY) && brain->snn_somatosensory_bridge) encoding_count++;
                if ((mod & BRAIN_MODALITY_SPEECH) && brain->snn_speech_bridge) encoding_count++;
                if (encoding_count > 0) {
                    char sensory_buf[NIMCP_TRANSCRIPT_SUMMARY_LEN];
                    snprintf(sensory_buf, sizeof(sensory_buf),
                             "Sensory SNN: %u modalities encoding%s",
                             encoding_count,
                             brain->cross_modal_aligner ? " (cross-modal aligned)" : "");
                    e = transcript_add(t, TRANSCRIPT_MODULE_GROUNDED_LANG,
                        0.35f, 0.5f, sensory_buf);
                }
            }

            /* Knowledge system */
            if (brain->knowledge && brain->cognitive_stats.knowledge_steps > 0) {
                e = transcript_add(t, TRANSCRIPT_MODULE_KNOWLEDGE,
                    0.4f, 0.5f,
                    "Knowledge graph queried");
            }

            /* Natural explanation (already in decision->explanation) */
            if (decision->explanation[0]) {
                e = transcript_add(t, TRANSCRIPT_MODULE_REASONING,
                    0.6f, decision->confidence,
                    decision->explanation);
            }

            transcript_finalize(t);
            decision->transcript = t;

            /* Cache a copy on the brain for API access after decision is freed */
            if (brain->last_transcript) {
                transcript_free(brain->last_transcript);
            }
            cognitive_transcript_t* copy = transcript_create();
            if (copy) {
                memcpy(copy, t, sizeof(cognitive_transcript_t));
            }
            brain->last_transcript = copy;
        }
    }

    // ========================================================================
    // PARALLEL POST-FORWARD: Wait for pool completion
    // ========================================================================
    if (post_forward_submitted) {
        nimcp_pool_wait(brain->inference_pool);
        // Free the heap-allocated task args
        if (post_ctx._internal_args) {
            nimcp_free(post_ctx._internal_args);
            post_ctx._internal_args = NULL;
        }
    }

    PROBE_STAGE(brain, PROBE_INF_COGNITIVE, {
        PROBE_SET_INT(&_ctx, "post_forward_parallel", post_forward_submitted ? 1 : 0);
    });

    // ========================================================================
    // HYPERLEDGER: Consensus-Gated Inference (multi-brain BFT voting)
    // ========================================================================
    if (brain->hyperledger_bridge && brain->hyperledger_enabled &&
        brain->collective_cognition && brain->collective_cognition_enabled) {
        consensus_gate_result_t gate_result = CONSENSUS_GATE_SKIP;
        hyperledger_consensus_gate(brain->hyperledger_bridge,
                                   decision->output_vector, decision->output_size,
                                   decision->confidence, &gate_result);
        if (gate_result == CONSENSUS_GATE_REJECT) {
            /* Consensus rejected this decision — lower confidence to signal uncertainty */
            decision->confidence *= 0.5f;
        }
    }

    // Update statistics (after all post-decision processing)
    update_inference_stats(brain, decision);

    /* === SAFETY WATCHDOG: Validate output and enforce actuator safety ===
     * After successful inference, signal the watchdog that the brain is alive,
     * then validate the output vector. If validation fails (NaN/Inf/magnitude),
     * replace output with safe fallback values. */
    if (brain->safety_watchdog_enabled && brain->safety_watchdog && decision) {
        typedef struct nimcp_safety_watchdog nimcp_safety_watchdog_t;
        extern void nimcp_watchdog_heartbeat(nimcp_safety_watchdog_t* watchdog);
        extern int nimcp_watchdog_validate_output(nimcp_safety_watchdog_t* watchdog,
                                                   float* output, uint32_t num_outputs);
        extern int nimcp_watchdog_get_safe_output(nimcp_safety_watchdog_t* watchdog,
                                                   float* output, uint32_t num_outputs);

        nimcp_safety_watchdog_t* wd = (nimcp_safety_watchdog_t*)brain->safety_watchdog;

        /* 1. Heartbeat — reset the deadman timer */
        nimcp_watchdog_heartbeat(wd);

        /* 2. Validate output vector for NaN/Inf/magnitude/rate violations */
        if (decision->output_vector && decision->output_size > 0) {
            int valid = nimcp_watchdog_validate_output(wd,
                            decision->output_vector, decision->output_size);
            if (valid != 0) {
                /* 3. Validation failed — replace with safe output */
                LOG_MODULE_WARN("BRAIN", "brain_decide: watchdog rejected output — "
                                "substituting safe values");
                nimcp_safety_audit_log_event(NIMCP_SAFETY_AUDIT_WATCHDOG_TRIGGER, 3,
                    "Safety watchdog rejected output — substituting safe values");
                nimcp_watchdog_get_safe_output(wd,
                    decision->output_vector, decision->output_size);
                decision->confidence *= 0.1f;  /* Signal low confidence */
            }
        }
    }

    /* === LGSS MOTOR GATE: Validate motor commands before output ===
     * Defense in depth — watchdog checks values, motor gate checks intent.
     * Evaluates the output vector against the safety KB for motor safety. */
    if (brain->lgss && brain->lgss_enabled && decision &&
        decision->output_vector && decision->output_size > 0) {
        safety_action_context_t lgss_motor_ctx;
        memset(&lgss_motor_ctx, 0, sizeof(lgss_motor_ctx));
        strncpy(lgss_motor_ctx.string_fields[0].key, "operation", 63);
        strncpy(lgss_motor_ctx.string_fields[0].value, "motor_output", SAFETY_MAX_VALUE_LEN - 1);
        strncpy(lgss_motor_ctx.string_fields[1].key, "target_type", 63);
        strncpy(lgss_motor_ctx.string_fields[1].value, "actuator_command", SAFETY_MAX_VALUE_LEN - 1);
        lgss_motor_ctx.num_string_fields = 2;

        /* Compute magnitude of output vector as a proxy for motor force */
        float motor_magnitude = 0.0f;
        for (uint32_t i = 0; i < decision->output_size && i < 1024; i++) {
            motor_magnitude += decision->output_vector[i] * decision->output_vector[i];
        }
        motor_magnitude = sqrtf(motor_magnitude);

        strncpy(lgss_motor_ctx.numeric_fields[0].key, "magnitude", 63);
        lgss_motor_ctx.numeric_fields[0].value = motor_magnitude;
        strncpy(lgss_motor_ctx.numeric_fields[1].key, "output_size", 63);
        lgss_motor_ctx.numeric_fields[1].value = (float)decision->output_size;
        lgss_motor_ctx.num_numeric_fields = 2;

        lgss_motor_ctx.domain_hint = SAFETY_DOMAIN_HUMAN_HARM;
        lgss_motor_ctx.has_domain_hint = true;
        snprintf(lgss_motor_ctx.action_description, sizeof(lgss_motor_ctx.action_description),
            "Motor output gate: %u outputs, magnitude=%.3f",
            decision->output_size, motor_magnitude);
        strncpy(lgss_motor_ctx.source, "MOTOR_GATE", 63);
        lgss_motor_ctx.timestamp = nimcp_time_now_us();

        safety_evaluation_t lgss_motor_eval;
        int lgss_motor_ret = lgss_evaluate(brain->lgss, &lgss_motor_ctx, &lgss_motor_eval);
        /* W11: emit KG evaluation event (every outcome). */
        if (lgss_motor_ret == 0) {
            w11_emit_lgss_evaluation(brain,
                                     (int)lgss_motor_eval.action,
                                     (int)lgss_motor_eval.max_severity,
                                     lgss_motor_eval.confidence,
                                     "MOTOR_GATE",
                                     lgss_motor_ctx.action_description);
        }
        if (lgss_motor_ret == 0 && lgss_motor_eval.action == SAFETY_ACTION_DENY) {
            /* Motor gate blocked — zero out output vector and reduce confidence */
            for (uint32_t i = 0; i < decision->output_size; i++) {
                decision->output_vector[i] = 0.0f;
            }
            decision->confidence *= 0.05f;
            strncat(decision->label, " [MOTOR-BLOCKED-LGSS]",
                   sizeof(decision->label) - strlen(decision->label) - 1);
            nimcp_safety_audit_log_event(NIMCP_SAFETY_AUDIT_LGSS_MOTOR_BLOCKED, 3,
                "LGSS motor gate BLOCKED output: magnitude=%.3f, outputs=%u",
                motor_magnitude, decision->output_size);
            LOG_MODULE_WARN("BRAIN", "LGSS motor gate blocked output — "
                            "zeroed output vector");
        }
    }

    /* === NATIVE LANGUAGE: Generate text from brain output ===
     * If native language is enabled, produce a text representation of the
     * brain's neural response. This is the brain speaking in its own words. */
    if (brain->native_language_enabled && brain->native_language && decision &&
        decision->output_vector && decision->output_size > 0) {
        extern int nimcp_language_generate(void*, const float*, uint32_t,
                                            char*, uint32_t);
        char native_text[512];
        int text_len = nimcp_language_generate(brain->native_language,
            decision->output_vector, decision->output_size,
            native_text, sizeof(native_text));
        if (text_len > 0) {
            /* Store in decision metadata if field exists, otherwise log */
            (void)native_text; /* Available for caller via future API */
        }
    }

    /* === COGNITIVE ENHANCEMENTS: Post-inference processing === */

    /* Output attention: reweight output based on task context */
    if (brain->output_attention && decision && decision->output_vector) {
        extern int nimcp_oa_attend(void*, const float*, uint32_t, const char*, float*);
        /* Use cached label from last training step as task context */
        nimcp_oa_attend(brain->output_attention,
            decision->output_vector, decision->output_size,
            "inference", decision->output_vector);
    }

    /* Analogical transfer: blend with similar past solutions */
    if (brain->analogical_transfer && decision && decision->output_vector && features) {
        extern int nimcp_analogical_apply_transfer(void*, const float*, uint32_t,
            const float*, uint32_t, float*);
        int analogy_applied = nimcp_analogical_apply_transfer(brain->analogical_transfer,
            features, num_features,
            decision->output_vector, decision->output_size,
            decision->output_vector);
        /* W13: emit analogy-match event when a transfer actually happened. */
        if (analogy_applied) {
            wave13_analogy_emit_match(brain, "inference",
                                      decision->confidence,
                                      decision->confidence);
        }
    }

    /* Multi-timescale memory: push current inference to immediate buffer */
    if (brain->multiscale_memory && decision && decision->output_vector) {
        extern void nimcp_multiscale_push(void*, const float*, uint32_t, const char*, float);
        nimcp_multiscale_push(brain->multiscale_memory,
            decision->output_vector, decision->output_size,
            "inference", decision->confidence);
        /* W13: emit multiscale push event (inference path). */
        wave13_multiscale_emit_push(brain, "inference", decision->confidence);
    }

    /* Inner speech: refine output through self-talk loop */
    if (brain->inner_speech && brain->native_language_enabled &&
        decision && decision->output_vector && decision->output_size > 0) {
        extern int nimcp_inner_speech_refine(void*, float*, uint32_t, float*, char*, uint32_t);
        nimcp_inner_speech_refine(brain->inner_speech,
            decision->output_vector, decision->output_size,
            decision->output_vector, NULL, 0);
    }

    /* Record refined output to episodic replay for consolidation during sleep */
    if (brain->episodic_replay && decision && decision->output_vector) {
        extern void nimcp_episodic_replay_record(void*, const float*, uint32_t,
            const float*, uint32_t, const char*, float, float);
        nimcp_episodic_replay_record(brain->episodic_replay,
            features, num_features,
            decision->output_vector, decision->output_size,
            "inference_refined", decision->confidence, 0.0f);
    }

    /* === WORKING MEMORY: Read scratchpad context into inference === */
    if (brain->wm_scratchpad && decision && decision->output_vector) {
        extern int nimcp_wms_read_all(void*, float*, uint32_t);
        float wm_context[512];
        int wm_n = nimcp_wms_read_all(brain->wm_scratchpad, wm_context, 512);
        if (wm_n > 0) {
            /* Blend working memory context into output (subtle influence) */
            uint32_t blend_n = (uint32_t)wm_n < decision->output_size
                               ? (uint32_t)wm_n : decision->output_size;
            for (uint32_t i = 0; i < blend_n; i++) {
                decision->output_vector[i] =
                    0.95f * decision->output_vector[i] + 0.05f * wm_context[i];
            }
        }
    }

    /* === WORLD MODEL: Predict and compare for surprise detection === */
    if (brain->world_model_trainer && decision) {
        extern float nimcp_wmt_get_prediction_error(const void*);
        float pred_error = nimcp_wmt_get_prediction_error(brain->world_model_trainer);
        /* High prediction error = surprising input = boost confidence
         * (the brain should pay attention to novel situations) */
        if (pred_error > 0.5f && decision->confidence < 0.9f) {
            decision->confidence *= 1.0f + 0.1f * pred_error;
            if (decision->confidence > 1.0f) decision->confidence = 1.0f;
        }
    }

    /* === WORLD PRIOR: Step simulation engines forward ===
     * Keep the physics/chemistry/biology simulations in sync with the brain's
     * internal time. This allows the world prior to detect violations in real-time
     * and provides ground truth for the world model trainer's loss function. */
    if (brain->world_prior) {
        extern int world_prior_step(void* wp, float dt);
        world_prior_step(brain->world_prior, 0.01f);
    }

    /* === DYNAMIC ARCHITECTURE: Record inference activation === */
    if (brain->dynamic_arch && decision) {
        extern int nimcp_dynamic_arch_record_activation(void*, const char*, uint32_t, float);
        nimcp_dynamic_arch_record_activation(brain->dynamic_arch,
            "inference", 0, decision->confidence);
    }

    // Cache decision for future reuse (thread-safe with mutex protection)
    // W7-8 (C-INF-M3): Log warning on mutex lock failure instead of silently
    // skipping cache update. A failed lock indicates contention or corruption
    // that should be diagnosed, not silently ignored.
    if (nimcp_platform_mutex_lock(&brain->cache_mutex) == 0) {
        cache_decision(brain, features, num_features, decision);
        nimcp_platform_mutex_unlock(&brain->cache_mutex);
    } else {
        LOG_MODULE_WARN("BRAIN", "brain_decide: failed to lock cache_mutex — "
                        "decision not cached (possible contention or corruption)");
    }

    PROBE_STAGE(brain, PROBE_INF_DECISION, {
        PROBE_SET_FLOAT(&_ctx, "confidence", decision->confidence);
        float _dnorm = 0.0f;
        for (uint32_t _i = 0; _i < decision->output_size; _i++)
            _dnorm += decision->output_vector[_i] * decision->output_vector[_i];
        PROBE_SET_FLOAT(&_ctx, "output_norm", sqrtf(_dnorm));
        PROBE_SET_INT(&_ctx, "output_size", (int64_t)decision->output_size);
        PROBE_SET_FLOAT(&_ctx, "inference_time_ms",
            (float)decision->inference_time_us / 1000.0f);
        PROBE_SET_STRING(&_ctx, "label", decision->label);
    });

    // Free the defensive copy of features
    nimcp_free(local_features);

    /* === EMIT PER-PHASE TIMING SUMMARY (NIMCP_DEBUG_TIMING=1) === */
    if (_bd_dbg) {
        BD_MARK(_bd_t_end);
        double total_ms = BD_MS(_bd_t_start, _bd_t_end);
        if (total_ms > 1000.0) {  /* only log slow decisions to keep noise down */
            NIMCP_LOGGING_INFO(
                "brain_decide phases (ms): preforward=%.0f forward=%.0f "
                "hemispheric=%.0f snn=%.0f post_par=%.0f reasoning=%.0f "
                "ethics=%.0f cognitive=%.0f TOTAL=%.0f",
                BD_MS(_bd_t_start, _bd_t_preforward),
                BD_MS(_bd_t_preforward, _bd_t_forward),
                BD_MS(_bd_t_forward, _bd_t_hemispheric),
                BD_MS(_bd_t_hemispheric, _bd_t_snn),
                BD_MS(_bd_t_snn, _bd_t_post_parallel),
                BD_MS(_bd_t_post_parallel, _bd_t_reasoning),
                BD_MS(_bd_t_reasoning, _bd_t_ethics),
                BD_MS(_bd_t_ethics, _bd_t_end),
                total_ms);
        }
    }
    #undef BD_MARK
    #undef BD_MS

    /* Empathy observation: feed the just-computed decision into
     * brain->empathy_network so its mirror-neuron state reflects recent
     * brain activity. Null-safe — if empathy_network isn't configured,
     * skip. Uses first output dim as confidence proxy; output_index
     * becomes the feature_low encoding. */
    if (brain->empathy_network && decision &&
        decision->output_vector && decision->output_size > 0) {
        /* Find argmax and its magnitude for confidence. */
        uint32_t argmax = 0;
        float max_abs = 0.0f;
        for (uint32_t i = 0; i < decision->output_size; i++) {
            float a = decision->output_vector[i];
            if (a < 0.0f) a = -a;
            if (a > max_abs) { max_abs = a; argmax = i; }
        }
        if (max_abs > 1.0f) max_abs = 1.0f;
        event_packet_t self_action = {0};
        self_action.version_flags  = EVENT_FLAG_EXCITATORY;
        self_action.source_node_id = 0;                         /* self */
        self_action.confidence     = (uint16_t)(max_abs * 65535.0f);
        self_action.feature_low    = (uint16_t)(argmax & 0xFFFF);
        self_action.feature_high   = (uint16_t)((argmax >> 16) & 0xFFFF);
        self_action.hop_count      = 0;
        self_action.timestamp      = 0;
        (void)empathy_network_observe(
            (empathy_network_t)brain->empathy_network, &self_action, 0);
    }

    /* W9-finish: empathetic_response dispatch. Uses arousal (emotional
     * intensity) as the trigger since emotional_learning exposes arousal
     * but not signed valence. Treats high arousal as a distress proxy.
     * Response is discarded — goal is to activate the subsystem. */
    if (brain->empathetic_response_engine && brain->emotional_learning) {
        float arsl = nimcp_emotional_learning_get_arousal(brain->emotional_learning);
        if (arsl > 0.6f) {
            emotional_state_t est = {0};
            est.emotion_type      = (arsl > 0.85f) ? EMOTION_RAGE
                                                   : EMOTION_FRUSTRATION;
            est.intensity         = (arsl > 0.85f) ? EMOTION_INTENSITY_HIGH
                                                   : EMOTION_INTENSITY_MEDIUM;
            est.intensity_value   = arsl;
            est.valence           = -arsl;  /* proxy: high arousal → distress */
            est.arousal           = arsl;
            est.crisis_flags      = 0;
            est.crisis_confidence = 0.0f;

            empathetic_response_t resp = {0};
            (void)empathetic_response_generate(
                brain->empathetic_response_engine, &est, &resp);
        }
    }

    /* W9-finish: middleware_controller pattern dispatch. argmax(output)
     * as pattern_id, |max| as similarity. Fires all active pattern
     * subscribers. Null-safe. */
    if (brain->middleware_controller && brain->enable_middleware_controller &&
        decision && decision->output_vector && decision->output_size > 0) {
        uint32_t mw_argmax = 0;
        float mw_max = 0.0f;
        for (uint32_t i = 0; i < decision->output_size; i++) {
            float a = decision->output_vector[i];
            if (a < 0.0f) a = -a;
            if (a > mw_max) { mw_max = a; mw_argmax = i; }
        }
        if (mw_max > 1.0f) mw_max = 1.0f;
        middleware_controller_on_pattern_match(
            (struct middleware_controller*)brain->middleware_controller,
            mw_argmax, mw_max, /*region_id=*/0);
    }

    /* W16-A + W16-B: KG salience bias + prior-decision recurrence.
     * Makes the KG actually affect brain_decide's output. See
     * w16_apply_kg_consumers() for details. */
    w16_apply_kg_consumers(brain, decision);

    brain_clear_error();
    return decision;

inference_timeout:
    /* G3: Inference deadline exceeded — return minimal decision with low confidence */
    {
        brain_decision_t* timeout_decision = allocate_decision(brain->config.num_outputs);
        if (timeout_decision) {
            timeout_decision->confidence = 0.05f;
            timeout_decision->output_size = brain->config.num_outputs;
            /* output_vector is zeroed by allocate_decision */
            determine_output_label(brain, timeout_decision);
            update_inference_stats(brain, timeout_decision);
        }
        return timeout_decision;
    }
}


//=============================================================================
// brain_predict - Wrapper for prediction functionality
//=============================================================================
/**
 * @brief Perform prediction with given input
 *
 * WHAT: Forward pass through network to generate predictions
 * WHY:  Compatibility wrapper for tests and external APIs
 * HOW:  Validates parameters and delegates to network forward pass
 *
 * @param brain Brain handle
 * @param input Input features array
 * @param input_size Size of input array
 * @param output Output predictions array (pre-allocated)
 * @param output_size Size of output array
 * @return true on success, false on error
 */
bool brain_predict(brain_t brain, const float* input, uint32_t input_size,
                  float* output, uint32_t output_size)
{
    LOG_MODULE_DEBUG("BRAIN", "brain_predict: input_size=%u, output_size=%u", input_size, output_size);

    // Validation
    if (!brain) {
        LOG_MODULE_ERROR("BRAIN", "brain_predict: NULL brain");
        set_error("brain_predict: NULL brain");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "brain_predict: brain is NULL");
        return false;
    }

    if (!input || input_size == 0) {
        LOG_MODULE_ERROR("BRAIN", "brain_predict: invalid input parameters (input=%p, size=%u)", input, input_size);
        set_error("brain_predict: invalid input parameters");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "brain_predict: input is NULL");
        return false;
    }

    if (!output || output_size == 0) {
        LOG_MODULE_ERROR("BRAIN", "brain_predict: invalid output parameters (output=%p, size=%u)", output, output_size);
        set_error("brain_predict: invalid output parameters");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "brain_predict: output is NULL");
        return false;
    }

    // Check network exists
    if (!brain->network) {
        LOG_MODULE_ERROR("BRAIN", "brain_predict: network not initialized");
        set_error("brain_predict: network not initialized");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "brain_predict: brain->network is NULL");
        return false;
    }

    // Validate input size matches configured dimensions
    if (brain->config.num_inputs > 0 && input_size != brain->config.num_inputs) {
        LOG_MODULE_ERROR("BRAIN", "brain_predict: input size mismatch (expected=%u, got=%u)",
                         brain->config.num_inputs, input_size);
        set_error("brain_predict: input size mismatch");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "brain_predict: validation failed");
        return false;
    }

    // Validate output size matches configured dimensions
    if (brain->config.num_outputs > 0 && output_size != brain->config.num_outputs) {
        LOG_MODULE_ERROR("BRAIN", "brain_predict: output size mismatch (expected=%u, got=%u)",
                         brain->config.num_outputs, output_size);
        set_error("brain_predict: output size mismatch");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_INVALID_PARAM, "brain_predict: validation failed");
        return false;
    }

    LOG_MODULE_INFO("BRAIN", "brain_predict: performing forward pass (readonly=%d)", brain->can_use_readonly);

    // W7-7 (C-INF-M2): Forward path consistency note.
    // brain_predict() uses adaptive_network_forward() (thresholded), which applies
    // adaptive output thresholding that zeros below-threshold outputs. This differs
    // from the API-level predict_fast/predict_in_domain which use forward_raw().
    // brain_decide() also uses adaptive_network_forward (via perform_forward_pass).
    //
    // This means:
    //   - brain_predict() and brain_decide() are CONSISTENT (both thresholded)
    //   - predict_fast() uses raw (unthresholded) for classification argmax
    //
    // The thresholded version is correct here because brain_predict() populates
    // a raw output buffer for the caller, and the threshold reflects the network's
    // actual learned decision boundary. predict_fast uses raw specifically because
    // it does its own argmax and thresholding would collapse outputs to the same class.
    //
    // Perform forward pass through network
    // Use read-only mode if this is a COW clone
    if (brain->can_use_readonly) {
        adaptive_network_forward_readonly(brain->network, input, input_size,
                                         output, output_size, 0);
    } else {
        adaptive_network_forward(brain->network, input, input_size,
                                output, output_size, 0);
    }

    // Publish prediction event via bio-async
    brain_publish_processing_event("prediction", 1.0F);

    LOG_MODULE_DEBUG("BRAIN", "brain_predict: prediction complete");
    brain_clear_error();
    return true;
}
