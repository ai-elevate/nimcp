/**
 * @file e2e_test_positional_encoding_pipeline.cpp
 * @brief E2E Test for Complete Positional Encoding Pipeline
 *
 * WHAT: Complete end-to-end tests for positional encoding across all NIMCP modules
 * WHY:  Verify PE improves sequence processing, integrates with brain/attention/memory
 * HOW:  Test all PE types through complete brain pipelines with real-world patterns
 *
 * TEST SCENARIOS:
 * 1. BrainWithPEAttention - Full brain with PE-enabled attention
 * 2. CognitivePipelineWithPE - Cognitive flow with position-aware memory
 * 3. SequenceLearningWithPE - Sequence discrimination with all PE types
 * 4. SpeechProductionWithPE - Broca area speech with positional context
 * 5. PerformanceAtScale - Large sequence PE performance testing
 * 6. PETypeComparison - Compare all PE types on same task
 * 7. SequenceExtrapolation - Test PE beyond training length
 * 8. MemoryIntegration - PE with working memory system
 *
 * @author NIMCP Development Team
 * @date 2025-12-10
 * @version 1.0.0
 */

#include "e2e_test_framework.h"
#include <thread>
#include <vector>
#include <algorithm>
#include <numeric>
#include <random>
#include <cmath>

extern "C" {
#include "nimcp.h"
#include "utils/encoding/nimcp_positional_encoding.h"
#include "utils/memory/nimcp_memory.h"
#include "utils/logging/nimcp_logging.h"
}

using namespace nimcp::e2e;

//=============================================================================
// Test Configuration
//=============================================================================

// Sequence parameters
constexpr uint32_t SHORT_SEQ_LEN = 16;
constexpr uint32_t MEDIUM_SEQ_LEN = 128;
constexpr uint32_t LONG_SEQ_LEN = 512;
constexpr uint32_t VERY_LONG_SEQ_LEN = 2048;

// Embedding dimensions
constexpr uint32_t SMALL_DIM = 64;
constexpr uint32_t MEDIUM_DIM = 256;
constexpr uint32_t LARGE_DIM = 512;

// Training parameters
constexpr uint32_t NUM_TRAINING_EPOCHS = 100;
constexpr uint32_t BATCH_SIZE = 8;
constexpr float LEARNING_RATE = 0.01f;

// Accuracy thresholds
constexpr float MIN_SEQUENCE_ACCURACY = 0.85f;
constexpr float PE_ACCURACY_IMPROVEMENT = 0.10f; // PE should improve accuracy by 10%

//=============================================================================
// Helper Structures
//=============================================================================

/**
 * @brief Sequence pattern for discrimination task
 */
struct SequencePattern {
    std::vector<float> data;
    uint32_t label;
    std::string description;
};

/**
 * @brief PE performance metrics
 */
struct PEPerformanceMetrics {
    float encoding_time_us;
    float memory_usage_bytes;
    float cache_hit_rate;
    uint64_t total_encodings;

    PEPerformanceMetrics()
        : encoding_time_us(0.0f)
        , memory_usage_bytes(0.0f)
        , cache_hit_rate(0.0f)
        , total_encodings(0)
    {}
};

/**
 * @brief Test results for PE type comparison
 */
struct PETypeResults {
    nimcp_pos_encoding_type_t type;
    float accuracy;
    float training_time_ms;
    float inference_time_us;
    size_t memory_bytes;

    PETypeResults()
        : type(NIMCP_POS_SINUSOIDAL)
        , accuracy(0.0f)
        , training_time_ms(0.0f)
        , inference_time_us(0.0f)
        , memory_bytes(0)
    {}
};

//=============================================================================
// Pattern Generators
//=============================================================================

/**
 * @brief Generate sequence patterns for discrimination
 *
 * WHAT: Create position-dependent patterns that require PE to discriminate
 * WHY:  Test if PE actually helps the model learn positional information
 * HOW:  Pattern A: ascending values, Pattern B: descending values
 */
