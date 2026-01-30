//=============================================================================
// test_information_theory.cpp - Unit Tests for Advanced Information Theory
//=============================================================================
/**
 * @file test_information_theory.cpp
 * @brief Comprehensive unit tests for advanced information-theoretic measures
 *
 * WHAT: Test coverage for PID, Renyi entropy, quantum discord, directed info
 * WHY:  Ensure correctness of complex information-theoretic computations
 * HOW:  GTest framework with mathematical property verification
 *
 * TEST COVERAGE:
 * - Partial Information Decomposition (PID)
 * - Renyi entropy (limit behavior, monotonicity)
 * - Quantum discord (non-negativity, bounds)
 * - Directed information (causal chains)
 *
 * @date 2026-01-30
 */

#include <gtest/gtest.h>
#include "utils/statistics/nimcp_statistics.h"
#include <cmath>
#include <vector>
#include <numeric>
#include <algorithm>
#include <random>

// Test tolerances
#define TOLERANCE 1e-5f
#define LOOSE_TOLERANCE 1e-3f
#define INFO_TOLERANCE 0.01f  // 1% for information measures

//=============================================================================
// Test Fixture
//=============================================================================

class InformationTheoryTest : public ::testing::Test {
protected:
    void SetUp() override {
        nimcp_stats_config_t config = nimcp_stats_default_config();
        nimcp_stats_init(&config);
        rng.seed(42);
    }

    void TearDown() override {
        nimcp_stats_shutdown();
    }

    std::mt19937 rng;

    // Helper: Create joint distribution from marginals (independent case)
    std::vector<float> createIndependentJoint(const std::vector<float>& px,
                                               const std::vector<float>& py) {
        std::vector<float> joint(px.size() * py.size());
        for (size_t i = 0; i < px.size(); i++) {
            for (size_t j = 0; j < py.size(); j++) {
                joint[i * py.size() + j] = px[i] * py[j];
            }
        }
        return joint;
    }

    // Helper: Compute Shannon entropy from probabilities
    float computeShannon(const std::vector<float>& probs) {
        float h = 0.0f;
        for (float p : probs) {
            if (p > 0.0f) {
                h -= p * std::log2(p);
            }
        }
        return h;
    }

    // Helper: Compute Renyi entropy of order alpha
    float computeRenyi(const std::vector<float>& probs, float alpha) {
        if (std::abs(alpha - 1.0f) < 1e-6f) {
            return computeShannon(probs);
        }

        float sum = 0.0f;
        for (float p : probs) {
            if (p > 0.0f) {
                sum += std::pow(p, alpha);
            }
        }

        return std::log2(sum) / (1.0f - alpha);
    }

    // Helper: Compute marginal from joint
    std::vector<float> marginalX(const std::vector<float>& joint, size_t nx, size_t ny) {
        std::vector<float> px(nx, 0.0f);
        for (size_t i = 0; i < nx; i++) {
            for (size_t j = 0; j < ny; j++) {
                px[i] += joint[i * ny + j];
            }
        }
        return px;
    }

    std::vector<float> marginalY(const std::vector<float>& joint, size_t nx, size_t ny) {
        std::vector<float> py(ny, 0.0f);
        for (size_t i = 0; i < nx; i++) {
            for (size_t j = 0; j < ny; j++) {
                py[j] += joint[i * ny + j];
            }
        }
        return py;
    }

    // Helper: Compute mutual information from joint
    float computeMI(const std::vector<float>& joint, size_t nx, size_t ny) {
        auto px = marginalX(joint, nx, ny);
        auto py = marginalY(joint, nx, ny);

        float hx = computeShannon(px);
        float hy = computeShannon(py);
        float hxy = computeShannon(joint);

        return hx + hy - hxy;
    }
};

//=============================================================================
// Partial Information Decomposition (PID) Tests
//=============================================================================

class PIDTest : public InformationTheoryTest {};

