/**
 * @file test_brain_layer_freezing.cpp
 * @brief Comprehensive unit tests for selective layer freezing in brain_finetune
 *
 * WHAT: Test suite for layer freezing functionality in transfer learning
 * WHY:  Ensure 100% code coverage and correctness of selective layer freezing
 * HOW:  Test different freeze configurations and verify learning behavior
 *
 * @author NIMCP Test Team
 * @date 2025-01-17
 */

#include <gtest/gtest.h>
#include "core/brain/nimcp_brain.h"
#include <vector>
#include <cmath>
#include <random>

//=============================================================================
// Test Fixtures
//=============================================================================

class BrainLayerFreezingTest : public ::testing::Test {
protected:
    brain_t brain;

    void SetUp() override {
        brain = nullptr;
    }

    void TearDown() override {
        if (brain) {
            brain_destroy(brain);
        }
    }

    // Helper: Create simple brain for testing
    brain_t CreateTestBrain() {
        brain = brain_create("test_brain", BRAIN_SIZE_TINY,
                           BRAIN_TASK_CLASSIFICATION, 2, 1);
        EXPECT_NE(brain, nullptr);
        return brain;
    }

    // Helper: Generate simple training data (XOR problem)
    void GenerateXORData(std::vector<float>& training_data,
                        std::vector<float>& labels,
                        uint32_t& num_samples) {
        num_samples = 4;

        // XOR inputs: [x1, x2]
        training_data = {
            0.0f, 0.0f,  // Input 0
            0.0f, 1.0f,  // Input 1
            1.0f, 0.0f,  // Input 2
            1.0f, 1.0f   // Input 3
        };

        // XOR outputs: [out]
        labels = {
            0.0f,  // 0 XOR 0 = 0
            1.0f,  // 0 XOR 1 = 1
            1.0f,  // 1 XOR 0 = 1
            0.0f   // 1 XOR 1 = 0
        };
    }

    // Helper: Generate simple classification data
    void GenerateClassificationData(std::vector<float>& training_data,
                                    std::vector<float>& labels,
                                    uint32_t& num_samples,
                                    uint32_t num_inputs,
                                    uint32_t num_outputs) {
        std::mt19937 rng(42);
        std::uniform_real_distribution<float> dist(0.0f, 1.0f);

        num_samples = 50;
        training_data.resize(num_samples * num_inputs);
        labels.resize(num_samples * num_outputs);

        for (uint32_t i = 0; i < num_samples; i++) {
            // Random features
            for (uint32_t j = 0; j < num_inputs; j++) {
                training_data[i * num_inputs + j] = dist(rng);
            }

            // One-hot labels
            uint32_t class_idx = i % num_outputs;
            for (uint32_t j = 0; j < num_outputs; j++) {
                labels[i * num_outputs + j] = (j == class_idx) ? 1.0f : 0.0f;
            }
        }
    }

    // Helper: Capture weights before training
    std::vector<float> CaptureWeights() {
        brain_stats_t stats;
        brain_get_stats(brain, &stats);

        // We can't directly access weights, but we can measure behavior
        // Use decision outputs as a proxy for weights
        std::vector<float> proxy_weights;

        // Make test predictions with fixed input
        float test_input[10] = {0.1f, 0.2f, 0.3f, 0.4f, 0.5f,
                               0.6f, 0.7f, 0.8f, 0.9f, 1.0f};

        brain_decision_t* decision = brain_decide(brain, test_input, 10);
        if (decision) {
            for (uint32_t i = 0; i < decision->output_size; i++) {
                proxy_weights.push_back(decision->output_vector[i]);
            }
            brain_free_decision(decision);
        }

        return proxy_weights;
    }

    // Helper: Measure weight change
    float MeasureWeightChange(const std::vector<float>& before,
                             const std::vector<float>& after) {
        if (before.size() != after.size()) {
            return 0.0f;
        }

        float total_change = 0.0f;
        for (size_t i = 0; i < before.size(); i++) {
            float diff = after[i] - before[i];
            total_change += diff * diff;
        }

        return std::sqrt(total_change);
    }
};

//=============================================================================
// Basic Functionality Tests
//=============================================================================

TEST_F(BrainLayerFreezingTest, FinetuneWithDefaults) {
    // WHAT: Basic fine-tuning with default config
    // WHY:  Ensure function works with NULL config
    // HOW:  Call brain_finetune with NULL config

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, nullptr);
    EXPECT_TRUE(success);
}

TEST_F(BrainLayerFreezingTest, FinetuneWithCustomConfig) {
    // WHAT: Fine-tuning with custom configuration
    // WHY:  Test config parameter handling
    // HOW:  Provide explicit config

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    brain_finetune_config_t config = {
        .learning_rate = 0.01f,
        .num_epochs = 3,
        .freeze_sensory = false,
        .freeze_cognitive = false,
        .finetune_classifier = true,
        .batch_size = 16,
        .verbose = false
    };

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, &config);
    EXPECT_TRUE(success);
}