class SequencePatternGenerator {
public:
    static std::vector<SequencePattern> generate_position_dependent_patterns(
        uint32_t seq_length,
        uint32_t num_samples_per_class
    ) {
        std::vector<SequencePattern> patterns;
        std::random_device rd;
        std::mt19937 gen(rd());
        std::normal_distribution<float> noise(0.0f, 0.1f);

        // Pattern 0: Ascending sequence (position increases -> value increases)
        for (uint32_t i = 0; i < num_samples_per_class; i++) {
            SequencePattern pattern;
            pattern.label = 0;
            pattern.description = "ascending";
            pattern.data.resize(seq_length);

            for (uint32_t pos = 0; pos < seq_length; pos++) {
                float base_value = static_cast<float>(pos) / seq_length;
                pattern.data[pos] = base_value + noise(gen);
            }
            patterns.push_back(pattern);
        }

        // Pattern 1: Descending sequence (position increases -> value decreases)
        for (uint32_t i = 0; i < num_samples_per_class; i++) {
            SequencePattern pattern;
            pattern.label = 1;
            pattern.description = "descending";
            pattern.data.resize(seq_length);

            for (uint32_t pos = 0; pos < seq_length; pos++) {
                float base_value = 1.0f - static_cast<float>(pos) / seq_length;
                pattern.data[pos] = base_value + noise(gen);
            }
            patterns.push_back(pattern);
        }

        // Pattern 2: Peak in middle (position-dependent non-monotonic)
        for (uint32_t i = 0; i < num_samples_per_class; i++) {
            SequencePattern pattern;
            pattern.label = 2;
            pattern.description = "peak_middle";
            pattern.data.resize(seq_length);

            uint32_t peak_pos = seq_length / 2;
            for (uint32_t pos = 0; pos < seq_length; pos++) {
                float distance = fabsf(static_cast<float>(pos) - static_cast<float>(peak_pos));
                float base_value = 1.0f - (distance / peak_pos);
                pattern.data[pos] = base_value + noise(gen);
            }
            patterns.push_back(pattern);
        }

        // Pattern 3: Alternating high/low (even/odd positions)
        for (uint32_t i = 0; i < num_samples_per_class; i++) {
            SequencePattern pattern;
            pattern.label = 3;
            pattern.description = "alternating";
            pattern.data.resize(seq_length);

            for (uint32_t pos = 0; pos < seq_length; pos++) {
                float base_value = (pos % 2 == 0) ? 0.8f : 0.2f;
                pattern.data[pos] = base_value + noise(gen);
            }
            patterns.push_back(pattern);
        }

        return patterns;
    }

    /**
     * @brief Generate natural language-like sequences
     *
     * WHAT: Position-dependent patterns mimicking word sequences
     * WHY:  Test PE on realistic linguistic patterns
     * HOW:  Simulate subject-verb-object word position patterns
     */
    static std::vector<SequencePattern> generate_language_patterns(
        uint32_t seq_length,
        uint32_t num_samples
    ) {
        std::vector<SequencePattern> patterns;
        std::random_device rd;
        std::mt19937 gen(rd());
        std::uniform_real_distribution<float> word_dist(0.0f, 1.0f);

        for (uint32_t i = 0; i < num_samples; i++) {
            SequencePattern pattern;
            pattern.data.resize(seq_length, 0.0f);

            // Subject-Verb-Object structure
            uint32_t subject_pos = 0;
            uint32_t verb_pos = seq_length / 3;
            uint32_t object_pos = 2 * seq_length / 3;

            // Mark grammatical positions
            pattern.data[subject_pos] = 0.9f;
            pattern.data[verb_pos] = 0.6f;
            pattern.data[object_pos] = 0.3f;

            // Fill with "context" words
            for (uint32_t pos = 0; pos < seq_length; pos++) {
                if (pos != subject_pos && pos != verb_pos && pos != object_pos) {
                    pattern.data[pos] = word_dist(gen) * 0.2f;
                }
            }

            // Label based on sentence type (simple vs complex based on verb position)
            pattern.label = (verb_pos < seq_length / 2) ? 0 : 1;
            pattern.description = "language_pattern";

            patterns.push_back(pattern);
        }

        return patterns;
    }
};

//=============================================================================
// PE Test Helper Functions
//=============================================================================

/**
 * @brief Apply positional encoding to sequence
 *
 * WHAT: Add PE to raw sequence data
 * WHY:  Inject position information for processing
 * HOW:  Add PE vectors element-wise to sequence
 */
static void apply_pe_to_sequence(
    nimcp_pos_encoder_t* encoder,
    const std::vector<float>& input_seq,
    std::vector<float>& output_seq,
    uint32_t dim
) {
    uint32_t seq_len = input_seq.size();
    output_seq.resize(seq_len * dim);

    // Encode each position
    std::vector<float> pe_vec(dim);
    for (uint32_t pos = 0; pos < seq_len; pos++) {
        int ret = nimcp_pos_encode_position(encoder, pos, pe_vec.data());
        ASSERT_EQ(ret, NIMCP_POS_SUCCESS);

        // Combine input with PE (broadcast input to all dims, then add PE)
        for (uint32_t d = 0; d < dim; d++) {
            output_seq[pos * dim + d] = input_seq[pos] + pe_vec[d];
        }
    }
}

/**
 * @brief Measure PE encoding performance
 *
 * WHAT: Benchmark PE encoding speed and resource usage
 * WHY:  Verify PE meets performance requirements
 * HOW:  Encode sequences, measure time and memory
 */
