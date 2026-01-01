/**
 * @file test_e2e_cognitive_processing_gpu.cpp
 * @brief E2E Tests for GPU-Accelerated Cognitive Processing
 *
 * WHAT: End-to-end testing of cognitive task execution on GPU
 * WHY:  Verify complete cognitive pipelines work correctly with GPU acceleration
 * HOW:  Test JEPA prediction, Broca language production, attention, and reasoning
 *
 * TEST PIPELINES:
 * - JEPALatentPrediction: JEPA world model prediction on GPU
 * - BrocaLanguageProduction: Language production pipeline on GPU
 * - AttentionMechanism: Multi-head attention processing on GPU
 * - CognitiveReasoning: Multi-step reasoning with GPU acceleration
 * - GPUvsCPUAccuracy: Verify GPU results match CPU within tolerance
 * - PerformanceBenchmark: Measure cognitive processing throughput
 *
 * @author NIMCP Development Team
 * @date 2025-12-31
 * @version 1.0.0
 */

#include "../e2e_test_framework.h"

extern "C" {
#include "gpu/nimcp_execution_mode.h"
#include "gpu/context/nimcp_gpu_context.h"
#include "gpu/tensor/nimcp_tensor_gpu.h"
#include "gpu/cognitive/nimcp_jepa_gpu.h"
#include "gpu/cognitive/nimcp_broca_gpu.h"
#include "utils/memory/nimcp_memory.h"
}

#include <thread>
#include <atomic>
#include <vector>
#include <string>
#include <cstring>
#include <cmath>
#include <chrono>
#include <random>
#include <numeric>
#include <algorithm>

//=============================================================================
// Test Metrics Structure
//=============================================================================

struct CognitiveMetrics {
    double gpu_time_ms;
    double cpu_time_ms;
    double speedup;
    size_t memory_usage_bytes;
    double numerical_accuracy;
    double throughput_ops_per_sec;
    uint64_t total_operations;
    double latency_ms;
};

//=============================================================================
// Test Fixture
//=============================================================================

class CognitiveProcessingGPUE2ETest : public ::testing::Test {
protected:
    nimcp_gpu_context_t* gpu_ctx_ = nullptr;
    hardware_capabilities_t caps_;
    bool has_gpu_ = false;
    std::mt19937 rng_;
    CognitiveMetrics metrics_;

    void SetUp() override {
        memset(&caps_, 0, sizeof(caps_));
        memset(&metrics_, 0, sizeof(metrics_));

        execution_detect_capabilities(&caps_);
        has_gpu_ = caps_.cuda_available || caps_.rocm_available || caps_.opencl_available;

        if (has_gpu_) {
            gpu_ctx_ = nimcp_gpu_context_create_auto();
        }

        rng_.seed(42);
    }

    void TearDown() override {
        if (gpu_ctx_) {
            nimcp_gpu_context_destroy(gpu_ctx_);
            gpu_ctx_ = nullptr;
        }
    }

    bool HasGPU() const { return has_gpu_ && gpu_ctx_ != nullptr; }

    void GenerateLatentVectors(size_t batch_size, size_t latent_dim,
                               std::vector<float>& data) {
        data.resize(batch_size * latent_dim);
        std::uniform_real_distribution<float> dist(-1.0f, 1.0f);
        for (auto& v : data) {
            v = dist(rng_);
        }
    }

    double ComputeNumericalAccuracy(const std::vector<float>& cpu_result,
                                    const std::vector<float>& gpu_result) {
        if (cpu_result.size() != gpu_result.size()) return -1.0;
        double max_diff = 0.0;
        for (size_t i = 0; i < cpu_result.size(); i++) {
            double diff = std::abs(cpu_result[i] - gpu_result[i]);
            max_diff = std::max(max_diff, diff);
        }
        return max_diff;
    }

    void PrintMetrics(const std::string& test_name) {
        std::cout << "\n=== " << test_name << " Metrics ===" << std::endl;
        std::cout << "  GPU Time: " << metrics_.gpu_time_ms << " ms" << std::endl;
        std::cout << "  CPU Time: " << metrics_.cpu_time_ms << " ms" << std::endl;
        std::cout << "  Speedup: " << metrics_.speedup << "x" << std::endl;
        std::cout << "  Memory Usage: " << (metrics_.memory_usage_bytes / 1024.0 / 1024.0)
                  << " MB" << std::endl;
        std::cout << "  Numerical Accuracy (max diff): " << metrics_.numerical_accuracy << std::endl;
        std::cout << "  Throughput: " << metrics_.throughput_ops_per_sec
                  << " ops/sec" << std::endl;
        std::cout << "  Latency: " << metrics_.latency_ms << " ms" << std::endl;
    }
};

//=============================================================================
// Pipeline 1: JEPA Latent Space Prediction
//=============================================================================