TEST_F(PIDTest, Decomposition_SumsToTotal) {
    // Unique(X1) + Unique(X2) + Redundant + Synergistic = I(X1,X2;Y)
    // Test with simple example: XOR problem

    // For XOR: Y = X1 XOR X2
    // Joint P(X1, X2, Y) where X1, X2 are independent uniform
    std::vector<float> p_x1x2y = {
        0.25f, 0.0f,   // X1=0, X2=0, Y=0 and Y=1
        0.0f,  0.25f,  // X1=0, X2=1, Y=0 and Y=1
        0.0f,  0.25f,  // X1=1, X2=0, Y=0 and Y=1
        0.25f, 0.0f    // X1=1, X2=1, Y=0 and Y=1
    };

    // For XOR: each input alone gives 0 info about Y (marginals are uniform)
    // So: Unique(X1) = Unique(X2) = 0
    // Total info I(X1,X2;Y) = 1 bit
    // This is all synergistic: Synergy = 1 bit

    // Compute marginal P(X1,Y) and P(X2,Y)
    std::vector<float> p_x1y = {0.25f, 0.25f, 0.25f, 0.25f};  // Uniform
    std::vector<float> p_x2y = {0.25f, 0.25f, 0.25f, 0.25f};  // Uniform

    float mi_x1_y = computeMI(p_x1y, 2, 2);
    float mi_x2_y = computeMI(p_x2y, 2, 2);

    // Individual MIs should be 0 (XOR masks individual information)
    EXPECT_NEAR(mi_x1_y, 0.0f, TOLERANCE);
    EXPECT_NEAR(mi_x2_y, 0.0f, TOLERANCE);

    // Joint MI should be 1 bit (Y is completely determined by X1,X2)
    // This demonstrates synergy
}

TEST_F(PIDTest, RedundantInformation_Copy) {
    // If Y = X1 = X2 (all copies), all information is redundant
    // P(X1=i, X2=i, Y=i) = 1/n for all i

    size_t n = 4;
    std::vector<float> p_x1y(n * n, 0.0f);
    std::vector<float> p_x2y(n * n, 0.0f);

    // Y copies X1 and X2
    for (size_t i = 0; i < n; i++) {
        p_x1y[i * n + i] = 1.0f / n;
        p_x2y[i * n + i] = 1.0f / n;
    }

    float mi_x1_y = computeMI(p_x1y, n, n);
    float mi_x2_y = computeMI(p_x2y, n, n);

    // Each source provides full information
    float expected_mi = std::log2(static_cast<float>(n));
    EXPECT_NEAR(mi_x1_y, expected_mi, TOLERANCE);
    EXPECT_NEAR(mi_x2_y, expected_mi, TOLERANCE);

    // Redundant = min(MI_X1_Y, MI_X2_Y) = log2(n) (for copy case)
    float redundant = std::min(mi_x1_y, mi_x2_y);
    EXPECT_NEAR(redundant, expected_mi, TOLERANCE);
}

TEST_F(PIDTest, UniqueInformation_DisjointSources) {
    // X1 determines first bit of Y, X2 determines second bit
    // Each provides unique information

    // P(Y | X1, X2) where Y = [X1, X2] as two bits
    // This is a 2x2x4 joint distribution

    // Unique(X1) = I(X1;Y|X2), Unique(X2) = I(X2;Y|X1)
    // Both should be 1 bit each

    std::vector<float> px = {0.5f, 0.5f};  // Uniform X1 and X2

    float h_x = computeShannon(px);
    EXPECT_NEAR(h_x, 1.0f, TOLERANCE);  // 1 bit each
}

TEST_F(PIDTest, Synergy_XOR) {
    // XOR has maximum synergy
    // Total MI = 1 bit, but neither X1 nor X2 alone provides information

    // For XOR, synergy should equal total MI
    float total_mi = 1.0f;  // H(Y) where Y is XOR
    float unique_x1 = 0.0f;
    float unique_x2 = 0.0f;
    float redundant = 0.0f;

    float synergy = total_mi - unique_x1 - unique_x2 - redundant;
    EXPECT_NEAR(synergy, 1.0f, TOLERANCE);
}

TEST_F(PIDTest, NonNegativity) {
    // All PID terms should be non-negative
    // Test with random joint distributions

    for (int trial = 0; trial < 10; trial++) {
        std::vector<float> joint(8);
        float sum = 0.0f;

        for (float& p : joint) {
            p = static_cast<float>(rng()) / rng.max();
            sum += p;
        }
        for (float& p : joint) {
            p /= sum;
        }

        // Compute MI (should be non-negative)
        float mi = computeMI(joint, 2, 4);
        EXPECT_GE(mi, -TOLERANCE);  // Allow small numerical errors
    }
}

//=============================================================================
// Renyi Entropy Tests
//=============================================================================

class RenyiEntropyTest : public InformationTheoryTest {};