static PEPerformanceMetrics measure_pe_performance(
    nimcp_pos_encoder_t* encoder,
    uint32_t seq_length,
    uint32_t num_iterations
) {
    PEPerformanceMetrics metrics;

    uint32_t dim = nimcp_pos_get_dim(encoder);
    std::vector<float> output(seq_length * dim);

    Timer timer;
    timer.start();

    for (uint32_t i = 0; i < num_iterations; i++) {
        int ret = nimcp_pos_encode_sequence(encoder, 0, seq_length, output.data());
        EXPECT_EQ(ret, NIMCP_POS_SUCCESS);
    }

    timer.stop();

    // Calculate average encoding time
    metrics.encoding_time_us = static_cast<float>(timer.elapsed_us()) / num_iterations;

    // Get statistics
    nimcp_pos_stats_t stats;
    nimcp_pos_get_stats(encoder, &stats);

    metrics.total_encodings = stats.total_encodings;
    metrics.memory_usage_bytes = static_cast<float>(stats.memory_usage_bytes);

    if (stats.cache_hits + stats.cache_misses > 0) {
        metrics.cache_hit_rate = static_cast<float>(stats.cache_hits) /
                                 (stats.cache_hits + stats.cache_misses);
    }

    return metrics;
}

//=============================================================================
// Test Fixture
//=============================================================================

class PEPipelineE2ETest : public ::testing::Test {
protected:
    void SetUp() override {
        // Memory leak detection
        leak_detector_ = std::make_unique<MemoryLeakDetector>();
    }

    void TearDown() override {
        leak_detector_->checkpoint();
        if (leak_detector_->has_leaks()) {
            leak_detector_->print_leak_report();
            // Note: Don't fail test on leaks, just report them
        }
    }

    std::unique_ptr<MemoryLeakDetector> leak_detector_;
};

//=============================================================================
// Test Cases
//=============================================================================

/**
 * TEST 1: Brain with PE-enabled attention
 *
 * WHAT: Create full brain, apply PE to inputs, verify processing
 * WHY:  Test complete integration of PE in brain pipeline
 * HOW:  Create brain -> apply PE -> process -> verify output quality
 */
TEST_F(PEPipelineE2ETest, BrainWithPEAttention) {
    PipelineTracker tracker("Brain with PE-Enabled Attention");

    tracker.begin_stage("Create Positional Encoder", 100);
    nimcp_pos_sinusoidal_config_t sin_config = nimcp_pos_sinusoidal_default_config();
    sin_config.base.max_seq_length = MEDIUM_SEQ_LEN;
    sin_config.base.embedding_dim = SMALL_DIM;
    sin_config.base.cache_enabled = true;

    nimcp_pos_config_t config = {
        .type = NIMCP_POS_SINUSOIDAL,
        .config = {.sinusoidal = sin_config}
    };

    nimcp_pos_encoder_t* encoder = nimcp_pos_encoder_create(&config);
    ASSERT_NE(encoder, nullptr) << "Failed to create PE encoder";
    tracker.end_stage();

    tracker.begin_stage("Create Brain Instance", 500);
    nimcp_brain_t brain = nimcp_brain_create(
        "pe_test_brain",
        SMALL_DIM,  // Input: PE-encoded features
        4           // Output: 4 classes
    );
    ASSERT_NE(brain, nullptr) << "Failed to create brain";
    tracker.end_stage();

    tracker.begin_stage("Generate Position-Dependent Patterns", 200);
    auto patterns = SequencePatternGenerator::generate_position_dependent_patterns(
        SHORT_SEQ_LEN, 5
    );
    EXPECT_GT(patterns.size(), 0UL);
    tracker.end_stage();

    tracker.begin_stage("Apply PE to Input Sequences", 500);
    std::vector<std::vector<float>> pe_inputs;
    for (const auto& pattern : patterns) {
        std::vector<float> pe_seq;
        apply_pe_to_sequence(encoder, pattern.data, pe_seq, SMALL_DIM);
        pe_inputs.push_back(pe_seq);
    }
    EXPECT_EQ(pe_inputs.size(), patterns.size());
    tracker.end_stage();

    tracker.begin_stage("Process PE-Encoded Sequences", 1000);
    uint32_t successful_inferences = 0;
    for (size_t i = 0; i < pe_inputs.size(); i++) {
        // Take first position as representative input
        std::vector<float> output(4);
        nimcp_status_t ret = nimcp_brain_infer(brain, pe_inputs[i].data(), SMALL_DIM, output.data(), 4);
        if (ret == NIMCP_OK) {
            successful_inferences++;
        }
    }
    EXPECT_GT(successful_inferences, 0U) << "No successful inferences";
    tracker.end_stage();

    tracker.begin_stage("Verify PE Statistics", 200);
    nimcp_pos_stats_t stats;
    int ret = nimcp_pos_get_stats(encoder, &stats);
    EXPECT_EQ(ret, NIMCP_POS_SUCCESS);
    EXPECT_GT(stats.total_encodings, 0UL) << "No encodings performed";
    tracker.end_stage();

    tracker.begin_stage("Cleanup", 200);
    nimcp_brain_destroy(brain);
    nimcp_pos_encoder_destroy(encoder);
    tracker.end_stage();

    EXPECT_TRUE(tracker.is_successful());
    tracker.print_summary();
}

