/**
 * @file test_cortical_features_regression.cpp
 * @brief Comprehensive regression tests for cortical feature processing
 *
 * WHAT: Regression tests for orientation tuning, feature maps, topographic mapping,
 *       sparse coding, and surround suppression in cortical columns
 * WHY:  Ensure feature processing behaviors are stable across versions
 * HOW:  GTest framework with consistency checks, determinism tests, and benchmarks
 *
 * TEST CATEGORIES:
 * - Orientation Tuning Consistency: Tuning curve stability
 * - Feature Map Stability: Map processing reproducibility
 * - Topographic Mapping Accuracy: Spatial organization correctness
 * - Sparse Coding Determinism: Sparse representation stability
 * - Surround Suppression Consistency: Contextual modulation stability
 *
 * @author NIMCP Development Team
 * @date 2025-01-24
 */

#include <gtest/gtest.h>
#include <cmath>
#include <cstring>
#include <vector>
#include <chrono>
#include <random>
#include <algorithm>
#include <numeric>

#include "utils/nimcp_test_base.h"
#include "core/cortical_columns/nimcp_cortical_column.h"
#include "core/cortical_columns/nimcp_cortical_layers.h"
#include "utils/memory/nimcp_memory.h"

//=============================================================================
// Constants and Thresholds
//=============================================================================

// Tuning parameters
constexpr float ORIENTATION_TOLERANCE = 15.0f;  // Degrees
constexpr float TUNING_WIDTH_MIN = 10.0f;
constexpr float TUNING_WIDTH_MAX = 60.0f;

// Feature map parameters
constexpr float FEATURE_CORRELATION_THRESHOLD = 0.9f;
constexpr float SPARSITY_THRESHOLD = 0.8f;  // At least 80% sparse

// Numerical tolerances
constexpr float NUMERICAL_TOLERANCE = 1e-5f;
constexpr float ACTIVATION_TOLERANCE = 0.01f;

//=============================================================================
// Test Fixture
//=============================================================================

class CorticalFeaturesRegressionTest : public NimcpTestBase {
protected:
    cortical_column_pool_t* pool = nullptr;
    std::mt19937 rng{42};

    void SetUp() override {
        NimcpTestBase::SetUp();

        cortical_column_pool_config_t config = {
            .max_minicolumns = 500,
            .max_hypercolumns = 50,
            .max_neurons_per_minicolumn = 100,
            .enable_cow_support = true
        };
        pool = cortical_column_pool_create(&config);
    }

    void TearDown() override {
        if (pool) {
            cortical_column_pool_destroy(pool);
            pool = nullptr;
        }
        NimcpTestBase::TearDown();
    }

    // Helper: Create minicolumn with specific tuning preference
    minicolumn_config_t create_tuned_minicolumn(float orientation, uint32_t num_neurons = 80) {
        uint32_t* neuron_ids = new uint32_t[num_neurons];
        for (uint32_t i = 0; i < num_neurons; i++) {
            neuron_ids[i] = i;
        }

        return {
            .neuron_ids = neuron_ids,
            .num_neurons = num_neurons,
            .receptive_field = {
                .center_x = 0.0f,
                .center_y = 0.0f,
                .center_z = 0.0f,
                .radius = 2.0f
            },
            .tuning_preference = orientation,
            .layers = {
                .layer_2_3_count = num_neurons / 3,
                .layer_4_count = num_neurons / 3,
                .layer_5_6_count = num_neurons - 2 * (num_neurons / 3)
            }
        };
    }

    void free_minicolumn_config(minicolumn_config_t& config) {
        delete[] config.neuron_ids;
        config.neuron_ids = nullptr;
    }

    // Helper: Generate oriented grating stimulus
    std::vector<float> create_oriented_grating(float orientation_deg, uint32_t size = 32) {
        std::vector<float> grating(size * size);
        float angle_rad = orientation_deg * M_PI / 180.0f;
        float frequency = 0.2f;

        for (uint32_t y = 0; y < size; y++) {
            for (uint32_t x = 0; x < size; x++) {
                float projected = x * cos(angle_rad) + y * sin(angle_rad);
                grating[y * size + x] = 0.5f + 0.5f * sin(projected * frequency * 2 * M_PI);
            }
        }
        return grating;
    }