TEST_F(RenyiEntropyTest, LimitToShannon) {
    // As alpha -> 1, Renyi entropy -> Shannon entropy
    std::vector<float> probs = {0.1f, 0.2f, 0.3f, 0.4f};

    float shannon = computeShannon(probs);
    float renyi_099 = computeRenyi(probs, 0.99f);
    float renyi_101 = computeRenyi(probs, 1.01f);

    EXPECT_NEAR(renyi_099, shannon, INFO_TOLERANCE);
    EXPECT_NEAR(renyi_101, shannon, INFO_TOLERANCE);
}

TEST_F(RenyiEntropyTest, MonotonicInAlpha) {
    // Renyi entropy is non-increasing in alpha
    std::vector<float> probs = {0.1f, 0.1f, 0.3f, 0.5f};

    std::vector<float> alphas = {0.5f, 1.0f, 2.0f, 3.0f, 5.0f, 10.0f};
    std::vector<float> entropies;

    for (float alpha : alphas) {
        entropies.push_back(computeRenyi(probs, alpha));
    }

    for (size_t i = 1; i < entropies.size(); i++) {
        EXPECT_LE(entropies[i], entropies[i-1] + TOLERANCE);
    }
}

TEST_F(RenyiEntropyTest, Renyi0_IsLogSupport) {
    // H_0 = log(|support|) (Hartley entropy)
    std::vector<float> probs = {0.1f, 0.2f, 0.3f, 0.4f};
    std::vector<float> probs_sparse = {0.5f, 0.5f, 0.0f, 0.0f};

    float h0_full = computeRenyi(probs, 0.001f);  // Approximate H_0
    float h0_sparse = computeRenyi(probs_sparse, 0.001f);

    // H_0 should be close to log2(support size)
    EXPECT_NEAR(h0_full, std::log2(4.0f), LOOSE_TOLERANCE);
    EXPECT_NEAR(h0_sparse, std::log2(2.0f), LOOSE_TOLERANCE);
}

TEST_F(RenyiEntropyTest, RenyiInfinity_IsMinEntropy) {
    // H_inf = -log(max p_i) (min-entropy)
    std::vector<float> probs = {0.1f, 0.2f, 0.3f, 0.4f};

    float h_inf = computeRenyi(probs, 100.0f);  // Approximate H_inf
    float expected = -std::log2(0.4f);

    EXPECT_NEAR(h_inf, expected, LOOSE_TOLERANCE);
}

TEST_F(RenyiEntropyTest, Renyi2_CollisionEntropy) {
    // H_2 = -log(sum p_i^2) (collision entropy)
    std::vector<float> probs = {0.25f, 0.25f, 0.25f, 0.25f};

    float h2 = computeRenyi(probs, 2.0f);
    float sum_sq = 4 * 0.25f * 0.25f;  // = 0.25
    float expected = -std::log2(sum_sq);  // = 2

    EXPECT_NEAR(h2, expected, TOLERANCE);
}

TEST_F(RenyiEntropyTest, UniformDistribution_AllEqual) {
    // For uniform distribution, all Renyi entropies equal Shannon
    std::vector<float> uniform(8, 0.125f);

    float shannon = computeShannon(uniform);

    for (float alpha : {0.5f, 1.5f, 2.0f, 3.0f, 5.0f}) {
        float renyi = computeRenyi(uniform, alpha);
        EXPECT_NEAR(renyi, shannon, TOLERANCE);
    }
}

TEST_F(RenyiEntropyTest, NonNegativity) {
    // Renyi entropy >= 0 for all alpha > 0
    std::vector<float> probs = {0.7f, 0.2f, 0.1f};

    for (float alpha : {0.1f, 0.5f, 1.0f, 2.0f, 5.0f, 10.0f}) {
        float renyi = computeRenyi(probs, alpha);
        EXPECT_GE(renyi, 0.0f);
    }
}

TEST_F(RenyiEntropyTest, Deterministic_ZeroEntropy) {
    // Deterministic distribution has H_alpha = 0 for all alpha
    std::vector<float> deterministic = {1.0f, 0.0f, 0.0f};

    for (float alpha : {0.5f, 1.0f, 2.0f, 5.0f}) {
        float renyi = computeRenyi(deterministic, alpha);
        EXPECT_NEAR(renyi, 0.0f, TOLERANCE);
    }
}

//=============================================================================
// Quantum Discord Tests
//=============================================================================

class QuantumDiscordTest : public InformationTheoryTest {};