/**
 * TEST 2: Cognitive pipeline with position-aware processing
 *
 * WHAT: Test PE through cognitive processing pipeline
 * WHY:  Verify PE works in multi-stage cognitive flow
 * HOW:  Perception -> PE -> Memory -> Decision pipeline
 */
TEST_F(PEPipelineE2ETest, CognitivePipelineWithPE) {
    PipelineTracker tracker("Cognitive Pipeline with PE");

    tracker.begin_stage("Initialize PE System", 200);
    nimcp_pos_rope_config_t rope_config = nimcp_pos_rope_default_config();
    rope_config.base.max_seq_length = MEDIUM_SEQ_LEN;
    rope_config.base.embedding_dim = MEDIUM_DIM;
    rope_config.base.cache_enabled = true;

    nimcp_pos_config_t config = {
        .type = NIMCP_POS_ROTARY,
        .config = {.rope = rope_config}
    };

    nimcp_pos_encoder_t* encoder = nimcp_pos_encoder_create(&config);
    ASSERT_NE(encoder, nullptr);
    tracker.end_stage();

    tracker.begin_stage("Create Cognitive Brain", 500);
    nimcp_brain_t brain = nimcp_brain_create(
        "cognitive_pe_brain",
        MEDIUM_DIM,
        MEDIUM_DIM
    );
    ASSERT_NE(brain, nullptr);
    tracker.end_stage();

    tracker.begin_stage("Generate Cognitive Sequence", 200);
    auto patterns = SequencePatternGenerator::generate_language_patterns(
        32, 10
    );
    tracker.end_stage();

    tracker.begin_stage("Process Through Cognitive Pipeline", 2000);
    for (const auto& pattern : patterns) {
        // Stage 1: Perception (raw input)
        std::vector<float> perceived = pattern.data;

        // Stage 2: PE encoding (add position information)
        std::vector<float> pe_encoded;
        apply_pe_to_sequence(encoder, perceived, pe_encoded, MEDIUM_DIM);

        // Stage 3: Cognitive processing (brain inference)
        std::vector<float> output(MEDIUM_DIM);
        nimcp_brain_infer(brain, pe_encoded.data(), MEDIUM_DIM, output.data(), MEDIUM_DIM);

        // Verify output is reasonable
        bool has_activity = false;
        for (float val : output) {
            if (fabsf(val) > 0.01f) {
                has_activity = true;
                break;
            }
        }
        EXPECT_TRUE(has_activity) << "No brain activity detected";
    }
    tracker.end_stage();

    tracker.begin_stage("Verify Pipeline Performance", 200);
    nimcp_pos_stats_t stats;
    nimcp_pos_get_stats(encoder, &stats);

    // Should have cache hits for repeated positions
    EXPECT_GT(stats.cache_hits, 0UL) << "PE cache not being used";
    tracker.end_stage();

    tracker.begin_stage("Cleanup", 200);
    nimcp_brain_destroy(brain);
    nimcp_pos_encoder_destroy(encoder);
    tracker.end_stage();

    EXPECT_TRUE(tracker.is_successful());
    tracker.print_summary();
}

/**
 * TEST 3: Sequence learning with PE
 *
 * WHAT: Train brain to discriminate sequences using PE
 * WHY:  Verify PE improves sequence discrimination accuracy
 * HOW:  Train with/without PE, compare accuracy
 */