TEST_F(CognitiveProcessingGPUE2ETest, JEPALatentPredictionGPU) {
    E2E_PIPELINE_START("JEPA Latent Prediction on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const size_t BATCH_SIZE = 32;
    const size_t INPUT_DIM = 256;
    const size_t HIDDEN_DIM = 512;
    const size_t OUTPUT_DIM = 256;
    const size_t NUM_LAYERS = 3;

    // Stage 1: Create JEPA predictor
    E2E_STAGE_BEGIN("Create JEPA GPU predictor", 2000);

    nimcp_jepa_gpu_predictor_t* predictor = nimcp_jepa_gpu_predictor_create(
        gpu_ctx_, INPUT_DIM, HIDDEN_DIM, OUTPUT_DIM, NUM_LAYERS, NIMCP_JEPA_ACT_GELU);
    E2E_ASSERT_NOT_NULL(predictor, "Failed to create JEPA predictor");

    std::cout << "\n  JEPA Predictor Configuration:" << std::endl;
    std::cout << "    Input dim: " << INPUT_DIM << std::endl;
    std::cout << "    Hidden dim: " << HIDDEN_DIM << std::endl;
    std::cout << "    Output dim: " << OUTPUT_DIM << std::endl;
    std::cout << "    Layers: " << NUM_LAYERS << std::endl;

    E2E_STAGE_END();

    // Stage 2: Initialize weights
    E2E_STAGE_BEGIN("Initialize predictor weights", 1000);

    std::vector<float> weights_data;
    std::vector<float> bias_data;
    std::uniform_real_distribution<float> w_dist(-0.1f, 0.1f);

    for (uint32_t layer = 0; layer < NUM_LAYERS; layer++) {
        size_t in_size = (layer == 0) ? INPUT_DIM : HIDDEN_DIM;
        size_t out_size = (layer == NUM_LAYERS - 1) ? OUTPUT_DIM : HIDDEN_DIM;

        weights_data.resize(in_size * out_size);
        bias_data.resize(out_size);

        for (auto& w : weights_data) w = w_dist(rng_);
        for (auto& b : bias_data) b = 0.0f;

        bool success = nimcp_jepa_gpu_predictor_upload_weights(
            predictor, layer, weights_data.data(), bias_data.data());
        E2E_ASSERT(success, "Failed to upload weights for layer " + std::to_string(layer));
    }

    E2E_STAGE_END();

    // Stage 3: Create input/output tensors
    E2E_STAGE_BEGIN("Create latent tensors", 500);

    size_t input_dims[] = {BATCH_SIZE, INPUT_DIM};
    size_t output_dims[] = {BATCH_SIZE, OUTPUT_DIM};

    nimcp_gpu_tensor_t* context = nimcp_gpu_tensor_create(gpu_ctx_, input_dims, 2,
                                                           NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* prediction = nimcp_gpu_tensor_create(gpu_ctx_, output_dims, 2,
                                                              NIMCP_GPU_PRECISION_FP32);

    E2E_ASSERT_NOT_NULL(context, "Failed to create context tensor");
    E2E_ASSERT_NOT_NULL(prediction, "Failed to create prediction tensor");

    // Initialize context with latent vectors
    std::vector<float> context_data;
    GenerateLatentVectors(BATCH_SIZE, INPUT_DIM, context_data);
    nimcp_gpu_memcpy(gpu_ctx_, context->data, context_data.data(),
                     context_data.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    E2E_STAGE_END();

    // Stage 4: Forward prediction
    E2E_STAGE_BEGIN("JEPA forward prediction", 5000);

    const int NUM_ITERATIONS = 100;
    auto start = std::chrono::high_resolution_clock::now();

    for (int i = 0; i < NUM_ITERATIONS; i++) {
        bool success = nimcp_jepa_gpu_forward_predict(predictor, context, prediction);
        E2E_ASSERT(success, "JEPA forward prediction failed");
    }

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(end - start).count();
    metrics_.latency_ms = metrics_.gpu_time_ms / NUM_ITERATIONS;

    std::vector<float> prediction_data(BATCH_SIZE * OUTPUT_DIM);
    nimcp_gpu_memcpy(gpu_ctx_, prediction_data.data(), prediction->data,
                     prediction_data.size() * sizeof(float), GPU_MEMCPY_DEVICE_TO_HOST);

    // Verify predictions are non-zero (network is producing output)
    float sum = std::accumulate(prediction_data.begin(), prediction_data.end(), 0.0f);
    std::cout << "\n  Prediction sum: " << sum << std::endl;
    std::cout << "  Average latency: " << metrics_.latency_ms << " ms" << std::endl;

    EXPECT_NE(sum, 0.0f) << "Predictions should be non-zero";

    E2E_STAGE_END();

    // Stage 5: Test masked prediction
    E2E_STAGE_BEGIN("JEPA masked prediction", 2000);

    size_t mask_dims[] = {BATCH_SIZE, INPUT_DIM};
    nimcp_gpu_tensor_t* mask = nimcp_gpu_tensor_create(gpu_ctx_, mask_dims, 2,
                                                        NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* masked_context = nimcp_gpu_tensor_create(gpu_ctx_, mask_dims, 2,
                                                                  NIMCP_GPU_PRECISION_FP32);

    bool success = nimcp_jepa_gpu_generate_block_mask(gpu_ctx_, mask, 16, 0.3f);
    E2E_ASSERT(success, "Failed to generate block mask");

    success = nimcp_jepa_gpu_apply_mask(gpu_ctx_, context, mask, masked_context);
    E2E_ASSERT(success, "Failed to apply mask");

    success = nimcp_jepa_gpu_forward_predict(predictor, masked_context, prediction);
    E2E_ASSERT(success, "Masked prediction failed");

    nimcp_gpu_tensor_destroy(mask);
    nimcp_gpu_tensor_destroy(masked_context);

    E2E_STAGE_END();

    // Stage 6: Compute loss
    E2E_STAGE_BEGIN("Compute prediction loss", 1000);

    nimcp_gpu_tensor_t* target = nimcp_gpu_tensor_create(gpu_ctx_, output_dims, 2,
                                                          NIMCP_GPU_PRECISION_FP32);

    std::vector<float> target_data;
    GenerateLatentVectors(BATCH_SIZE, OUTPUT_DIM, target_data);
    nimcp_gpu_memcpy(gpu_ctx_, target->data, target_data.data(),
                     target_data.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    float loss = 0.0f;
    success = nimcp_jepa_gpu_compute_loss(gpu_ctx_, prediction, target, nullptr, &loss);
    E2E_ASSERT(success, "Loss computation failed");

    std::cout << "\n  Prediction loss (MSE): " << loss << std::endl;
    EXPECT_GT(loss, 0.0f) << "Loss should be positive";

    nimcp_gpu_tensor_destroy(target);

    E2E_STAGE_END();

    // Cleanup
    nimcp_gpu_tensor_destroy(context);
    nimcp_gpu_tensor_destroy(prediction);
    nimcp_jepa_gpu_predictor_destroy(predictor);

    metrics_.throughput_ops_per_sec = (NUM_ITERATIONS * BATCH_SIZE) / (metrics_.gpu_time_ms / 1000.0);
    PrintMetrics("JEPA Latent Prediction GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 2: Broca Language Production
//=============================================================================

TEST_F(CognitiveProcessingGPUE2ETest, BrocaLanguageProductionGPU) {
    E2E_PIPELINE_START("Broca Language Production on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const uint32_t LEXICON_SIZE = 10000;
    const uint32_t BATCH_SIZE = 64;
    const uint32_t MAX_PHONEMES_PER_WORD = 16;

    // Stage 1: Create Broca GPU context
    E2E_STAGE_BEGIN("Create Broca GPU context", 2000);

    broca_gpu_config_t config = broca_gpu_default_config();
    config.max_lexicon_size = LEXICON_SIZE;
    config.max_batch_size = BATCH_SIZE;
    config.enable_coarticulation = true;

    broca_gpu_context_t* broca = broca_gpu_create(gpu_ctx_, &config);
    E2E_ASSERT_NOT_NULL(broca, "Failed to create Broca GPU context");

    E2E_STAGE_END();

    // Stage 2: Upload lexicon
    E2E_STAGE_BEGIN("Upload lexicon to GPU", 3000);

    std::vector<broca_gpu_lexical_entry_t> lexicon(LEXICON_SIZE);
    std::uniform_int_distribution<uint32_t> phoneme_count_dist(2, MAX_PHONEMES_PER_WORD);
    std::uniform_int_distribution<uint8_t> phoneme_dist(1, 44);  // ~44 English phonemes
    std::uniform_real_distribution<float> freq_dist(0.0001f, 1.0f);

    for (uint32_t i = 0; i < LEXICON_SIZE; i++) {
        lexicon[i].word_id = i;
        lexicon[i].phoneme_count = phoneme_count_dist(rng_);
        for (uint32_t p = 0; p < lexicon[i].phoneme_count; p++) {
            lexicon[i].phonemes[p] = phoneme_dist(rng_);
        }
        lexicon[i].pos = static_cast<uint8_t>(i % 8);  // 8 parts of speech
        lexicon[i].frequency = freq_dist(rng_);
        lexicon[i].activation = 0.0f;
    }

    bool success = broca_gpu_upload_lexicon(broca, lexicon.data(), LEXICON_SIZE);
    E2E_ASSERT(success, "Failed to upload lexicon");

    std::cout << "\n  Lexicon size: " << LEXICON_SIZE << " entries" << std::endl;

    E2E_STAGE_END();

    // Stage 3: Batch lexical lookup
    E2E_STAGE_BEGIN("Batch lexical lookup", 2000);

    std::vector<uint32_t> word_ids(BATCH_SIZE);
    std::uniform_int_distribution<uint32_t> word_dist(0, LEXICON_SIZE - 1);
    for (auto& id : word_ids) {
        id = word_dist(rng_);
    }

    std::vector<broca_gpu_lookup_result_t> results(BATCH_SIZE);

    auto lookup_start = std::chrono::high_resolution_clock::now();

    for (int iter = 0; iter < 100; iter++) {
        success = broca_gpu_batch_lexical_lookup(broca, word_ids.data(), BATCH_SIZE, results.data());
        E2E_ASSERT(success, "Batch lexical lookup failed");
    }

    broca_gpu_synchronize(broca);
    auto lookup_end = std::chrono::high_resolution_clock::now();
    double lookup_time = std::chrono::duration<double, std::milli>(lookup_end - lookup_start).count();

    int found_count = 0;
    for (const auto& r : results) {
        if (r.found) found_count++;
    }

    std::cout << "\n  Found " << found_count << "/" << BATCH_SIZE << " words" << std::endl;
    std::cout << "  Lookup time (100 batches): " << lookup_time << " ms" << std::endl;

    EXPECT_EQ(found_count, static_cast<int>(BATCH_SIZE)) << "All words should be found";

    E2E_STAGE_END();

    // Stage 4: Phonological encoding
    E2E_STAGE_BEGIN("Phonological encoding", 2000);

    const size_t MAX_PHONEMES = BATCH_SIZE * MAX_PHONEMES_PER_WORD;
    std::vector<uint8_t> phoneme_buffer(MAX_PHONEMES);
    uint32_t phoneme_count = 0;
    std::vector<uint32_t> word_boundaries(BATCH_SIZE + 1);

    auto encode_start = std::chrono::high_resolution_clock::now();

    success = broca_gpu_encode_phonemes(broca, word_ids.data(), BATCH_SIZE,
                                         phoneme_buffer.data(), MAX_PHONEMES,
                                         &phoneme_count, word_boundaries.data());
    E2E_ASSERT(success, "Phoneme encoding failed");

    broca_gpu_synchronize(broca);
    auto encode_end = std::chrono::high_resolution_clock::now();
    double encode_time = std::chrono::duration<double, std::milli>(encode_end - encode_start).count();

    std::cout << "\n  Encoded " << phoneme_count << " phonemes" << std::endl;
    std::cout << "  Encoding time: " << encode_time << " ms" << std::endl;

    EXPECT_GT(phoneme_count, 0u) << "Should encode some phonemes";

    E2E_STAGE_END();

    // Stage 5: Apply coarticulation
    E2E_STAGE_BEGIN("Coarticulation processing", 1000);

    success = broca_gpu_apply_coarticulation(broca, phoneme_buffer.data(),
                                              phoneme_count, 0.5f);
    E2E_ASSERT(success, "Coarticulation failed");

    E2E_STAGE_END();

    // Stage 6: Motor command generation
    E2E_STAGE_BEGIN("Motor command generation", 2000);

    const uint32_t MAX_COMMANDS = phoneme_count * 6;  // ~6 articulators per phoneme
    std::vector<broca_gpu_motor_command_t> commands(MAX_COMMANDS);
    uint32_t command_count = 0;

    auto motor_start = std::chrono::high_resolution_clock::now();

    success = broca_gpu_generate_motor_commands(broca, phoneme_buffer.data(),
                                                 phoneme_count, commands.data(),
                                                 MAX_COMMANDS, &command_count, 0.0f);
    E2E_ASSERT(success, "Motor command generation failed");

    broca_gpu_synchronize(broca);
    auto motor_end = std::chrono::high_resolution_clock::now();
    double motor_time = std::chrono::duration<double, std::milli>(motor_end - motor_start).count();

    std::cout << "\n  Generated " << command_count << " motor commands" << std::endl;
    std::cout << "  Motor command time: " << motor_time << " ms" << std::endl;

    EXPECT_GT(command_count, 0u) << "Should generate motor commands";

    E2E_STAGE_END();

    // Stage 7: Full utterance production pipeline
    E2E_STAGE_BEGIN("Full utterance production", 3000);

    std::vector<broca_gpu_motor_command_t> utterance_commands(MAX_COMMANDS);
    uint32_t utterance_cmd_count = 0;

    auto utterance_start = std::chrono::high_resolution_clock::now();

    for (int iter = 0; iter < 100; iter++) {
        success = broca_gpu_produce_utterance(broca, word_ids.data(), BATCH_SIZE,
                                               utterance_commands.data(), MAX_COMMANDS,
                                               &utterance_cmd_count, 0.0f);
        E2E_ASSERT(success, "Utterance production failed");
    }

    broca_gpu_synchronize(broca);
    auto utterance_end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(
        utterance_end - utterance_start).count();

    std::cout << "\n  Utterance commands: " << utterance_cmd_count << std::endl;
    std::cout << "  Pipeline time (100 iterations): " << metrics_.gpu_time_ms << " ms" << std::endl;

    E2E_STAGE_END();

    // Stage 8: Get statistics
    E2E_STAGE_BEGIN("Collect statistics", 500);

    broca_gpu_stats_t stats;
    success = broca_gpu_get_stats(broca, &stats);
    E2E_ASSERT(success, "Failed to get stats");

    std::cout << "\n  GPU Statistics:" << std::endl;
    std::cout << "    Lexical lookups: " << stats.lexical_lookups << std::endl;
    std::cout << "    Phonemes encoded: " << stats.phonemes_encoded << std::endl;
    std::cout << "    Motor commands: " << stats.motor_commands << std::endl;
    std::cout << "    GPU memory used: " << (stats.gpu_memory_used / 1024.0 / 1024.0) << " MB" << std::endl;

    metrics_.memory_usage_bytes = stats.gpu_memory_used;

    E2E_STAGE_END();

    broca_gpu_destroy(broca);

    metrics_.throughput_ops_per_sec = (100 * BATCH_SIZE) / (metrics_.gpu_time_ms / 1000.0);
    PrintMetrics("Broca Language Production GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 3: Multi-Head Attention on GPU
//=============================================================================

TEST_F(CognitiveProcessingGPUE2ETest, MultiHeadAttentionGPU) {
    E2E_PIPELINE_START("Multi-Head Attention on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const size_t BATCH_SIZE = 16;
    const size_t SEQ_LEN = 128;
    const size_t D_MODEL = 512;
    const size_t NUM_HEADS = 8;
    const size_t D_HEAD = D_MODEL / NUM_HEADS;

    // Stage 1: Create attention tensors
    E2E_STAGE_BEGIN("Create attention tensors", 2000);

    size_t qkv_dims[] = {BATCH_SIZE, SEQ_LEN, D_MODEL};
    size_t attn_dims[] = {BATCH_SIZE, NUM_HEADS, SEQ_LEN, SEQ_LEN};
    size_t head_dims[] = {BATCH_SIZE, NUM_HEADS, SEQ_LEN, D_HEAD};

    nimcp_gpu_tensor_t* query = nimcp_gpu_tensor_create(gpu_ctx_, qkv_dims, 3, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* key = nimcp_gpu_tensor_create(gpu_ctx_, qkv_dims, 3, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* value = nimcp_gpu_tensor_create(gpu_ctx_, qkv_dims, 3, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* attn_weights = nimcp_gpu_tensor_create(gpu_ctx_, attn_dims, 4, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* output = nimcp_gpu_tensor_create(gpu_ctx_, qkv_dims, 3, NIMCP_GPU_PRECISION_FP32);

    E2E_ASSERT_NOT_NULL(query, "Failed to create query tensor");
    E2E_ASSERT_NOT_NULL(key, "Failed to create key tensor");
    E2E_ASSERT_NOT_NULL(value, "Failed to create value tensor");

    // Initialize with random values
    size_t total_elements = BATCH_SIZE * SEQ_LEN * D_MODEL;
    std::vector<float> data(total_elements);
    std::normal_distribution<float> dist(0.0f, 0.02f);
    for (auto& v : data) v = dist(rng_);

    nimcp_gpu_memcpy(gpu_ctx_, query->data, data.data(), total_elements * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);
    for (auto& v : data) v = dist(rng_);
    nimcp_gpu_memcpy(gpu_ctx_, key->data, data.data(), total_elements * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);
    for (auto& v : data) v = dist(rng_);
    nimcp_gpu_memcpy(gpu_ctx_, value->data, data.data(), total_elements * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    std::cout << "\n  Attention Configuration:" << std::endl;
    std::cout << "    Batch size: " << BATCH_SIZE << std::endl;
    std::cout << "    Sequence length: " << SEQ_LEN << std::endl;
    std::cout << "    Model dimension: " << D_MODEL << std::endl;
    std::cout << "    Number of heads: " << NUM_HEADS << std::endl;

    E2E_STAGE_END();

    // Stage 2: Compute Q @ K^T (scaled dot-product)
    E2E_STAGE_BEGIN("Compute attention scores", 3000);

    // Reshape for batch matmul: [B, H, S, D_head]
    size_t q_reshaped_dims[] = {BATCH_SIZE * NUM_HEADS, SEQ_LEN, D_HEAD};
    size_t k_reshaped_dims[] = {BATCH_SIZE * NUM_HEADS, D_HEAD, SEQ_LEN};
    size_t scores_dims[] = {BATCH_SIZE * NUM_HEADS, SEQ_LEN, SEQ_LEN};

    nimcp_gpu_tensor_t* q_reshaped = nimcp_gpu_tensor_create(gpu_ctx_, q_reshaped_dims, 3, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* k_reshaped = nimcp_gpu_tensor_create(gpu_ctx_, k_reshaped_dims, 3, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* scores = nimcp_gpu_tensor_create(gpu_ctx_, scores_dims, 3, NIMCP_GPU_PRECISION_FP32);

    // Copy and reshape Q, K (simplified - in production would use proper reshape)
    nimcp_gpu_copy(gpu_ctx_, query, q_reshaped);
    nimcp_gpu_copy(gpu_ctx_, key, k_reshaped);

    const float scale = 1.0f / std::sqrt(static_cast<float>(D_HEAD));

    auto attn_start = std::chrono::high_resolution_clock::now();

    // Batched GEMM: scores = Q @ K^T
    bool success = nimcp_gpu_gemm_batched(gpu_ctx_, q_reshaped, k_reshaped, scores,
                                           scale, 0.0f, false, true);
    E2E_ASSERT(success, "Attention score computation failed");

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto attn_end = std::chrono::high_resolution_clock::now();

    std::cout << "\n  Score computation time: "
              << std::chrono::duration<double, std::milli>(attn_end - attn_start).count()
              << " ms" << std::endl;

    E2E_STAGE_END();

    // Stage 3: Apply softmax
    E2E_STAGE_BEGIN("Apply softmax", 2000);

    size_t softmax_dims[] = {BATCH_SIZE * NUM_HEADS * SEQ_LEN, SEQ_LEN};
    nimcp_gpu_tensor_t* scores_2d = nimcp_gpu_tensor_create(gpu_ctx_, softmax_dims, 2, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_copy(gpu_ctx_, scores, scores_2d);

    auto softmax_start = std::chrono::high_resolution_clock::now();

    success = nimcp_gpu_softmax(gpu_ctx_, scores_2d, scores_2d);
    E2E_ASSERT(success, "Softmax failed");

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto softmax_end = std::chrono::high_resolution_clock::now();

    std::cout << "\n  Softmax time: "
              << std::chrono::duration<double, std::milli>(softmax_end - softmax_start).count()
              << " ms" << std::endl;

    nimcp_gpu_tensor_destroy(scores_2d);

    E2E_STAGE_END();

    // Stage 4: Compute attention output
    E2E_STAGE_BEGIN("Compute attention output", 2000);

    size_t v_reshaped_dims[] = {BATCH_SIZE * NUM_HEADS, SEQ_LEN, D_HEAD};
    size_t out_reshaped_dims[] = {BATCH_SIZE * NUM_HEADS, SEQ_LEN, D_HEAD};

    nimcp_gpu_tensor_t* v_reshaped = nimcp_gpu_tensor_create(gpu_ctx_, v_reshaped_dims, 3, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* out_reshaped = nimcp_gpu_tensor_create(gpu_ctx_, out_reshaped_dims, 3, NIMCP_GPU_PRECISION_FP32);

    nimcp_gpu_copy(gpu_ctx_, value, v_reshaped);

    auto output_start = std::chrono::high_resolution_clock::now();

    // output = softmax(scores) @ V
    success = nimcp_gpu_gemm_batched(gpu_ctx_, scores, v_reshaped, out_reshaped,
                                      1.0f, 0.0f, false, false);
    E2E_ASSERT(success, "Attention output computation failed");

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto output_end = std::chrono::high_resolution_clock::now();

    std::cout << "\n  Output computation time: "
              << std::chrono::duration<double, std::milli>(output_end - output_start).count()
              << " ms" << std::endl;

    E2E_STAGE_END();

    // Stage 5: Full attention benchmark
    E2E_STAGE_BEGIN("Full attention benchmark", 5000);

    const int NUM_ITERATIONS = 50;
    auto bench_start = std::chrono::high_resolution_clock::now();

    for (int i = 0; i < NUM_ITERATIONS; i++) {
        nimcp_gpu_gemm_batched(gpu_ctx_, q_reshaped, k_reshaped, scores, scale, 0.0f, false, true);
        nimcp_gpu_softmax(gpu_ctx_, scores, scores);
        nimcp_gpu_gemm_batched(gpu_ctx_, scores, v_reshaped, out_reshaped, 1.0f, 0.0f, false, false);
    }

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto bench_end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(bench_end - bench_start).count();
    metrics_.latency_ms = metrics_.gpu_time_ms / NUM_ITERATIONS;

    std::cout << "\n  Benchmark (" << NUM_ITERATIONS << " iterations): " << metrics_.gpu_time_ms << " ms" << std::endl;
    std::cout << "  Per-iteration latency: " << metrics_.latency_ms << " ms" << std::endl;

    E2E_STAGE_END();

    // Cleanup
    nimcp_gpu_tensor_destroy(query);
    nimcp_gpu_tensor_destroy(key);
    nimcp_gpu_tensor_destroy(value);
    nimcp_gpu_tensor_destroy(attn_weights);
    nimcp_gpu_tensor_destroy(output);
    nimcp_gpu_tensor_destroy(q_reshaped);
    nimcp_gpu_tensor_destroy(k_reshaped);
    nimcp_gpu_tensor_destroy(scores);
    nimcp_gpu_tensor_destroy(v_reshaped);
    nimcp_gpu_tensor_destroy(out_reshaped);

    uint64_t flops_per_iter = 2 * BATCH_SIZE * NUM_HEADS * SEQ_LEN * SEQ_LEN * D_HEAD * 2;  // Q@K^T + attn@V
    metrics_.throughput_ops_per_sec = (flops_per_iter * NUM_ITERATIONS) / (metrics_.gpu_time_ms / 1000.0);

    PrintMetrics("Multi-Head Attention GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 4: GPU vs CPU Cognitive Accuracy
//=============================================================================

TEST_F(CognitiveProcessingGPUE2ETest, GPUvsCPUCognitiveAccuracy) {
    E2E_PIPELINE_START("GPU vs CPU Cognitive Accuracy");

    const size_t N = 1024;
    const size_t M = 512;

    // Stage 1: CPU baseline computation
    E2E_STAGE_BEGIN("CPU cognitive computation", 3000);

    std::vector<float> a(N * M), b(M * N), c_cpu(N * N, 0.0f);
    std::uniform_real_distribution<float> dist(-1.0f, 1.0f);
    for (auto& v : a) v = dist(rng_);
    for (auto& v : b) v = dist(rng_);

    auto cpu_start = std::chrono::high_resolution_clock::now();

    // CPU matrix multiply
    for (size_t i = 0; i < N; i++) {
        for (size_t j = 0; j < N; j++) {
            float sum = 0.0f;
            for (size_t k = 0; k < M; k++) {
                sum += a[i * M + k] * b[k * N + j];
            }
            c_cpu[i * N + j] = sum;
        }
    }

    // Apply GELU activation (CPU)
    for (auto& v : c_cpu) {
        float x = v;
        v = 0.5f * x * (1.0f + std::tanh(std::sqrt(2.0f / 3.14159265f) * (x + 0.044715f * x * x * x)));
    }

    auto cpu_end = std::chrono::high_resolution_clock::now();
    metrics_.cpu_time_ms = std::chrono::duration<double, std::milli>(cpu_end - cpu_start).count();

    std::cout << "\n  CPU computation time: " << metrics_.cpu_time_ms << " ms" << std::endl;

    E2E_STAGE_END();

    // Stage 2: GPU computation
    E2E_STAGE_BEGIN("GPU cognitive computation", 2000);

    std::vector<float> c_gpu(N * N, 0.0f);

    if (HasGPU()) {
        size_t a_dims[] = {N, M};
        size_t b_dims[] = {M, N};
        size_t c_dims[] = {N, N};

        nimcp_gpu_tensor_t* gpu_a = nimcp_gpu_tensor_from_host(gpu_ctx_, a.data(), a_dims, 2, NIMCP_GPU_PRECISION_FP32);
        nimcp_gpu_tensor_t* gpu_b = nimcp_gpu_tensor_from_host(gpu_ctx_, b.data(), b_dims, 2, NIMCP_GPU_PRECISION_FP32);
        nimcp_gpu_tensor_t* gpu_c = nimcp_gpu_tensor_create(gpu_ctx_, c_dims, 2, NIMCP_GPU_PRECISION_FP32);

        auto gpu_start = std::chrono::high_resolution_clock::now();

        bool success = nimcp_gpu_gemm(gpu_ctx_, gpu_a, gpu_b, gpu_c, 1.0f, 0.0f, false, false);
        E2E_ASSERT(success, "GPU GEMM failed");

        success = nimcp_gpu_gelu(gpu_ctx_, gpu_c, gpu_c);
        E2E_ASSERT(success, "GPU GELU failed");

        nimcp_gpu_context_synchronize(gpu_ctx_);
        auto gpu_end = std::chrono::high_resolution_clock::now();
        metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(gpu_end - gpu_start).count();

        nimcp_gpu_tensor_to_host(gpu_c, c_gpu.data());

        nimcp_gpu_tensor_destroy(gpu_a);
        nimcp_gpu_tensor_destroy(gpu_b);
        nimcp_gpu_tensor_destroy(gpu_c);

        std::cout << "  GPU computation time: " << metrics_.gpu_time_ms << " ms" << std::endl;
    } else {
        c_gpu = c_cpu;
        metrics_.gpu_time_ms = metrics_.cpu_time_ms;
        std::cout << "  GPU not available - using CPU results" << std::endl;
    }

    E2E_STAGE_END();

    // Stage 3: Compare results
    E2E_STAGE_BEGIN("Compare accuracy", 1000);

    metrics_.numerical_accuracy = ComputeNumericalAccuracy(c_cpu, c_gpu);
    metrics_.speedup = metrics_.cpu_time_ms / std::max(0.001, metrics_.gpu_time_ms);

    std::cout << "\n  Numerical accuracy (max diff): " << metrics_.numerical_accuracy << std::endl;
    std::cout << "  Speedup: " << metrics_.speedup << "x" << std::endl;

    EXPECT_LT(metrics_.numerical_accuracy, 1e-3)
        << "GPU and CPU results differ too much for cognitive operations";

    E2E_STAGE_END();

    PrintMetrics("GPU vs CPU Cognitive Accuracy");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 5: Inverse Model (Action Inference)
//=============================================================================

TEST_F(CognitiveProcessingGPUE2ETest, JEPAInverseModelGPU) {
    E2E_PIPELINE_START("JEPA Inverse Model on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const size_t BATCH_SIZE = 64;
    const size_t STATE_DIM = 256;
    const size_t ACTION_DIM = 32;
    const size_t HIDDEN_DIM = 128;
    const size_t NUM_LAYERS = 2;

    // Stage 1: Create inverse model
    E2E_STAGE_BEGIN("Create inverse model", 1000);

    nimcp_jepa_gpu_inverse_t* inverse = nimcp_jepa_gpu_inverse_create(
        gpu_ctx_, STATE_DIM, ACTION_DIM, HIDDEN_DIM, NUM_LAYERS);
    E2E_ASSERT_NOT_NULL(inverse, "Failed to create inverse model");

    std::cout << "\n  Inverse Model Configuration:" << std::endl;
    std::cout << "    State dim: " << STATE_DIM << std::endl;
    std::cout << "    Action dim: " << ACTION_DIM << std::endl;

    E2E_STAGE_END();

    // Stage 2: Create state tensors
    E2E_STAGE_BEGIN("Create state tensors", 500);

    size_t state_dims[] = {BATCH_SIZE, STATE_DIM};
    size_t action_dims[] = {BATCH_SIZE, ACTION_DIM};

    nimcp_gpu_tensor_t* state_t = nimcp_gpu_tensor_create(gpu_ctx_, state_dims, 2, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* state_next = nimcp_gpu_tensor_create(gpu_ctx_, state_dims, 2, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* action = nimcp_gpu_tensor_create(gpu_ctx_, action_dims, 2, NIMCP_GPU_PRECISION_FP32);

    E2E_ASSERT_NOT_NULL(state_t, "Failed to create state_t tensor");
    E2E_ASSERT_NOT_NULL(state_next, "Failed to create state_next tensor");
    E2E_ASSERT_NOT_NULL(action, "Failed to create action tensor");

    // Initialize states
    std::vector<float> state_data;
    GenerateLatentVectors(BATCH_SIZE, STATE_DIM, state_data);
    nimcp_gpu_memcpy(gpu_ctx_, state_t->data, state_data.data(),
                     state_data.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    GenerateLatentVectors(BATCH_SIZE, STATE_DIM, state_data);
    nimcp_gpu_memcpy(gpu_ctx_, state_next->data, state_data.data(),
                     state_data.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    E2E_STAGE_END();

    // Stage 3: Infer actions
    E2E_STAGE_BEGIN("Infer actions from state transitions", 3000);

    const int NUM_ITERATIONS = 100;
    auto infer_start = std::chrono::high_resolution_clock::now();

    for (int i = 0; i < NUM_ITERATIONS; i++) {
        bool success = nimcp_jepa_gpu_inverse_infer(inverse, state_t, state_next, action);
        E2E_ASSERT(success, "Action inference failed");
    }

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto infer_end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(infer_end - infer_start).count();
    metrics_.latency_ms = metrics_.gpu_time_ms / NUM_ITERATIONS;

    // Download and verify actions
    std::vector<float> action_data(BATCH_SIZE * ACTION_DIM);
    nimcp_gpu_memcpy(gpu_ctx_, action_data.data(), action->data,
                     action_data.size() * sizeof(float), GPU_MEMCPY_DEVICE_TO_HOST);

    float action_sum = std::accumulate(action_data.begin(), action_data.end(), 0.0f);
    std::cout << "\n  Inferred action sum: " << action_sum << std::endl;
    std::cout << "  Inference time (" << NUM_ITERATIONS << " iters): " << metrics_.gpu_time_ms << " ms" << std::endl;
    std::cout << "  Per-inference latency: " << metrics_.latency_ms << " ms" << std::endl;

    E2E_STAGE_END();

    // Cleanup
    nimcp_gpu_tensor_destroy(state_t);
    nimcp_gpu_tensor_destroy(state_next);
    nimcp_gpu_tensor_destroy(action);
    nimcp_jepa_gpu_inverse_destroy(inverse);

    metrics_.throughput_ops_per_sec = (NUM_ITERATIONS * BATCH_SIZE) / (metrics_.gpu_time_ms / 1000.0);
    PrintMetrics("JEPA Inverse Model GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Main
//=============================================================================

int main(int argc, char** argv) {
    ::testing::InitGoogleTest(&argc, argv);
    return RUN_ALL_TESTS();
}