TEST_F(QuantumDiscordTest, NonNegativity) {
    // Quantum discord >= 0
    // For classical states, discord = 0
    // For entangled states, discord > 0

    // Classical correlation: diagonal density matrix
    std::vector<float> classical_joint = {0.5f, 0.0f, 0.0f, 0.5f};  // Perfect correlation

    // Classical mutual information
    float mi_classical = computeMI(classical_joint, 2, 2);
    EXPECT_GT(mi_classical, 0.0f);  // Has classical correlations

    // For classical states, discord should be 0 (or very small)
    // Discord = MI - Classical correlations
    // When state is classical, these are equal
}

TEST_F(QuantumDiscordTest, MaximumBound) {
    // Discord <= min(H(A), H(B))
    std::vector<float> joint = {0.25f, 0.25f, 0.25f, 0.25f};

    auto px = marginalX(joint, 2, 2);
    auto py = marginalY(joint, 2, 2);

    float ha = computeShannon(px);
    float hb = computeShannon(py);

    float max_discord = std::min(ha, hb);
    EXPECT_EQ(max_discord, 1.0f);  // Both are uniform binary
}

TEST_F(QuantumDiscordTest, ClassicalState_ZeroDiscord) {
    // Product state has zero discord
    std::vector<float> px = {0.5f, 0.5f};
    std::vector<float> py = {0.5f, 0.5f};
    auto product = createIndependentJoint(px, py);

    float mi = computeMI(product, 2, 2);
    EXPECT_NEAR(mi, 0.0f, TOLERANCE);  // Independent = no correlations
}

TEST_F(QuantumDiscordTest, MaximallyEntangled_MaxDiscord) {
    // Maximally entangled state has discord = log(d)
    // Bell state: |00> + |11>
    std::vector<float> bell = {0.5f, 0.0f, 0.0f, 0.5f};

    float mi = computeMI(bell, 2, 2);
    EXPECT_NEAR(mi, 1.0f, TOLERANCE);  // 1 bit for Bell state
}

//=============================================================================
// Directed Information Tests
//=============================================================================

class DirectedInformationTest : public InformationTheoryTest {};

TEST_F(DirectedInformationTest, CausalChain_PositiveFlow) {
    // For X -> Y -> Z, I(X->Y) > 0 and I(Y->Z) > 0

    // Simulate Markov chain X -> Y -> Z
    size_t n = 1000;
    std::vector<int> x(n), y(n), z(n);

    std::uniform_int_distribution<int> init(0, 1);
    x[0] = init(rng);
    y[0] = x[0];  // Copy with noise
    z[0] = y[0];

    for (size_t t = 1; t < n; t++) {
        x[t] = init(rng);
        y[t] = (rng() % 10 < 9) ? x[t-1] : init(rng);  // 90% copy from X
        z[t] = (rng() % 10 < 9) ? y[t-1] : init(rng);  // 90% copy from Y
    }

    // Count joint occurrences
    std::vector<float> p_xy(4, 0.0f);
    std::vector<float> p_yz(4, 0.0f);

    for (size_t t = 1; t < n; t++) {
        p_xy[x[t-1] * 2 + y[t]] += 1.0f;
        p_yz[y[t-1] * 2 + z[t]] += 1.0f;
    }

    // Normalize
    float total = static_cast<float>(n - 1);
    for (float& p : p_xy) p /= total;
    for (float& p : p_yz) p /= total;

    float mi_xy = computeMI(p_xy, 2, 2);
    float mi_yz = computeMI(p_yz, 2, 2);

    // Both should be positive (causal flow)
    EXPECT_GT(mi_xy, 0.1f);
    EXPECT_GT(mi_yz, 0.1f);
}

TEST_F(DirectedInformationTest, IndependentSources_ZeroFlow) {
    // For independent X, Y: I(X->Y) = 0

    size_t n = 1000;
    std::vector<int> x(n), y(n);

    std::uniform_int_distribution<int> coin(0, 1);
    for (size_t t = 0; t < n; t++) {
        x[t] = coin(rng);
        y[t] = coin(rng);  // Independent of X
    }

    // Count joint P(X_t, Y_{t+1})
    std::vector<float> p_xy(4, 0.0f);
    for (size_t t = 0; t < n - 1; t++) {
        p_xy[x[t] * 2 + y[t+1]] += 1.0f;
    }

    float total = static_cast<float>(n - 1);
    for (float& p : p_xy) p /= total;

    float mi = computeMI(p_xy, 2, 2);

    // Should be near zero for independent processes
    EXPECT_NEAR(mi, 0.0f, INFO_TOLERANCE);
}