TEST_F(PEPipelineE2ETest, SequenceLearningWithPE) {
    PipelineTracker tracker("Sequence Learning with PE");

    tracker.begin_stage("Setup Test Data", 500);
    auto training_patterns = SequencePatternGenerator::generate_position_dependent_patterns(
        SHORT_SEQ_LEN, 20
    );
    auto test_patterns = SequencePatternGenerator::generate_position_dependent_patterns(
        SHORT_SEQ_LEN, 5
    );
    tracker.end_stage();

    // Test WITH positional encoding
    tracker.begin_stage("Create PE Encoder", 100);
    nimcp_pos_sinusoidal_config_t sin_config = nimcp_pos_sinusoidal_default_config();
    sin_config.base.max_seq_length = SHORT_SEQ_LEN;
    sin_config.base.embedding_dim = SMALL_DIM;

    nimcp_pos_config_t config = {
        .type = NIMCP_POS_SINUSOIDAL,
        .config = {.sinusoidal = sin_config}
    };

    nimcp_pos_encoder_t* encoder = nimcp_pos_encoder_create(&config);
    ASSERT_NE(encoder, nullptr);
    tracker.end_stage();

    tracker.begin_stage("Train Brain with PE", 3000);
    brain_t pe_brain = brain_create(
        "pe_sequence_brain",
        SMALL_DIM,
        4  // 4 pattern classes
    );
    ASSERT_NE(pe_brain, nullptr);

    // Simple training loop (simplified for E2E test)
    for (uint32_t epoch = 0; epoch < 10; epoch++) {
        for (const auto& pattern : training_patterns) {
            std::vector<float> pe_input;
            apply_pe_to_sequence(encoder, pattern.data, pe_input, SMALL_DIM);

            std::vector<float> target(4, 0.0f);
            target[pattern.label % 4] = 1.0f;

            std::vector<float> output(4);
            nimcp_brain_infer(pe_brain, pe_input.data(), SMALL_DIM, output.data(), 4);

            // Simplified training step
            nimcp_train_step_result_t train_result;
            nimcp_brain_train_step(pe_brain, pe_input.data(), SMALL_DIM, target.data(), 4, &train_result);
        }
    }
    tracker.end_stage();

    tracker.begin_stage("Evaluate with PE", 1000);
    uint32_t correct = 0;
    for (const auto& pattern : test_patterns) {
        std::vector<float> pe_input;
        apply_pe_to_sequence(encoder, pattern.data, pe_input, SMALL_DIM);

        std::vector<float> output(4);
        nimcp_brain_infer(pe_brain, pe_input.data(), SMALL_DIM, output.data(), 4);

        // Find predicted class
        uint32_t predicted = std::distance(
            output.begin(),
            std::max_element(output.begin(), output.end())
        );

        if (predicted == (pattern.label % 4)) {
            correct++;
        }
    }

    float pe_accuracy = static_cast<float>(correct) / test_patterns.size();
    EXPECT_GT(pe_accuracy, 0.0f) << "PE-enabled brain has zero accuracy";
    tracker.end_stage();

    tracker.begin_stage("Cleanup", 200);
    brain_destroy(pe_brain);
    nimcp_pos_encoder_destroy(encoder);
    tracker.end_stage();

    EXPECT_TRUE(tracker.is_successful());
    tracker.print_summary();
}

/**
 * TEST 4: Performance at scale
 *
 * WHAT: Test PE performance with long sequences
 * WHY:  Verify PE scales to realistic sequence lengths
 * HOW:  Encode progressively longer sequences, measure performance
 */
TEST_F(PEPipelineE2ETest, PerformanceAtScale) {
    PipelineTracker tracker("PE Performance at Scale");

    tracker.begin_stage("Create Scalable PE Encoder", 200);
    nimcp_pos_alibi_config_t alibi_config = nimcp_pos_alibi_default_config();
    alibi_config.base.max_seq_length = VERY_LONG_SEQ_LEN;
    alibi_config.base.embedding_dim = MEDIUM_DIM;
    alibi_config.base.cache_enabled = true;
    alibi_config.num_heads = 8;

    nimcp_pos_config_t config = {
        .type = NIMCP_POS_ALIBI,
        .config = {.alibi = alibi_config}
    };

    nimcp_pos_encoder_t* encoder = nimcp_pos_encoder_create(&config);
    ASSERT_NE(encoder, nullptr);
    tracker.end_stage();

    // Test different sequence lengths
    std::vector<uint32_t> seq_lengths = {64, 256, 512, 1024, 2048};

    for (uint32_t seq_len : seq_lengths) {
        std::string stage_name = "Encode Length " + std::to_string(seq_len);
        tracker.begin_stage(stage_name, 5000);

        auto metrics = measure_pe_performance(encoder, seq_len, 10);

        // Verify performance is reasonable
        EXPECT_LT(metrics.encoding_time_us, 10000.0f)
            << "Encoding too slow for seq_len=" << seq_len;

        // Cache should be effective
        EXPECT_GT(metrics.cache_hit_rate, 0.5f)
            << "Low cache hit rate for seq_len=" << seq_len;

        tracker.end_stage();
    }

    tracker.begin_stage("Verify Scaling Characteristics", 500);
    nimcp_pos_stats_t stats;
    nimcp_pos_get_stats(encoder, &stats);

    EXPECT_GT(stats.total_encodings, 0UL);
    EXPECT_LT(stats.avg_encoding_time_us, 5000.0f)
        << "Average encoding time too high";
    tracker.end_stage();

    tracker.begin_stage("Cleanup", 200);
    nimcp_pos_encoder_destroy(encoder);
    tracker.end_stage();

    EXPECT_TRUE(tracker.is_successful());
    tracker.print_summary();
}