//=============================================================================
// Layer Freezing Configuration Tests
//=============================================================================

TEST_F(BrainLayerFreezingTest, FreezeAllLayers) {
    // WHAT: Freeze all layers (sensory + cognitive, no classifier training)
    // WHY:  Test maximum freezing configuration
    // HOW:  All freeze flags true, finetune_classifier false

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    auto weights_before = CaptureWeights();

    brain_finetune_config_t config = {
        .learning_rate = 0.01f,
        .num_epochs = 2,
        .freeze_sensory = true,
        .freeze_cognitive = true,
        .finetune_classifier = false,  // Freeze classifier too
        .batch_size = 16,
        .verbose = false
    };

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, &config);
    EXPECT_TRUE(success);

    auto weights_after = CaptureWeights();

    // With all layers frozen (1% LR), change should be minimal
    float change = MeasureWeightChange(weights_before, weights_after);
    EXPECT_LT(change, 0.1f);  // Very small change
}

TEST_F(BrainLayerFreezingTest, UnfreezeAllLayers) {
    // WHAT: No freezing (all layers trainable)
    // WHY:  Test full training mode
    // HOW:  All freeze flags false

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    auto weights_before = CaptureWeights();

    brain_finetune_config_t config = {
        .learning_rate = 0.05f,
        .num_epochs = 5,
        .freeze_sensory = false,
        .freeze_cognitive = false,
        .finetune_classifier = true,
        .batch_size = 16,
        .verbose = false
    };

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, &config);
    EXPECT_TRUE(success);

    auto weights_after = CaptureWeights();

    // With no freezing, change should be significant
    float change = MeasureWeightChange(weights_before, weights_after);
    EXPECT_GT(change, 0.05f);  // Noticeable change
}

TEST_F(BrainLayerFreezingTest, FreezeSensoryOnly) {
    // WHAT: Freeze only sensory layers
    // WHY:  Test partial freezing
    // HOW:  freeze_sensory=true, others false

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    brain_finetune_config_t config = {
        .learning_rate = 0.02f,
        .num_epochs = 3,
        .freeze_sensory = true,
        .freeze_cognitive = false,
        .finetune_classifier = true,
        .batch_size = 16,
        .verbose = false
    };

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, &config);
    EXPECT_TRUE(success);
}

TEST_F(BrainLayerFreezingTest, FreezeCognitiveOnly) {
    // WHAT: Freeze only cognitive layers
    // WHY:  Test different partial freezing
    // HOW:  freeze_cognitive=true, others false

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    brain_finetune_config_t config = {
        .learning_rate = 0.02f,
        .num_epochs = 3,
        .freeze_sensory = false,
        .freeze_cognitive = true,
        .finetune_classifier = true,
        .batch_size = 16,
        .verbose = false
    };

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, &config);
    EXPECT_TRUE(success);
}

TEST_F(BrainLayerFreezingTest, ClassifierOnlyTraining) {
    // WHAT: Typical transfer learning (freeze features, train classifier)
    // WHY:  Most common use case
    // HOW:  Freeze sensory+cognitive, train classifier

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    brain_finetune_config_t config = {
        .learning_rate = 0.01f,
        .num_epochs = 5,
        .freeze_sensory = true,
        .freeze_cognitive = true,
        .finetune_classifier = true,
        .batch_size = 32,
        .verbose = true  // Test verbose output
    };

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, &config);
    EXPECT_TRUE(success);
}

//=============================================================================
// Learning Rate Tests
//=============================================================================

TEST_F(BrainLayerFreezingTest, LearningRateScaling_Frozen) {
    // WHAT: Verify frozen layers use reduced learning rate
    // WHY:  Core functionality of layer freezing
    // HOW:  Compare weight changes with frozen vs unfrozen

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    // Test 1: All frozen (1% LR)
    auto weights_before_frozen = CaptureWeights();

    brain_finetune_config_t config_frozen = {
        .learning_rate = 0.1f,
        .num_epochs = 3,
        .freeze_sensory = true,
        .freeze_cognitive = true,
        .finetune_classifier = false,
        .batch_size = 16,
        .verbose = false
    };

    brain_finetune(brain, training_data.data(), labels.data(),
                  num_samples, &config_frozen);

    auto weights_after_frozen = CaptureWeights();
    float change_frozen = MeasureWeightChange(weights_before_frozen,
                                              weights_after_frozen);

    // Reset brain
    brain_destroy(brain);
    brain = CreateTestBrain();

    // Test 2: None frozen (100% LR)
    auto weights_before_unfrozen = CaptureWeights();

    brain_finetune_config_t config_unfrozen = {
        .learning_rate = 0.1f,
        .num_epochs = 3,
        .freeze_sensory = false,
        .freeze_cognitive = false,
        .finetune_classifier = true,
        .batch_size = 16,
        .verbose = false
    };

    brain_finetune(brain, training_data.data(), labels.data(),
                  num_samples, &config_unfrozen);

    auto weights_after_unfrozen = CaptureWeights();
    float change_unfrozen = MeasureWeightChange(weights_before_unfrozen,
                                                weights_after_unfrozen);

    // Frozen should change much less than unfrozen
    EXPECT_LT(change_frozen, change_unfrozen * 0.5f);
}