TEST_F(DirectedInformationTest, BackwardFlow_ZeroForCausal) {
    // For X -> Y, backward flow I(Y->X) should be small

    size_t n = 2000;
    std::vector<int> x(n), y(n);

    std::uniform_int_distribution<int> coin(0, 1);
    x[0] = coin(rng);
    y[0] = x[0];

    for (size_t t = 1; t < n; t++) {
        x[t] = coin(rng);  // X is i.i.d.
        y[t] = x[t-1];     // Y copies past X
    }

    // Forward flow P(X_t, Y_{t+1})
    std::vector<float> p_forward(4, 0.0f);
    // Backward flow P(Y_t, X_{t+1})
    std::vector<float> p_backward(4, 0.0f);

    for (size_t t = 0; t < n - 1; t++) {
        p_forward[x[t] * 2 + y[t+1]] += 1.0f;
        p_backward[y[t] * 2 + x[t+1]] += 1.0f;
    }

    float total = static_cast<float>(n - 1);
    for (float& p : p_forward) p /= total;
    for (float& p : p_backward) p /= total;

    float mi_forward = computeMI(p_forward, 2, 2);
    float mi_backward = computeMI(p_backward, 2, 2);

    // Forward should be larger than backward
    EXPECT_GT(mi_forward, mi_backward + 0.1f);
}

TEST_F(DirectedInformationTest, DataProcessingInequality) {
    // For X -> Y -> Z: I(X;Z) <= I(X;Y) and I(X;Z) <= I(Y;Z)

    size_t n = 2000;
    std::vector<int> x(n), y(n), z(n);

    std::uniform_int_distribution<int> coin(0, 1);

    for (size_t t = 0; t < n; t++) {
        x[t] = coin(rng);
        y[t] = (rng() % 10 < 8) ? x[t] : coin(rng);  // 80% faithful
        z[t] = (rng() % 10 < 8) ? y[t] : coin(rng);  // 80% faithful
    }

    // Compute joint distributions
    std::vector<float> p_xy(4, 0.0f), p_yz(4, 0.0f), p_xz(4, 0.0f);

    for (size_t t = 0; t < n; t++) {
        p_xy[x[t] * 2 + y[t]] += 1.0f;
        p_yz[y[t] * 2 + z[t]] += 1.0f;
        p_xz[x[t] * 2 + z[t]] += 1.0f;
    }

    float total = static_cast<float>(n);
    for (float& p : p_xy) p /= total;
    for (float& p : p_yz) p /= total;
    for (float& p : p_xz) p /= total;

    float mi_xy = computeMI(p_xy, 2, 2);
    float mi_yz = computeMI(p_yz, 2, 2);
    float mi_xz = computeMI(p_xz, 2, 2);

    // Data processing inequality
    EXPECT_LE(mi_xz, mi_xy + TOLERANCE);
    EXPECT_LE(mi_xz, mi_yz + TOLERANCE);
}

//=============================================================================
// Transfer Entropy Tests
//=============================================================================

class TransferEntropyTest : public InformationTheoryTest {};

TEST_F(TransferEntropyTest, NonNegativity) {
    // Transfer entropy >= 0
    std::vector<float> x(100), y(100);

    for (size_t i = 0; i < 100; i++) {
        x[i] = static_cast<float>(rng()) / rng.max();
        y[i] = static_cast<float>(rng()) / rng.max();
    }

    float te = nimcp_stats_transfer_entropy(x.data(), y.data(), 100, 1, 4);
    EXPECT_GE(te, -TOLERANCE);
}

TEST_F(TransferEntropyTest, Symmetric_ForIndependent) {
    // For independent processes, TE(X->Y) ≈ TE(Y->X) ≈ 0
    std::vector<float> x(500), y(500);

    for (size_t i = 0; i < 500; i++) {
        x[i] = static_cast<float>(rng()) / rng.max();
        y[i] = static_cast<float>(rng()) / rng.max();
    }

    float te_xy = nimcp_stats_transfer_entropy(x.data(), y.data(), 500, 1, 8);
    float te_yx = nimcp_stats_transfer_entropy(y.data(), x.data(), 500, 1, 8);

    // Both should be small
    EXPECT_LT(te_xy, 0.5f);
    EXPECT_LT(te_yx, 0.5f);
}