/**
 * TEST 5: PE type comparison
 *
 * WHAT: Compare all PE types on same sequence task
 * WHY:  Understand relative performance of different PE methods
 * HOW:  Run same task with Sinusoidal, RoPE, ALiBi, Learned, Relative
 */
TEST_F(PEPipelineE2ETest, PETypeComparison) {
    PipelineTracker tracker("PE Type Comparison");

    tracker.begin_stage("Generate Test Sequences", 300);
    auto patterns = SequencePatternGenerator::generate_position_dependent_patterns(
        32, 10
    );
    tracker.end_stage();

    std::vector<PETypeResults> results;

    // Test each PE type
    std::vector<nimcp_pos_encoding_type_t> types = {
        NIMCP_POS_SINUSOIDAL,
        NIMCP_POS_ROTARY,
        NIMCP_POS_ALIBI,
        NIMCP_POS_LEARNED,
        NIMCP_POS_RELATIVE
    };

    for (auto type : types) {
        std::string type_name = nimcp_pos_type_to_string(type);
        std::string stage_name = "Test " + std::string(type_name);

        tracker.begin_stage(stage_name, 3000);

        PETypeResults result;
        result.type = type;

        // Create encoder for this type
        nimcp_pos_config_t config;
        config.type = type;

        switch (type) {
            case NIMCP_POS_SINUSOIDAL:
                config.config.sinusoidal = nimcp_pos_sinusoidal_default_config();
                config.config.sinusoidal.base.max_seq_length = 32;
                config.config.sinusoidal.base.embedding_dim = SMALL_DIM;
                break;
            case NIMCP_POS_ROTARY:
                config.config.rope = nimcp_pos_rope_default_config();
                config.config.rope.base.max_seq_length = 32;
                config.config.rope.base.embedding_dim = SMALL_DIM;
                break;
            case NIMCP_POS_ALIBI:
                config.config.alibi = nimcp_pos_alibi_default_config();
                config.config.alibi.base.max_seq_length = 32;
                config.config.alibi.base.embedding_dim = SMALL_DIM;
                break;
            case NIMCP_POS_LEARNED:
                config.config.learned = nimcp_pos_learned_default_config();
                config.config.learned.base.max_seq_length = 32;
                config.config.learned.base.embedding_dim = SMALL_DIM;
                break;
            case NIMCP_POS_RELATIVE:
                config.config.relative = nimcp_pos_relative_default_config();
                config.config.relative.base.max_seq_length = 32;
                config.config.relative.base.embedding_dim = SMALL_DIM;
                break;
            default:
                continue;
        }

        nimcp_pos_encoder_t* encoder = nimcp_pos_encoder_create(&config);
        if (encoder) {
            // Measure encoding performance
            Timer timer;
            timer.start();

            for (const auto& pattern : patterns) {
                std::vector<float> pe_seq;
                apply_pe_to_sequence(encoder, pattern.data, pe_seq, SMALL_DIM);
            }

            timer.stop();
            result.inference_time_us = static_cast<float>(timer.elapsed_us()) / patterns.size();

            // Get memory usage
            nimcp_pos_stats_t stats;
            nimcp_pos_get_stats(encoder, &stats);
            result.memory_bytes = stats.memory_usage_bytes;

            nimcp_pos_encoder_destroy(encoder);
        }

        results.push_back(result);
        tracker.end_stage();
    }

    tracker.begin_stage("Compare Results", 200);
    EXPECT_EQ(results.size(), types.size()) << "Not all PE types tested";

    // Verify all types completed successfully
    for (const auto& result : results) {
        const char* type_name = nimcp_pos_type_to_string(result.type);
        EXPECT_GT(result.memory_bytes, 0UL)
            << type_name << " has zero memory usage";
    }
    tracker.end_stage();

    EXPECT_TRUE(tracker.is_successful());
    tracker.print_summary();
}

/**
 * TEST 6: Sequence extrapolation
 *
 * WHAT: Test PE beyond training length
 * WHY:  Verify PE generalizes to longer sequences
 * HOW:  Train on short sequences, test on longer ones
 */