    // Helper: Calculate circular distance between orientations
    float circular_distance(float a, float b, float period = 180.0f) {
        float diff = std::abs(a - b);
        return std::min(diff, period - diff);
    }

    // Helper: Calculate correlation between vectors
    float calculate_correlation(const std::vector<float>& a, const std::vector<float>& b) {
        if (a.size() != b.size() || a.empty()) return 0.0f;

        float mean_a = std::accumulate(a.begin(), a.end(), 0.0f) / a.size();
        float mean_b = std::accumulate(b.begin(), b.end(), 0.0f) / b.size();

        float cov = 0.0f, var_a = 0.0f, var_b = 0.0f;
        for (size_t i = 0; i < a.size(); i++) {
            float da = a[i] - mean_a;
            float db = b[i] - mean_b;
            cov += da * db;
            var_a += da * da;
            var_b += db * db;
        }

        if (var_a < 1e-10f || var_b < 1e-10f) return 0.0f;
        return cov / (sqrt(var_a) * sqrt(var_b));
    }

    // Helper: Calculate sparsity (fraction of near-zero values)
    float calculate_sparsity(const std::vector<float>& values, float threshold = 0.1f) {
        if (values.empty()) return 0.0f;

        uint32_t near_zero = 0;
        for (float val : values) {
            if (std::abs(val) < threshold) near_zero++;
        }
        return static_cast<float>(near_zero) / values.size();
    }

    // Helper: Generate random input
    std::vector<float> random_input(uint32_t size) {
        std::vector<float> input(size);
        std::uniform_real_distribution<float> dist(0.0f, 1.0f);
        for (auto& val : input) {
            val = dist(rng);
        }
        return input;
    }

    // Helper: Measure time
    template<typename Func>
    double measure_time_ms(Func func) {
        auto start = std::chrono::high_resolution_clock::now();
        func();
        auto end = std::chrono::high_resolution_clock::now();
        return std::chrono::duration<double, std::milli>(end - start).count();
    }
};

//=============================================================================
// CATEGORY 1: Orientation Tuning Consistency
//=============================================================================

TEST_F(CorticalFeaturesRegressionTest, OrientationTuningPreferenceStability) {
    // WHAT: Verify orientation preference remains stable
    // WHY:  Tuning preferences must not drift
    // TARGET: Same orientation produces consistent peak response

    ASSERT_NE(pool, nullptr);

    const float target_orientation = 45.0f;
    auto config = create_tuned_minicolumn(target_orientation);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    // Test multiple times with same stimulus
    std::vector<float> responses;
    auto stimulus = create_oriented_grating(target_orientation);

    for (int trial = 0; trial < 10; trial++) {
        float response = minicolumn_compute(col, stimulus.data(), stimulus.size());
        if (response >= 0.0f) {
            responses.push_back(response);
        }
    }

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    // All responses should be identical
    if (responses.size() > 1) {
        for (size_t i = 1; i < responses.size(); i++) {
            EXPECT_FLOAT_EQ(responses[0], responses[i])
                << "Tuning preference unstable at trial " << i;
        }
    }
}

TEST_F(CorticalFeaturesRegressionTest, OrientationTuningCurveShape) {
    // WHAT: Verify tuning curve has expected Gaussian-like shape
    // WHY:  Biological orientation columns have bell-shaped tuning
    // TARGET: Peak at preferred orientation, decreasing with distance

    ASSERT_NE(pool, nullptr);

    const float preferred = 90.0f;
    auto config = create_tuned_minicolumn(preferred);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    std::vector<float> orientations;
    std::vector<float> responses;

    // Sample tuning curve
    for (float ori = 0.0f; ori < 180.0f; ori += 15.0f) {
        auto stimulus = create_oriented_grating(ori);
        float response = minicolumn_compute(col, stimulus.data(), stimulus.size());

        if (response >= 0.0f) {
            orientations.push_back(ori);
            responses.push_back(response);
        }
    }

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    // Find peak
    auto max_it = std::max_element(responses.begin(), responses.end());
    if (max_it != responses.end()) {
        size_t peak_idx = std::distance(responses.begin(), max_it);
        float peak_orientation = orientations[peak_idx];

        // Peak should be near preferred
        float distance = circular_distance(peak_orientation, preferred);
        EXPECT_LT(distance, ORIENTATION_TOLERANCE)
            << "Peak at " << peak_orientation << ", expected near " << preferred;
    }
}

