/**
 * @file test_brain_learning_strategies.cpp
 * @brief Targeted tests for brain learning strategy functions
 *
 * PURPOSE: Cover uncovered learning strategy code paths to increase coverage
 * TARGET: strategy_classification_loss, strategy_regression_*, strategy_pattern_*, strategy_association_*
 * COVERAGE GOAL: Add ~2% coverage by testing all learning strategies
 */

#include <gtest/gtest.h>
#include <cmath>
    #include "core/brain/nimcp_brain.h"
    #include "utils/memory/nimcp_memory.h"

class BrainLearningStrategyTest : public ::testing::Test {
protected:
    void SetUp() override {
        nimcp_memory_init();
    }

    void TearDown() override {
        nimcp_memory_cleanup();
    }
};

//=============================================================================
// Classification Strategy Tests
//=============================================================================

TEST_F(BrainLearningStrategyTest, ClassificationStrategyTransformAndLoss) {
    // Create a brain with CLASSIFICATION task to trigger strategy creation
    brain_t brain = brain_create("classification_test", BRAIN_SIZE_TINY,
                                BRAIN_TASK_CLASSIFICATION, 10, 3);
    ASSERT_NE(brain, nullptr);

    // Prepare test data for classification (3 classes)
    float features[10] = {0.1f, 0.2f, 0.3f, 0.4f, 0.5f, 0.6f, 0.7f, 0.8f, 0.9f, 1.0f};
    const char* label = "class_a";

    // Train with the classification strategy - this exercises the transform and loss functions
    bool success = brain_learn_example(brain, features, 10, label, 1.0f);
    EXPECT_TRUE(success);

    // Make a prediction to exercise classification transform (softmax)
    brain_decision_t* decision = brain_decide(brain, features, 10);
    ASSERT_NE(decision, nullptr);

    // Verify classification output properties (probabilities should sum to ~1.0)
    float prob_sum = 0.0f;
    for (uint32_t i = 0; i < decision->output_size; i++) {
        EXPECT_GE(decision->output_vector[i], 0.0f);
        EXPECT_LE(decision->output_vector[i], 1.0f);
        prob_sum += decision->output_vector[i];
    }
    EXPECT_NEAR(prob_sum, 1.0f, 0.1f);  // Softmax outputs should sum to 1.0

    brain_free_decision(decision);
    brain_destroy(brain);
}

TEST_F(BrainLearningStrategyTest, ClassificationLossWithZeroTarget) {
    // Test classification strategy with edge case: zero targets
    brain_t brain = brain_create("classification_zero", BRAIN_SIZE_TINY,
                                BRAIN_TASK_CLASSIFICATION, 5, 2);
    ASSERT_NE(brain, nullptr);

    // Create features that should produce low probability for target class
    float features[5] = {0.0f, 0.0f, 0.0f, 0.0f, 0.0f};
    const char* label = "zero_class";

    // This will exercise cross-entropy loss with low predictions
    bool success = brain_learn_example(brain, features, 5, label, 0.5f);
    EXPECT_TRUE(success);

    brain_destroy(brain);
}

//=============================================================================
// Regression Strategy Tests
//=============================================================================

TEST_F(BrainLearningStrategyTest, RegressionStrategyTransformAndLoss) {
    // Create a brain with REGRESSION task
    brain_t brain = brain_create("regression_test", BRAIN_SIZE_TINY,
                                BRAIN_TASK_REGRESSION, 10, 1);
    ASSERT_NE(brain, nullptr);

    // Prepare regression test data (predicting a continuous value)
    float features[10] = {1.0f, 2.0f, 3.0f, 4.0f, 5.0f, 6.0f, 7.0f, 8.0f, 9.0f, 10.0f};
    const char* label = "5.5";  // Target continuous value

    // Train with regression strategy - exercises MSE loss and linear transform
    bool success = brain_learn_example(brain, features, 10, label, 1.0f);
    EXPECT_TRUE(success);

    // Make prediction - regression outputs should be continuous values
    brain_decision_t* decision = brain_decide(brain, features, 10);
    ASSERT_NE(decision, nullptr);

    // Regression outputs don't need to be in [0,1] range
    EXPECT_GT(decision->output_size, 0u);

    brain_free_decision(decision);
    brain_destroy(brain);
}