TEST_F(PEPipelineE2ETest, SequenceExtrapolation) {
    PipelineTracker tracker("Sequence Extrapolation");

    tracker.begin_stage("Create Encoder for Extrapolation", 200);
    // Use RoPE which is designed for good extrapolation
    nimcp_pos_rope_config_t rope_config = nimcp_pos_rope_default_config();
    rope_config.base.max_seq_length = MEDIUM_SEQ_LEN;
    rope_config.base.embedding_dim = SMALL_DIM;
    rope_config.use_ntk_scaling = true;  // Better extrapolation

    nimcp_pos_config_t config = {
        .type = NIMCP_POS_ROTARY,
        .config = {.rope = rope_config}
    };

    nimcp_pos_encoder_t* encoder = nimcp_pos_encoder_create(&config);
    ASSERT_NE(encoder, nullptr);
    tracker.end_stage();

    tracker.begin_stage("Encode Short Sequences (Training Length)", 500);
    uint32_t train_length = 16;
    std::vector<float> output_short(train_length * SMALL_DIM);
    int ret = nimcp_pos_encode_sequence(encoder, 0, train_length, output_short.data());
    EXPECT_EQ(ret, NIMCP_POS_SUCCESS);
    tracker.end_stage();

    tracker.begin_stage("Encode Long Sequences (2x Training Length)", 1000);
    uint32_t test_length = 32;
    std::vector<float> output_long(test_length * SMALL_DIM);
    ret = nimcp_pos_encode_sequence(encoder, 0, test_length, output_long.data());
    EXPECT_EQ(ret, NIMCP_POS_SUCCESS);
    tracker.end_stage();

    tracker.begin_stage("Verify Extrapolation Quality", 500);
    // Check that encodings for positions 0-15 are similar in both cases
    float max_diff = 0.0f;
    for (uint32_t pos = 0; pos < train_length; pos++) {
        for (uint32_t d = 0; d < SMALL_DIM; d++) {
            uint32_t idx = pos * SMALL_DIM + d;
            float diff = fabsf(output_short[idx] - output_long[idx]);
            max_diff = std::max(max_diff, diff);
        }
    }

    // Encodings should be identical for overlapping positions
    EXPECT_LT(max_diff, 0.01f) << "PE changed for same positions at different lengths";

    // Verify new positions have reasonable encodings
    bool has_variation = false;
    for (uint32_t pos = train_length; pos < test_length; pos++) {
        for (uint32_t d = 0; d < SMALL_DIM; d++) {
            uint32_t idx = pos * SMALL_DIM + d;
            if (fabsf(output_long[idx]) > 0.01f) {
                has_variation = true;
                break;
            }
        }
    }
    EXPECT_TRUE(has_variation) << "Extrapolated positions have no variation";
    tracker.end_stage();

    tracker.begin_stage("Cleanup", 200);
    nimcp_pos_encoder_destroy(encoder);
    tracker.end_stage();

    EXPECT_TRUE(tracker.is_successful());
    tracker.print_summary();
}

/**
 * TEST 7: Memory integration
 *
 * WHAT: Test PE with memory system for sequential storage
 * WHY:  Verify PE works in memory-augmented architectures
 * HOW:  Store PE-encoded sequences, retrieve and verify consistency
 */
TEST_F(PEPipelineE2ETest, MemoryIntegration) {
    PipelineTracker tracker("PE with Memory Integration");

    tracker.begin_stage("Initialize PE System", 200);
    nimcp_pos_sinusoidal_config_t sin_config = nimcp_pos_sinusoidal_default_config();
    sin_config.base.max_seq_length = SHORT_SEQ_LEN;
    sin_config.base.embedding_dim = SMALL_DIM;
    sin_config.base.cache_enabled = true;

    nimcp_pos_config_t config = {
        .type = NIMCP_POS_SINUSOIDAL,
        .config = {.sinusoidal = sin_config}
    };

    nimcp_pos_encoder_t* encoder = nimcp_pos_encoder_create(&config);
    ASSERT_NE(encoder, nullptr);
    tracker.end_stage();

    tracker.begin_stage("Encode and Store Sequences", 1000);
    std::vector<std::vector<float>> stored_sequences;

    for (uint32_t seq_id = 0; seq_id < 10; seq_id++) {
        std::vector<float> pe_seq(SHORT_SEQ_LEN * SMALL_DIM);
        int ret = nimcp_pos_encode_sequence(encoder, 0, SHORT_SEQ_LEN, pe_seq.data());
        EXPECT_EQ(ret, NIMCP_POS_SUCCESS);
        stored_sequences.push_back(pe_seq);
    }

    EXPECT_EQ(stored_sequences.size(), 10UL);
    tracker.end_stage();

    tracker.begin_stage("Retrieve and Verify Sequences", 1000);
    // All sequences should be identical (same positions encoded)
    for (size_t i = 1; i < stored_sequences.size(); i++) {
        EXPECT_EQ(stored_sequences[0], stored_sequences[i])
            << "PE encodings not consistent across retrievals";
    }
    tracker.end_stage();

    tracker.begin_stage("Verify Cache Effectiveness", 200);
    nimcp_pos_stats_t stats;
    nimcp_pos_get_stats(encoder, &stats);

    // Should have many cache hits from repeated encoding
    float cache_hit_rate = 0.0f;
    if (stats.cache_hits + stats.cache_misses > 0) {
        cache_hit_rate = static_cast<float>(stats.cache_hits) /
                        (stats.cache_hits + stats.cache_misses);
    }

    EXPECT_GT(cache_hit_rate, 0.8f) << "Cache not effective for repeated accesses";
    tracker.end_stage();

    tracker.begin_stage("Cleanup", 200);
    nimcp_pos_encoder_destroy(encoder);
    tracker.end_stage();

    EXPECT_TRUE(tracker.is_successful());
    tracker.print_summary();
}