TEST_F(CorticalFeaturesRegressionTest, OrientationTuningWidthConsistency) {
    // WHAT: Verify tuning width is consistent
    // WHY:  Tuning bandwidth should be stable
    // TARGET: Half-width at half-max in biological range

    ASSERT_NE(pool, nullptr);

    const float preferred = 45.0f;
    auto config = create_tuned_minicolumn(preferred);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    // Sample tuning curve finely
    std::vector<float> responses;
    for (float ori = 0.0f; ori < 180.0f; ori += 5.0f) {
        auto stimulus = create_oriented_grating(ori);
        float response = minicolumn_compute(col, stimulus.data(), stimulus.size());
        responses.push_back((response >= 0.0f) ? response : 0.0f);
    }

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    // Find peak and half-max
    float peak = *std::max_element(responses.begin(), responses.end());
    if (peak > 0.0f) {
        float half_max = peak / 2.0f;

        // Count orientations above half-max
        uint32_t above_half = 0;
        for (float r : responses) {
            if (r >= half_max) above_half++;
        }

        // Tuning width in degrees (each sample is 5 degrees)
        float tuning_width = above_half * 5.0f;

        // Should be within biological range
        EXPECT_GE(tuning_width, TUNING_WIDTH_MIN)
            << "Tuning too narrow: " << tuning_width << " degrees";
        EXPECT_LE(tuning_width, TUNING_WIDTH_MAX)
            << "Tuning too broad: " << tuning_width << " degrees";
    }
}

TEST_F(CorticalFeaturesRegressionTest, MultipleOrientationsDeterminism) {
    // WHAT: Verify multiple orientations are processed deterministically
    // WHY:  Hypercolumn with multiple tunings must be stable
    // TARGET: Same winners for same stimuli

    ASSERT_NE(pool, nullptr);

    const uint32_t num_orientations = 12;
    std::vector<minicolumn_config_t> configs;

    // Create orientation hypercolumn
    for (uint32_t i = 0; i < num_orientations; i++) {
        float orientation = (180.0f / num_orientations) * i;
        configs.push_back(create_tuned_minicolumn(orientation));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_orientations,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_WINNER_TAKE_ALL,
        .k_winners = 1,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.5f,
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    // Test with different orientations
    std::vector<float> test_orientations = {0.0f, 30.0f, 60.0f, 90.0f, 120.0f, 150.0f};

    for (float ori : test_orientations) {
        auto stimulus = create_oriented_grating(ori);

        // Two runs
        hypercolumn_compute(hcol, stimulus.data(), stimulus.size());
        uint32_t winner1 = hypercolumn_get_winner(hcol);

        hypercolumn_compute(hcol, stimulus.data(), stimulus.size());
        uint32_t winner2 = hypercolumn_get_winner(hcol);

        EXPECT_EQ(winner1, winner2) << "Winner unstable for orientation " << ori;
    }

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }
}

//=============================================================================
// CATEGORY 2: Feature Map Stability
//=============================================================================

TEST_F(CorticalFeaturesRegressionTest, FeatureMapReproducibility) {
    // WHAT: Verify feature map processing is reproducible
    // WHY:  Same input must produce same feature activations
    // TARGET: Distributions match exactly

    ASSERT_NE(pool, nullptr);

    const uint32_t num_minicolumns = 16;
    std::vector<minicolumn_config_t> configs;

    for (uint32_t i = 0; i < num_minicolumns; i++) {
        float orientation = (180.0f / num_minicolumns) * i;
        configs.push_back(create_tuned_minicolumn(orientation));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_minicolumns,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_SOFTMAX,
        .k_winners = 3,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.5f,
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    auto input = random_input(100);

    // First run
    hypercolumn_compute(hcol, input.data(), input.size());
    std::vector<float> map1(num_minicolumns);
    hypercolumn_get_distribution(hcol, map1.data(), num_minicolumns);

    // Second run
    hypercolumn_compute(hcol, input.data(), input.size());
    std::vector<float> map2(num_minicolumns);
    hypercolumn_get_distribution(hcol, map2.data(), num_minicolumns);

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }

    // Maps should be identical
    for (uint32_t i = 0; i < num_minicolumns; i++) {
        EXPECT_FLOAT_EQ(map1[i], map2[i]) << "Feature map differs at " << i;
    }
}