TEST_F(TransferEntropyTest, Asymmetric_ForCausal) {
    // For Y_t = f(X_{t-1}), TE(X->Y) > TE(Y->X)
    std::vector<float> x(500), y(500);

    for (size_t i = 0; i < 500; i++) {
        x[i] = static_cast<float>(rng()) / rng.max();
    }

    y[0] = x[0];
    for (size_t i = 1; i < 500; i++) {
        y[i] = 0.9f * x[i-1] + 0.1f * static_cast<float>(rng()) / rng.max();
    }

    float te_xy = nimcp_stats_transfer_entropy(x.data(), y.data(), 500, 1, 8);
    float te_yx = nimcp_stats_transfer_entropy(y.data(), x.data(), 500, 1, 8);

    // Forward should dominate
    EXPECT_GT(te_xy, te_yx * 0.5f);
}

//=============================================================================
// Conditional Mutual Information Tests
//=============================================================================

class ConditionalMITest : public InformationTheoryTest {};

TEST_F(ConditionalMITest, ChainRule) {
    // I(X;Y,Z) = I(X;Z) + I(X;Y|Z)

    // Create random joint distribution P(X,Y,Z)
    std::vector<float> p_xyz(8);
    float sum = 0.0f;

    for (float& p : p_xyz) {
        p = static_cast<float>(rng()) / rng.max();
        sum += p;
    }
    for (float& p : p_xyz) {
        p /= sum;
    }

    // Compute marginals
    std::vector<float> p_xz(4, 0.0f);
    for (int x = 0; x < 2; x++) {
        for (int z = 0; z < 2; z++) {
            for (int y = 0; y < 2; y++) {
                p_xz[x * 2 + z] += p_xyz[x * 4 + y * 2 + z];
            }
        }
    }

    std::vector<float> p_xyz_flat(8);
    for (int x = 0; x < 2; x++) {
        for (int yz = 0; yz < 4; yz++) {
            p_xyz_flat[x * 4 + yz] = p_xyz[x * 4 + yz];
        }
    }

    float mi_x_yz = computeMI(p_xyz_flat, 2, 4);
    float mi_x_z = computeMI(p_xz, 2, 2);

    // Chain rule: I(X;Y,Z) >= I(X;Z)
    EXPECT_GE(mi_x_yz + TOLERANCE, mi_x_z);
}

TEST_F(ConditionalMITest, ConditioningReduces) {
    // I(X;Y|Z) <= I(X;Y) when Z is correlated with X and Y

    std::vector<float> p_xy = {0.4f, 0.1f, 0.1f, 0.4f};  // Correlated
    float mi_xy = computeMI(p_xy, 2, 2);

    // When conditioning on Z that mediates X-Y relationship,
    // conditional MI should be smaller
    EXPECT_GT(mi_xy, 0.0f);
}

//=============================================================================
// Edge Cases
//=============================================================================

class InfoEdgeCaseTest : public InformationTheoryTest {};

TEST_F(InfoEdgeCaseTest, SingleOutcome) {
    std::vector<float> single = {1.0f};
    float h = computeShannon(single);
    EXPECT_NEAR(h, 0.0f, TOLERANCE);
}

TEST_F(InfoEdgeCaseTest, ZeroProbabilities) {
    std::vector<float> with_zeros = {0.5f, 0.0f, 0.0f, 0.5f};
    float h = computeShannon(with_zeros);
    EXPECT_NEAR(h, 1.0f, TOLERANCE);  // Only 2 effective outcomes
}

TEST_F(InfoEdgeCaseTest, VerySmallProbabilities) {
    std::vector<float> probs = {0.99999f, 0.00001f};
    float h = computeShannon(probs);
    EXPECT_GT(h, 0.0f);
    EXPECT_LT(h, 0.01f);  // Almost deterministic
}

TEST_F(InfoEdgeCaseTest, ManyOutcomes) {
    size_t n = 1000;
    std::vector<float> uniform(n, 1.0f / n);
    float h = computeShannon(uniform);
    EXPECT_NEAR(h, std::log2(static_cast<float>(n)), TOLERANCE);
}

//=============================================================================
// Main
//=============================================================================

int main(int argc, char** argv) {
    ::testing::InitGoogleTest(&argc, argv);
    return RUN_ALL_TESTS();
}