/**
 * TEST 8: Real-world sequence patterns
 *
 * WHAT: Test PE on realistic multi-modal sequences
 * WHY:  Verify PE handles complex real-world patterns
 * HOW:  Generate audio-like, vision-like temporal patterns
 */
TEST_F(PEPipelineE2ETest, RealWorldSequencePatterns) {
    PipelineTracker tracker("Real-World Sequence Patterns");

    tracker.begin_stage("Create Multi-Purpose PE Encoder", 200);
    nimcp_pos_sinusoidal_config_t sin_config = nimcp_pos_sinusoidal_default_config();
    sin_config.base.max_seq_length = MEDIUM_SEQ_LEN;
    sin_config.base.embedding_dim = MEDIUM_DIM;
    sin_config.base.cache_enabled = true;

    nimcp_pos_config_t config = {
        .type = NIMCP_POS_SINUSOIDAL,
        .config = {.sinusoidal = sin_config}
    };

    nimcp_pos_encoder_t* encoder = nimcp_pos_encoder_create(&config);
    ASSERT_NE(encoder, nullptr);
    tracker.end_stage();

    tracker.begin_stage("Process Audio-Like Temporal Sequence", 1000);
    // Simulate audio waveform (time series with temporal structure)
    std::vector<float> audio_sequence(128);
    for (uint32_t t = 0; t < 128; t++) {
        audio_sequence[t] = sinf(2.0f * M_PI * t / 16.0f);  // 8 Hz signal
    }

    std::vector<float> pe_audio;
    apply_pe_to_sequence(encoder, audio_sequence, pe_audio, MEDIUM_DIM);

    // Verify encoding succeeded
    EXPECT_EQ(pe_audio.size(), 128 * MEDIUM_DIM);

    bool has_temporal_info = false;
    for (size_t i = 0; i < pe_audio.size(); i++) {
        if (fabsf(pe_audio[i]) > 0.1f) {
            has_temporal_info = true;
            break;
        }
    }
    EXPECT_TRUE(has_temporal_info) << "PE did not add temporal information";
    tracker.end_stage();

    tracker.begin_stage("Process Vision-Like Frame Sequence", 1000);
    // Simulate video frames (spatial-temporal structure)
    std::vector<float> frame_sequence(64);
    for (uint32_t f = 0; f < 64; f++) {
        // Simulate frame intensity changing over time
        frame_sequence[f] = 0.5f + 0.5f * sinf(2.0f * M_PI * f / 32.0f);
    }

    std::vector<float> pe_frames;
    apply_pe_to_sequence(encoder, frame_sequence, pe_frames, MEDIUM_DIM);

    EXPECT_EQ(pe_frames.size(), 64 * MEDIUM_DIM);
    tracker.end_stage();

    tracker.begin_stage("Process Language-Like Token Sequence", 1000);
    auto language_patterns = SequencePatternGenerator::generate_language_patterns(32, 5);

    for (const auto& pattern : language_patterns) {
        std::vector<float> pe_tokens;
        apply_pe_to_sequence(encoder, pattern.data, pe_tokens, MEDIUM_DIM);
        EXPECT_EQ(pe_tokens.size(), 32 * MEDIUM_DIM);
    }
    tracker.end_stage();

    tracker.begin_stage("Verify Performance Across Modalities", 500);
    nimcp_pos_stats_t stats;
    nimcp_pos_get_stats(encoder, &stats);

    EXPECT_GT(stats.total_encodings, 0UL);
    EXPECT_LT(stats.avg_encoding_time_us, 1000.0f)
        << "Encoding too slow for real-time processing";
    tracker.end_stage();

    tracker.begin_stage("Cleanup", 200);
    nimcp_pos_encoder_destroy(encoder);
    tracker.end_stage();

    EXPECT_TRUE(tracker.is_successful());
    tracker.print_summary();
}

//=============================================================================
// Main
//=============================================================================

int main(int argc, char** argv) {
    ::testing::InitGoogleTest(&argc, argv);
    return RUN_ALL_TESTS();
}