TEST_F(CorticalFeaturesRegressionTest, FeatureMapCorrelationStability) {
    // WHAT: Verify feature map correlations are stable
    // WHY:  Similar inputs should produce correlated maps
    // TARGET: High correlation for similar inputs

    ASSERT_NE(pool, nullptr);

    const uint32_t num_minicolumns = 16;
    std::vector<minicolumn_config_t> configs;

    for (uint32_t i = 0; i < num_minicolumns; i++) {
        float orientation = (180.0f / num_minicolumns) * i;
        configs.push_back(create_tuned_minicolumn(orientation));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_minicolumns,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_SOFTMAX,
        .k_winners = 3,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.5f,
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    // Generate base input and slightly modified version
    auto input1 = random_input(100);
    auto input2 = input1;
    std::normal_distribution<float> noise(0.0f, 0.05f);
    for (float& val : input2) {
        val = std::clamp(val + noise(rng), 0.0f, 1.0f);
    }

    // Process both
    hypercolumn_compute(hcol, input1.data(), input1.size());
    std::vector<float> map1(num_minicolumns);
    hypercolumn_get_distribution(hcol, map1.data(), num_minicolumns);

    hypercolumn_compute(hcol, input2.data(), input2.size());
    std::vector<float> map2(num_minicolumns);
    hypercolumn_get_distribution(hcol, map2.data(), num_minicolumns);

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }

    // Similar inputs should produce correlated maps
    float correlation = calculate_correlation(map1, map2);
    EXPECT_GT(correlation, FEATURE_CORRELATION_THRESHOLD)
        << "Feature maps not correlated: r=" << correlation;
}

TEST_F(CorticalFeaturesRegressionTest, FeatureMapNormalization) {
    // WHAT: Verify feature maps are properly normalized
    // WHY:  Softmax output should be valid probability distribution
    // TARGET: Sum to 1, all non-negative

    ASSERT_NE(pool, nullptr);

    const uint32_t num_minicolumns = 16;
    std::vector<minicolumn_config_t> configs;

    for (uint32_t i = 0; i < num_minicolumns; i++) {
        configs.push_back(create_tuned_minicolumn((180.0f / num_minicolumns) * i));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_minicolumns,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_SOFTMAX,
        .k_winners = 3,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.5f,
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    // Test multiple inputs
    for (int test = 0; test < 20; test++) {
        auto input = random_input(100);
        hypercolumn_compute(hcol, input.data(), input.size());

        std::vector<float> distribution(num_minicolumns);
        hypercolumn_get_distribution(hcol, distribution.data(), num_minicolumns);

        float sum = 0.0f;
        for (float val : distribution) {
            EXPECT_GE(val, 0.0f) << "Negative value in feature map";
            EXPECT_LE(val, 1.0f) << "Value > 1 in feature map";
            EXPECT_FALSE(std::isnan(val)) << "NaN in feature map";
            sum += val;
        }

        EXPECT_NEAR(sum, 1.0f, 0.01f) << "Feature map doesn't sum to 1";
    }

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }
}

//=============================================================================
// CATEGORY 3: Topographic Mapping Accuracy
//=============================================================================

TEST_F(CorticalFeaturesRegressionTest, ReceptiveFieldCenterAccuracy) {
    // WHAT: Verify receptive field center calculation
    // WHY:  RF center determines spatial selectivity
    // TARGET: Weight is maximal at center

    ASSERT_NE(pool, nullptr);

    auto config = create_tuned_minicolumn(45.0f);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    // Set RF at specific location
    minicolumn_set_receptive_field(col, 5.0f, 5.0f, 0.0f, 2.0f);

    // Weight should be maximal at center
    float weight_at_center = minicolumn_compute_receptive_weight(col, 5.0f, 5.0f, 0.0f);
    float weight_off_center = minicolumn_compute_receptive_weight(col, 7.0f, 5.0f, 0.0f);

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    EXPECT_GT(weight_at_center, weight_off_center)
        << "Center weight not maximal";
    EXPECT_NEAR(weight_at_center, 1.0f, 0.01f)
        << "Center weight not ~1.0";
}