TEST_F(BrainLearningStrategyTest, RegressionMultiOutput) {
    // Test regression with multiple continuous outputs
    brain_t brain = brain_create("regression_multi", BRAIN_SIZE_TINY,
                                BRAIN_TASK_REGRESSION, 8, 3);
    ASSERT_NE(brain, nullptr);

    float features[8] = {0.1f, 0.2f, 0.3f, 0.4f, 0.5f, 0.6f, 0.7f, 0.8f};
    const char* label = "output_1";

    // Exercise MSE loss with multiple outputs
    for (int i = 0; i < 5; i++) {
        bool success = brain_learn_example(brain, features, 8, label, 1.0f);
        EXPECT_TRUE(success);
    }

    brain_decision_t* decision = brain_decide(brain, features, 8);
    ASSERT_NE(decision, nullptr);
    EXPECT_EQ(decision->output_size, 3u);

    brain_free_decision(decision);
    brain_destroy(brain);
}

//=============================================================================
// Pattern Matching Strategy Tests
//=============================================================================

TEST_F(BrainLearningStrategyTest, PatternMatchingStrategyTransformAndLoss) {
    // Create a brain with PATTERN_MATCHING task
    brain_t brain = brain_create("pattern_test", BRAIN_SIZE_TINY,
                                BRAIN_TASK_PATTERN_MATCHING, 10, 4);
    ASSERT_NE(brain, nullptr);

    // Pattern matching data - binary patterns
    float features[10] = {1.0f, 0.0f, 1.0f, 0.0f, 1.0f, 0.0f, 1.0f, 0.0f, 1.0f, 0.0f};
    const char* label = "pattern_a";

    // Train with pattern matching strategy - exercises binary threshold transform and BCE loss
    bool success = brain_learn_example(brain, features, 10, label, 1.0f);
    EXPECT_TRUE(success);

    // Make prediction - pattern matching outputs should be binary (0 or 1)
    brain_decision_t* decision = brain_decide(brain, features, 10);
    ASSERT_NE(decision, nullptr);

    // Pattern matching applies threshold (>0.5 -> 1.0, <=0.5 -> 0.0)
    for (uint32_t i = 0; i < decision->output_size; i++) {
        float val = decision->output_vector[i];
        // After thresholding, values should be close to 0.0 or 1.0
        EXPECT_TRUE(val == 0.0f || val == 1.0f || (val > 0.0f && val < 1.0f));
    }

    brain_free_decision(decision);
    brain_destroy(brain);
}

TEST_F(BrainLearningStrategyTest, PatternMatchingEdgeCases) {
    // Test pattern matching with edge case values
    brain_t brain = brain_create("pattern_edge", BRAIN_SIZE_TINY,
                                BRAIN_TASK_PATTERN_MATCHING, 6, 2);
    ASSERT_NE(brain, nullptr);

    // All ones pattern
    float features_ones[6] = {1.0f, 1.0f, 1.0f, 1.0f, 1.0f, 1.0f};
    bool success1 = brain_learn_example(brain, features_ones, 6, "all_ones", 1.0f);
    EXPECT_TRUE(success1);

    // All zeros pattern
    float features_zeros[6] = {0.0f, 0.0f, 0.0f, 0.0f, 0.0f, 0.0f};
    bool success2 = brain_learn_example(brain, features_zeros, 6, "all_zeros", 1.0f);
    EXPECT_TRUE(success2);

    // Mixed pattern at threshold boundary
    float features_mixed[6] = {0.5f, 0.5f, 0.5f, 0.5f, 0.5f, 0.5f};
    bool success3 = brain_learn_example(brain, features_mixed, 6, "threshold", 1.0f);
    EXPECT_TRUE(success3);

    brain_destroy(brain);
}

//=============================================================================
// Association Learning Strategy Tests
//=============================================================================

TEST_F(BrainLearningStrategyTest, AssociationStrategyTransformAndLoss) {
    // Create a brain with ASSOCIATION task (Hebbian learning)
    brain_t brain = brain_create("association_test", BRAIN_SIZE_TINY,
                                BRAIN_TASK_ASSOCIATION, 10, 5);
    ASSERT_NE(brain, nullptr);

    // Association learning data - vector associations
    float features[10] = {0.5f, 0.3f, 0.8f, 0.2f, 0.9f, 0.1f, 0.7f, 0.4f, 0.6f, 0.5f};
    const char* label = "association_a";

    // Train with association strategy - exercises normalization transform and cosine loss
    bool success = brain_learn_example(brain, features, 10, label, 1.0f);
    EXPECT_TRUE(success);

    // Make prediction - association outputs should be normalized
    brain_decision_t* decision = brain_decide(brain, features, 10);
    ASSERT_NE(decision, nullptr);

    // Association strategy normalizes to unit range (max absolute value = 1.0)
    float max_abs = 0.0f;
    for (uint32_t i = 0; i < decision->output_size; i++) {
        float abs_val = std::abs(decision->output_vector[i]);
        if (abs_val > max_abs) {
            max_abs = abs_val;
        }
        EXPECT_LE(abs_val, 1.0f);
    }

    brain_free_decision(decision);
    brain_destroy(brain);
}