//=============================================================================
// Error Handling Tests
//=============================================================================

TEST_F(BrainLayerFreezingTest, InvalidBrain) {
    // WHAT: NULL brain handle
    // WHY:  Should reject gracefully
    // HOW:  Call with NULL brain

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    bool success = brain_finetune(nullptr, training_data.data(), labels.data(),
                                 num_samples, nullptr);
    EXPECT_FALSE(success);
}

TEST_F(BrainLayerFreezingTest, InvalidTrainingData) {
    // WHAT: NULL training data
    // WHY:  Should reject gracefully
    // HOW:  Call with NULL data

    brain = CreateTestBrain();

    std::vector<float> labels(50);
    bool success = brain_finetune(brain, nullptr, labels.data(), 50, nullptr);
    EXPECT_FALSE(success);
}

TEST_F(BrainLayerFreezingTest, InvalidLabels) {
    // WHAT: NULL labels
    // WHY:  Should reject gracefully
    // HOW:  Call with NULL labels

    brain = CreateTestBrain();

    std::vector<float> training_data(500);
    bool success = brain_finetune(brain, training_data.data(), nullptr, 50, nullptr);
    EXPECT_FALSE(success);
}

TEST_F(BrainLayerFreezingTest, ZeroSamples) {
    // WHAT: Zero training samples
    // WHY:  Should reject gracefully
    // HOW:  Call with num_samples=0

    brain = CreateTestBrain();

    std::vector<float> training_data(100), labels(100);
    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 0, nullptr);
    EXPECT_FALSE(success);
}

//=============================================================================
// Verbose Output Tests
//=============================================================================

TEST_F(BrainLayerFreezingTest, VerboseOutput_Enabled) {
    // WHAT: Test verbose logging
    // WHY:  Ensure status messages are printed
    // HOW:  Enable verbose, capture stdout

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    brain_finetune_config_t config = {
        .learning_rate = 0.01f,
        .num_epochs = 2,
        .freeze_sensory = true,
        .freeze_cognitive = false,
        .finetune_classifier = true,
        .batch_size = 16,
        .verbose = true
    };

    // Redirect stdout to capture output
    testing::internal::CaptureStdout();

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, &config);
    EXPECT_TRUE(success);

    std::string output = testing::internal::GetCapturedStdout();

    // Should contain freeze status messages
    EXPECT_NE(output.find("Layer freezing"), std::string::npos);
    EXPECT_NE(output.find("Sensory"), std::string::npos);
    EXPECT_NE(output.find("Cognitive"), std::string::npos);
    EXPECT_NE(output.find("Classifier"), std::string::npos);
}

TEST_F(BrainLayerFreezingTest, VerboseOutput_Disabled) {
    // WHAT: Test silent mode
    // WHY:  Ensure no output when verbose=false
    // HOW:  Disable verbose, verify no output

    brain = CreateTestBrain();

    std::vector<float> training_data, labels;
    uint32_t num_samples;
    GenerateClassificationData(training_data, labels, num_samples, 10, 10);

    brain_finetune_config_t config = {
        .learning_rate = 0.01f,
        .num_epochs = 2,
        .freeze_sensory = false,
        .freeze_cognitive = false,
        .finetune_classifier = true,
        .batch_size = 16,
        .verbose = false
    };

    testing::internal::CaptureStdout();

    bool success = brain_finetune(brain, training_data.data(), labels.data(),
                                 num_samples, &config);
    EXPECT_TRUE(success);

    std::string output = testing::internal::GetCapturedStdout();

    // Should not contain detailed layer info
    EXPECT_EQ(output.find("Layer freezing"), std::string::npos);
}

//=============================================================================
// Learning Rate Restoration Tests
//=============================================================================

TEST_F(BrainLayerFreezingTest, LearningRateRestored) {
    GTEST_SKIP() << "Skipped: brain_get_config() API removed - cannot verify learning rate restoration";

    // WHAT: Original learning rate restored after fine-tuning
    // WHY:  Ensure no side effects on brain state
    // HOW:  Check LR before and after
    // NOTE: brain_get_config() removed - no equivalent in current API
}

//=============================================================================
// Main
//=============================================================================

int main(int argc, char** argv) {
    ::testing::InitGoogleTest(&argc, argv);
    return RUN_ALL_TESTS();
}