TEST_F(CorticalFeaturesRegressionTest, ReceptiveFieldRadiusEffect) {
    // WHAT: Verify RF radius affects weight falloff
    // WHY:  Larger radius = slower falloff
    // TARGET: Larger radius = higher weight at fixed distance

    ASSERT_NE(pool, nullptr);

    auto config = create_tuned_minicolumn(45.0f);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    float test_distance = 2.0f;

    // Narrow RF
    minicolumn_set_receptive_field(col, 0.0f, 0.0f, 0.0f, 1.0f);
    float weight_narrow = minicolumn_compute_receptive_weight(col, test_distance, 0.0f, 0.0f);

    // Wide RF
    minicolumn_set_receptive_field(col, 0.0f, 0.0f, 0.0f, 4.0f);
    float weight_wide = minicolumn_compute_receptive_weight(col, test_distance, 0.0f, 0.0f);

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    EXPECT_GT(weight_wide, weight_narrow)
        << "Wide RF should have higher weight at distance";
}

TEST_F(CorticalFeaturesRegressionTest, TopographicOrganization) {
    // WHAT: Verify topographic organization of hypercolumns
    // WHY:  Spatial position should affect RF centers
    // TARGET: Different positions have distinct RF centers

    ASSERT_NE(pool, nullptr);

    // Create hypercolumns at different positions
    std::vector<hypercolumn_t*> hypercolumns;
    std::vector<std::vector<minicolumn_config_t>> all_configs;

    for (float x = 0.0f; x < 10.0f; x += 2.0f) {
        std::vector<minicolumn_config_t> configs;
        for (uint32_t i = 0; i < 8; i++) {
            auto config = create_tuned_minicolumn((180.0f / 8) * i);
            // Set RF center based on topographic position
            config.receptive_field.center_x = x;
            config.receptive_field.center_y = 0.0f;
            configs.push_back(config);
        }

        hypercolumn_config_t hcol_config = {
            .num_minicolumns = 8,
            .minicolumn_configs = configs.data(),
            .feature_space_min = 0.0f,
            .feature_space_max = 180.0f,
            .topographic_x = x,
            .topographic_y = 0.0f,
            .competition = CC_COMPETITION_SOFTMAX,
            .k_winners = 1,
            .temperature = 1.0f,
            .lateral_inhibition_strength = 0.5f,
            .lateral_inhibition_sigma1 = 1.0f,
            .lateral_inhibition_sigma2 = 3.0f
        };

        hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
        if (hcol) {
            hypercolumns.push_back(hcol);
            all_configs.push_back(std::move(configs));
        }
    }

    // Verify they respond differently
    auto input = random_input(100);
    std::vector<uint32_t> winners;

    for (auto hcol : hypercolumns) {
        hypercolumn_compute(hcol, input.data(), input.size());
        winners.push_back(hypercolumn_get_winner(hcol));
    }

    // Cleanup
    for (auto hcol : hypercolumns) {
        hypercolumn_destroy(hcol);
    }
    for (auto& configs : all_configs) {
        for (auto& config : configs) {
            free_minicolumn_config(config);
        }
    }

    // At least verify no errors occurred
    for (uint32_t winner : winners) {
        EXPECT_LT(winner, 8u) << "Invalid winner index";
    }
}

TEST_F(CorticalFeaturesRegressionTest, GaussianWeightSymmetry) {
    // WHAT: Verify Gaussian RF weight is symmetric
    // WHY:  RF should have radial symmetry
    // TARGET: Same weight at equal distances in all directions

    ASSERT_NE(pool, nullptr);

    auto config = create_tuned_minicolumn(45.0f);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    minicolumn_set_receptive_field(col, 0.0f, 0.0f, 0.0f, 2.0f);

    float distance = 1.5f;

    // Test in all directions
    float weight_x = minicolumn_compute_receptive_weight(col, distance, 0.0f, 0.0f);
    float weight_y = minicolumn_compute_receptive_weight(col, 0.0f, distance, 0.0f);
    float weight_neg_x = minicolumn_compute_receptive_weight(col, -distance, 0.0f, 0.0f);
    float weight_neg_y = minicolumn_compute_receptive_weight(col, 0.0f, -distance, 0.0f);

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    // All should be equal
    EXPECT_NEAR(weight_x, weight_y, NUMERICAL_TOLERANCE);
    EXPECT_NEAR(weight_x, weight_neg_x, NUMERICAL_TOLERANCE);
    EXPECT_NEAR(weight_x, weight_neg_y, NUMERICAL_TOLERANCE);
}