TEST_F(BrainLearningStrategyTest, AssociationWithZeroMagnitude) {
    // Test association strategy with zero-magnitude vector (edge case)
    brain_t brain = brain_create("association_zero", BRAIN_SIZE_TINY,
                                BRAIN_TASK_ASSOCIATION, 5, 3);
    ASSERT_NE(brain, nullptr);

    // All zeros - tests the max_val > 0.0 check in normalization
    float features[5] = {0.0f, 0.0f, 0.0f, 0.0f, 0.0f};
    bool success = brain_learn_example(brain, features, 5, "zero_vector", 1.0f);
    EXPECT_TRUE(success);

    brain_decision_t* decision = brain_decide(brain, features, 5);
    ASSERT_NE(decision, nullptr);

    brain_free_decision(decision);
    brain_destroy(brain);
}

TEST_F(BrainLearningStrategyTest, AssociationWithLargeValues) {
    // Test association normalization with large values
    brain_t brain = brain_create("association_large", BRAIN_SIZE_TINY,
                                BRAIN_TASK_ASSOCIATION, 8, 4);
    ASSERT_NE(brain, nullptr);

    // Large magnitude values to test normalization
    float features[8] = {100.0f, -50.0f, 200.0f, -150.0f, 75.0f, -25.0f, 125.0f, -175.0f};
    bool success = brain_learn_example(brain, features, 8, "large_values", 1.0f);
    EXPECT_TRUE(success);

    brain_decision_t* decision = brain_decide(brain, features, 8);
    ASSERT_NE(decision, nullptr);

    // After normalization, all values should be in [-1, 1]
    for (uint32_t i = 0; i < decision->output_size; i++) {
        EXPECT_GE(decision->output_vector[i], -1.0f);
        EXPECT_LE(decision->output_vector[i], 1.0f);
    }

    brain_free_decision(decision);
    brain_destroy(brain);
}

//=============================================================================
// Strategy Comparison Tests
//=============================================================================

TEST_F(BrainLearningStrategyTest, AllStrategiesProduceValidOutputs) {
    // Test that all strategies produce valid outputs
    brain_task_t tasks[] = {
        BRAIN_TASK_CLASSIFICATION,
        BRAIN_TASK_REGRESSION,
        BRAIN_TASK_PATTERN_MATCHING,
        BRAIN_TASK_ASSOCIATION
    };

    const char* task_names[] = {
        "classification",
        "regression",
        "pattern_matching",
        "association"
    };

    for (size_t i = 0; i < 4; i++) {
        brain_t brain = brain_create(task_names[i], BRAIN_SIZE_TINY, tasks[i], 8, 3);
        ASSERT_NE(brain, nullptr) << "Failed to create brain for task " << task_names[i];

        float features[8] = {0.1f, 0.2f, 0.3f, 0.4f, 0.5f, 0.6f, 0.7f, 0.8f};

        // Train
        bool success = brain_learn_example(brain, features, 8, "test_label", 1.0f);
        EXPECT_TRUE(success) << "Learning failed for task " << task_names[i];

        // Predict
        brain_decision_t* decision = brain_decide(brain, features, 8);
        ASSERT_NE(decision, nullptr) << "Decision failed for task " << task_names[i];
        EXPECT_GT(decision->output_size, 0u);

        brain_free_decision(decision);
        brain_destroy(brain);
    }
}

TEST_F(BrainLearningStrategyTest, DefaultStrategyForCustomTask) {
    // Test that BRAIN_TASK_CUSTOM falls back to classification strategy
    brain_t brain = brain_create("custom_task", BRAIN_SIZE_TINY,
                                BRAIN_TASK_CUSTOM, 10, 3);
    ASSERT_NE(brain, nullptr);

    float features[10] = {0.1f, 0.2f, 0.3f, 0.4f, 0.5f, 0.6f, 0.7f, 0.8f, 0.9f, 1.0f};

    // Custom task should use default (classification) strategy
    bool success = brain_learn_example(brain, features, 10, "custom_label", 1.0f);
    EXPECT_TRUE(success);

    brain_decision_t* decision = brain_decide(brain, features, 10);
    ASSERT_NE(decision, nullptr);

    // Should behave like classification (softmax)
    float prob_sum = 0.0f;
    for (uint32_t i = 0; i < decision->output_size; i++) {
        prob_sum += decision->output_vector[i];
    }
    EXPECT_NEAR(prob_sum, 1.0f, 0.1f);

    brain_free_decision(decision);
    brain_destroy(brain);
}