//=============================================================================
// CATEGORY 4: Sparse Coding Determinism
//=============================================================================

TEST_F(CorticalFeaturesRegressionTest, WinnerTakeAllSparsity) {
    // WHAT: Verify WTA produces maximally sparse code
    // WHY:  WTA should activate exactly one unit
    // TARGET: 100% sparsity (1 active, rest zero)

    ASSERT_NE(pool, nullptr);

    const uint32_t num_minicolumns = 16;
    std::vector<minicolumn_config_t> configs;

    for (uint32_t i = 0; i < num_minicolumns; i++) {
        configs.push_back(create_tuned_minicolumn((180.0f / num_minicolumns) * i));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_minicolumns,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_WINNER_TAKE_ALL,
        .k_winners = 1,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.5f,
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    auto input = random_input(100);
    hypercolumn_compute(hcol, input.data(), input.size());

    std::vector<float> distribution(num_minicolumns);
    hypercolumn_get_distribution(hcol, distribution.data(), num_minicolumns);

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }

    // Count non-zero activations
    uint32_t active_count = 0;
    for (float val : distribution) {
        if (val > 0.01f) active_count++;
    }

    EXPECT_EQ(active_count, 1u) << "WTA should have exactly 1 active unit";
}

TEST_F(CorticalFeaturesRegressionTest, KWinnersSparsity) {
    // WHAT: Verify k-winners produces expected sparsity
    // WHY:  Should activate exactly k units
    // TARGET: Sparsity = (N-k)/N

    ASSERT_NE(pool, nullptr);

    const uint32_t num_minicolumns = 16;
    const uint32_t k = 3;
    std::vector<minicolumn_config_t> configs;

    for (uint32_t i = 0; i < num_minicolumns; i++) {
        configs.push_back(create_tuned_minicolumn((180.0f / num_minicolumns) * i));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_minicolumns,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_K_WINNERS,
        .k_winners = k,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.5f,
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    auto input = random_input(100);
    hypercolumn_compute(hcol, input.data(), input.size());

    std::vector<float> distribution(num_minicolumns);
    hypercolumn_get_distribution(hcol, distribution.data(), num_minicolumns);

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }

    // Count non-zero activations
    uint32_t active_count = 0;
    for (float val : distribution) {
        if (val > 0.01f) active_count++;
    }

    EXPECT_EQ(active_count, k) << "K-winners should have exactly " << k << " active units";
}

TEST_F(CorticalFeaturesRegressionTest, SparseCodingDeterminism) {
    // WHAT: Verify sparse coding is deterministic
    // WHY:  Same input must produce same sparse code
    // TARGET: Active units match across runs

    ASSERT_NE(pool, nullptr);

    const uint32_t num_minicolumns = 16;
    const uint32_t k = 3;
    std::vector<minicolumn_config_t> configs;

    for (uint32_t i = 0; i < num_minicolumns; i++) {
        configs.push_back(create_tuned_minicolumn((180.0f / num_minicolumns) * i));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_minicolumns,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_K_WINNERS,
        .k_winners = k,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.5f,
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    auto input = random_input(100);

    // Run twice
    hypercolumn_compute(hcol, input.data(), input.size());
    std::vector<float> dist1(num_minicolumns);
    hypercolumn_get_distribution(hcol, dist1.data(), num_minicolumns);

    hypercolumn_compute(hcol, input.data(), input.size());
    std::vector<float> dist2(num_minicolumns);
    hypercolumn_get_distribution(hcol, dist2.data(), num_minicolumns);

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }

    // Find active units
    std::vector<uint32_t> active1, active2;
    for (uint32_t i = 0; i < num_minicolumns; i++) {
        if (dist1[i] > 0.01f) active1.push_back(i);
        if (dist2[i] > 0.01f) active2.push_back(i);
    }

    EXPECT_EQ(active1, active2) << "Sparse codes differ";
}

//=============================================================================
// CATEGORY 5: Surround Suppression Consistency
//=============================================================================

TEST_F(CorticalFeaturesRegressionTest, LateralInhibitionEffect) {
    // WHAT: Verify lateral inhibition reduces activation
    // WHY:  Inhibition should suppress activity
    // TARGET: Activation decreases after inhibition

    ASSERT_NE(pool, nullptr);

    auto config = create_tuned_minicolumn(45.0f);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    auto input = random_input(100);

    // Compute without inhibition
    float activation_before = minicolumn_compute(col, input.data(), input.size());

    // Apply inhibition
    minicolumn_apply_lateral_inhibition(col, 0.5f);

    // Get stats to check inhibition level
    minicolumn_stats_t stats;
    minicolumn_get_stats(col, &stats);

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    if (activation_before >= 0.0f) {
        EXPECT_GE(stats.inhibition_level, 0.0f);
    }
}

TEST_F(CorticalFeaturesRegressionTest, LateralInhibitionDeterminism) {
    // WHAT: Verify lateral inhibition is deterministic
    // WHY:  Same inhibition amount must produce same result
    // TARGET: Activation levels match

    ASSERT_NE(pool, nullptr);

    auto config = create_tuned_minicolumn(45.0f);
    minicolumn_t* col1 = minicolumn_create(pool, &config);
    ASSERT_NE(col1, nullptr);

    auto input = random_input(100);

    // First column
    minicolumn_compute(col1, input.data(), input.size());
    minicolumn_apply_lateral_inhibition(col1, 0.3f);

    minicolumn_stats_t stats1;
    minicolumn_get_stats(col1, &stats1);

    // Second column with same processing
    minicolumn_t* col2 = minicolumn_create(pool, &config);
    ASSERT_NE(col2, nullptr);

    minicolumn_compute(col2, input.data(), input.size());
    minicolumn_apply_lateral_inhibition(col2, 0.3f);

    minicolumn_stats_t stats2;
    minicolumn_get_stats(col2, &stats2);

    minicolumn_destroy(col1);
    minicolumn_destroy(col2);
    free_minicolumn_config(config);

    EXPECT_FLOAT_EQ(stats1.activation_level, stats2.activation_level);
    EXPECT_FLOAT_EQ(stats1.inhibition_level, stats2.inhibition_level);
}

TEST_F(CorticalFeaturesRegressionTest, InhibitionBoundsRespected) {
    // WHAT: Verify inhibition respects bounds
    // WHY:  Activation must stay in [0, 1]
    // TARGET: No negative activations after strong inhibition

    ASSERT_NE(pool, nullptr);

    auto config = create_tuned_minicolumn(45.0f);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    auto input = random_input(100);
    minicolumn_compute(col, input.data(), input.size());

    // Apply very strong inhibition
    minicolumn_apply_lateral_inhibition(col, 10.0f);

    minicolumn_stats_t stats;
    minicolumn_get_stats(col, &stats);

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    EXPECT_GE(stats.activation_level, 0.0f) << "Activation went negative";
    EXPECT_LE(stats.activation_level, 1.0f) << "Activation exceeded 1.0";
}

TEST_F(CorticalFeaturesRegressionTest, HypercolumnLateralInhibitionConsistency) {
    // WHAT: Verify hypercolumn lateral inhibition is consistent
    // WHY:  Competition dynamics must be stable
    // TARGET: Same input produces same competition result

    ASSERT_NE(pool, nullptr);

    const uint32_t num_minicolumns = 8;
    std::vector<minicolumn_config_t> configs;

    for (uint32_t i = 0; i < num_minicolumns; i++) {
        configs.push_back(create_tuned_minicolumn((180.0f / num_minicolumns) * i));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_minicolumns,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_SOFTMAX,
        .k_winners = 3,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.8f,  // Strong inhibition
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    auto input = random_input(100);

    // Multiple runs
    std::vector<uint32_t> winners;
    for (int i = 0; i < 10; i++) {
        hypercolumn_compute(hcol, input.data(), input.size());
        winners.push_back(hypercolumn_get_winner(hcol));
    }

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }

    // All winners should be the same
    for (size_t i = 1; i < winners.size(); i++) {
        EXPECT_EQ(winners[0], winners[i]) << "Winner changed at iteration " << i;
    }
}

//=============================================================================
// Performance Benchmarks
//=============================================================================

TEST_F(CorticalFeaturesRegressionTest, OrientationTuningBenchmark) {
    // WHAT: Benchmark orientation tuning computation
    // WHY:  Feature detection must be fast
    // TARGET: >1000 tuning curve samples/sec

    ASSERT_NE(pool, nullptr);

    auto config = create_tuned_minicolumn(45.0f);
    minicolumn_t* col = minicolumn_create(pool, &config);
    ASSERT_NE(col, nullptr);

    auto stimulus = create_oriented_grating(45.0f);

    // Warmup
    for (int i = 0; i < 10; i++) {
        minicolumn_compute(col, stimulus.data(), stimulus.size());
    }

    // Benchmark
    const uint32_t iterations = 1000;
    auto start = std::chrono::high_resolution_clock::now();

    for (uint32_t i = 0; i < iterations; i++) {
        minicolumn_compute(col, stimulus.data(), stimulus.size());
    }

    auto end = std::chrono::high_resolution_clock::now();
    double elapsed_sec = std::chrono::duration<double>(end - start).count();
    double ops_per_sec = iterations / elapsed_sec;

    minicolumn_destroy(col);
    free_minicolumn_config(config);

    EXPECT_GT(ops_per_sec, 1000.0) << "Tuning computation: " << ops_per_sec << " ops/sec";
}

TEST_F(CorticalFeaturesRegressionTest, FeatureMapBenchmark) {
    // WHAT: Benchmark feature map generation
    // WHY:  Feature extraction must be fast
    // TARGET: >500 feature maps/sec

    ASSERT_NE(pool, nullptr);

    const uint32_t num_minicolumns = 16;
    std::vector<minicolumn_config_t> configs;

    for (uint32_t i = 0; i < num_minicolumns; i++) {
        configs.push_back(create_tuned_minicolumn((180.0f / num_minicolumns) * i));
    }

    hypercolumn_config_t hcol_config = {
        .num_minicolumns = num_minicolumns,
        .minicolumn_configs = configs.data(),
        .feature_space_min = 0.0f,
        .feature_space_max = 180.0f,
        .topographic_x = 0.0f,
        .topographic_y = 0.0f,
        .competition = CC_COMPETITION_SOFTMAX,
        .k_winners = 3,
        .temperature = 1.0f,
        .lateral_inhibition_strength = 0.5f,
        .lateral_inhibition_sigma1 = 1.0f,
        .lateral_inhibition_sigma2 = 3.0f
    };

    hypercolumn_t* hcol = hypercolumn_create(pool, &hcol_config);
    ASSERT_NE(hcol, nullptr);

    auto input = random_input(100);
    std::vector<float> distribution(num_minicolumns);

    // Warmup
    for (int i = 0; i < 10; i++) {
        hypercolumn_compute(hcol, input.data(), input.size());
        hypercolumn_get_distribution(hcol, distribution.data(), num_minicolumns);
    }

    // Benchmark
    const uint32_t iterations = 500;
    auto start = std::chrono::high_resolution_clock::now();

    for (uint32_t i = 0; i < iterations; i++) {
        hypercolumn_compute(hcol, input.data(), input.size());
        hypercolumn_get_distribution(hcol, distribution.data(), num_minicolumns);
    }

    auto end = std::chrono::high_resolution_clock::now();
    double elapsed_sec = std::chrono::duration<double>(end - start).count();
    double ops_per_sec = iterations / elapsed_sec;

    hypercolumn_destroy(hcol);
    for (auto& config : configs) {
        free_minicolumn_config(config);
    }

    EXPECT_GT(ops_per_sec, 500.0) << "Feature map generation: " << ops_per_sec << " ops/sec";
}

//=============================================================================
// Main
//=============================================================================

int main(int argc, char** argv) {
    ::testing::InitGoogleTest(&argc, argv);
    return RUN_ALL_TESTS();
}
