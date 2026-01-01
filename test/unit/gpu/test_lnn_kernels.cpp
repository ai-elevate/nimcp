/**
 * @file test_lnn_kernels.cpp
 * @brief Comprehensive unit tests for GPU LNN kernels
 *
 * WHAT: Tests for GPU-accelerated Liquid Neural Network operations
 * WHY:  Verify ODE solvers, LTC dynamics, sparse operations, and gradients
 * HOW:  GoogleTest with GPU context setup/teardown and numerical verification
 *
 * TEST COVERAGE:
 * - ODE solvers: Euler, Heun (RK2), RK4, DOPRI5 adaptive
 * - LTC derivative computation
 * - Tau (time constant) updates
 * - Sparse matrix operations (CSR format)
 * - Adjoint method for gradients
 * - Layer lifecycle (create, forward, destroy)
 *
 * @author NIMCP Development Team
 * @date 2025
 */

#include <gtest/gtest.h>
#include <cstring>
#include <cmath>
#include <vector>
#include <algorithm>
#include <numeric>

// GPU headers include CUDA headers that cannot be in extern "C" blocks
#include "gpu/lnn/nimcp_lnn_gpu.h"
#include "gpu/context/nimcp_gpu_context.h"
#include "gpu/tensor/nimcp_tensor_gpu.h"

extern "C" {
#include "lnn/nimcp_lnn_types.h"
#include "utils/tensor/nimcp_tensor.h"
}

//=============================================================================
// Test Constants
//=============================================================================

static constexpr size_t DEFAULT_N_NEURONS = 50;
static constexpr size_t SMALL_N_NEURONS = 10;
static constexpr size_t LARGE_N_NEURONS = 500;
static constexpr size_t DEFAULT_N_INPUTS = 20;
static constexpr float DEFAULT_DT = 1.0f;        // 1ms timestep
static constexpr float DEFAULT_TAU_BASE = 10.0f; // Base time constant (ms)
static constexpr float DEFAULT_ERROR_TOL = 1e-4f;
static constexpr float NUMERICAL_EPS = 1e-6f;

//=============================================================================
// Test Fixture
//=============================================================================

/**
 * @brief Test fixture for GPU LNN kernel tests
 *
 * WHAT: Provides GPU context setup/teardown and helper utilities
 * WHY:  Ensure proper GPU resource management across tests
 * HOW:  Creates context in SetUp, destroys in TearDown, provides tensor helpers
 */
class LNNKernelTest : public ::testing::Test {
protected:
    nimcp_gpu_context_t* ctx = nullptr;
    bool gpu_available = false;

    void SetUp() override {
        ctx = nimcp_gpu_context_create_auto();
        gpu_available = (ctx != nullptr && nimcp_gpu_context_is_valid(ctx));
    }

    void TearDown() override {
        if (ctx) {
            nimcp_gpu_context_destroy(ctx);
            ctx = nullptr;
        }
    }

    /**
     * @brief Skip test if GPU not available
     */
    void RequireGPU() {
        if (!gpu_available) {
            GTEST_SKIP() << "GPU not available, skipping test";
        }
    }

    /**
     * @brief Create default ODE configuration
     */
    nimcp_lnn_ode_config_t create_default_ode_config(lnn_ode_method_t method = LNN_ODE_RK4) {
        nimcp_lnn_ode_config_t config;
        config.method = method;
        config.dt = DEFAULT_DT;
        config.dt_min = 0.01f;
        config.dt_max = 10.0f;
        config.error_tolerance = DEFAULT_ERROR_TOL;
        config.max_steps = 100;
        config.adaptive_stepping = (method == LNN_ODE_DOPRI5);
        return config;
    }

    /**
     * @brief Create GPU tensor from host data
     */
    nimcp_gpu_tensor_t* create_tensor_from_data(const float* data, size_t size) {
        if (!gpu_available) return nullptr;
        size_t dims[1] = {size};
        return nimcp_gpu_tensor_from_host(ctx, data, dims, 1, NIMCP_GPU_PRECISION_FP32);
    }

    /**
     * @brief Create GPU tensor filled with zeros
     */
    nimcp_gpu_tensor_t* create_zero_tensor(size_t size) {
        if (!gpu_available) return nullptr;
        size_t dims[1] = {size};
        nimcp_gpu_tensor_t* tensor = nimcp_gpu_tensor_create(ctx, dims, 1, NIMCP_GPU_PRECISION_FP32);
        if (tensor) {
            nimcp_gpu_zeros(ctx, tensor);
        }
        return tensor;
    }

    /**
     * @brief Create GPU tensor filled with a value
     */
    nimcp_gpu_tensor_t* create_filled_tensor(size_t size, float value) {
        if (!gpu_available) return nullptr;
        size_t dims[1] = {size};
        nimcp_gpu_tensor_t* tensor = nimcp_gpu_tensor_create(ctx, dims, 1, NIMCP_GPU_PRECISION_FP32);
        if (tensor) {
            nimcp_gpu_fill(ctx, tensor, value);
        }
        return tensor;
    }

    /**
     * @brief Create 2D GPU tensor (matrix)
     */
    nimcp_gpu_tensor_t* create_matrix(size_t rows, size_t cols, float value) {
        if (!gpu_available) return nullptr;
        size_t dims[2] = {rows, cols};
        nimcp_gpu_tensor_t* tensor = nimcp_gpu_tensor_create(ctx, dims, 2, NIMCP_GPU_PRECISION_FP32);
        if (tensor) {
            nimcp_gpu_fill(ctx, tensor, value);
        }
        return tensor;
    }

    /**
     * @brief Create integer tensor (for sparse indices)
     */
    nimcp_gpu_tensor_t* create_int_tensor(const uint32_t* data, size_t size) {
        if (!gpu_available) return nullptr;
        size_t dims[1] = {size};
        return nimcp_gpu_tensor_from_host(ctx, data, dims, 1, NIMCP_GPU_PRECISION_UINT32);
    }

    /**
     * @brief Copy tensor data to host
     */
    bool copy_to_host(const nimcp_gpu_tensor_t* tensor, float* host_data) {
        if (!tensor || !host_data) return false;
        return nimcp_gpu_tensor_to_host(tensor, host_data);
    }

    /**
     * @brief Create mock CPU LNN layer for testing GPU layer creation
     * @param n_neurons Number of neurons (default: SMALL_N_NEURONS)
     * @param n_inputs Number of inputs (default: DEFAULT_N_INPUTS)
     */
    lnn_layer_t* create_mock_cpu_layer(size_t n_neurons = SMALL_N_NEURONS,
                                        size_t n_inputs = DEFAULT_N_INPUTS) {
        lnn_layer_t* layer = static_cast<lnn_layer_t*>(calloc(1, sizeof(lnn_layer_t)));
        if (!layer) return nullptr;

        layer->n_neurons = n_neurons;
        layer->ode_method = LNN_ODE_RK4;
        layer->dt = DEFAULT_DT;

        // Allocate neurons array
        layer->neurons = static_cast<lnn_neuron_t*>(
            calloc(layer->n_neurons, sizeof(lnn_neuron_t)));

        if (layer->neurons) {
            for (uint32_t i = 0; i < layer->n_neurons; i++) {
                layer->neurons[i].id = i;
                layer->neurons[i].x = 0.0f;
                layer->neurons[i].tau_base = DEFAULT_TAU_BASE;
                layer->neurons[i].tau_current = DEFAULT_TAU_BASE;
                layer->neurons[i].n_inputs = n_inputs;
                layer->neurons[i].activation = LNN_ACTIVATION_TANH;
            }
        }

        // Dimension arrays (uint32_t for tensor API)
        uint32_t state_dims[] = {(uint32_t)n_neurons};
        uint32_t w_in_dims[] = {(uint32_t)n_neurons, (uint32_t)n_inputs};
        uint32_t w_rec_dims[] = {(uint32_t)n_neurons, (uint32_t)n_neurons};

        // Create state tensor x [n_neurons] - zero initialized
        layer->x = nimcp_tensor_zeros(state_dims, 1, NIMCP_DTYPE_F32);

        // Create dx_dt tensor [n_neurons] - zero initialized
        layer->dx_dt = nimcp_tensor_zeros(state_dims, 1, NIMCP_DTYPE_F32);

        // Create tau tensor [n_neurons] - filled with tau base
        layer->tau = nimcp_tensor_full(state_dims, 1, NIMCP_DTYPE_F32, DEFAULT_TAU_BASE);

        // Create tau_base tensor [n_neurons] - filled with tau base
        layer->tau_base = nimcp_tensor_full(state_dims, 1, NIMCP_DTYPE_F32, DEFAULT_TAU_BASE);

        // Create W_in weight matrix [n_neurons, n_inputs]
        layer->W_in = nimcp_tensor_zeros(w_in_dims, 2, NIMCP_DTYPE_F32);
        if (layer->W_in) {
            // Initialize with small random-like values (deterministic for testing)
            float* data = static_cast<float*>(nimcp_tensor_data(layer->W_in));
            if (data) {
                for (size_t i = 0; i < n_neurons * n_inputs; i++) {
                    data[i] = 0.1f * ((float)(i % 10) - 5.0f) / 5.0f;
                }
            }
        }

        // Create W_rec recurrent weight matrix [n_neurons, n_neurons]
        layer->W_rec = nimcp_tensor_zeros(w_rec_dims, 2, NIMCP_DTYPE_F32);
        if (layer->W_rec) {
            // Add small diagonal for stability
            float* data = static_cast<float*>(nimcp_tensor_data(layer->W_rec));
            if (data) {
                for (size_t i = 0; i < n_neurons; i++) {
                    data[i * n_neurons + i] = 0.1f;
                }
            }
        }

        // Create b_in bias [n_neurons] - zero initialized
        layer->b_in = nimcp_tensor_zeros(state_dims, 1, NIMCP_DTYPE_F32);

        // Create W_tau weight matrix for tau modulation [n_neurons, n_inputs + n_neurons]
        uint32_t w_tau_dims[] = {(uint32_t)n_neurons, (uint32_t)(n_inputs + n_neurons)};
        layer->W_tau = nimcp_tensor_zeros(w_tau_dims, 2, NIMCP_DTYPE_F32);

        // Create b_tau bias [n_neurons] - zero initialized
        layer->b_tau = nimcp_tensor_zeros(state_dims, 1, NIMCP_DTYPE_F32);

        return layer;
    }

    /**
     * @brief Free mock CPU layer
     */
    void free_mock_cpu_layer(lnn_layer_t* layer) {
        if (!layer) return;
        if (layer->neurons) free(layer->neurons);
        if (layer->x) nimcp_tensor_destroy(layer->x);
        if (layer->dx_dt) nimcp_tensor_destroy(layer->dx_dt);
        if (layer->tau) nimcp_tensor_destroy(layer->tau);
        if (layer->tau_base) nimcp_tensor_destroy(layer->tau_base);
        if (layer->W_in) nimcp_tensor_destroy(layer->W_in);
        if (layer->W_rec) nimcp_tensor_destroy(layer->W_rec);
        if (layer->W_tau) nimcp_tensor_destroy(layer->W_tau);
        if (layer->b_in) nimcp_tensor_destroy(layer->b_in);
        if (layer->b_tau) nimcp_tensor_destroy(layer->b_tau);
        free(layer);
    }
};

//=============================================================================
// ODE Configuration Tests
//=============================================================================

/**
 * TEST: Default ODE configuration
 * WHAT: Get default ODE configuration
 * WHY:  Verify sensible defaults are provided
 */
TEST_F(LNNKernelTest, ODEConfig_Default_HasReasonableValues) {
    nimcp_lnn_ode_config_t config = nimcp_lnn_ode_default_config();

    EXPECT_EQ(config.method, LNN_ODE_RK4) << "Default method should be RK4";
    EXPECT_GT(config.dt, 0.0f) << "Default dt should be positive";
    EXPECT_LT(config.dt_min, config.dt_max) << "dt_min should be less than dt_max";
    EXPECT_GT(config.error_tolerance, 0.0f) << "Error tolerance should be positive";
    EXPECT_GT(config.max_steps, 0u) << "Max steps should be positive";
}

//=============================================================================
// Euler ODE Solver Tests
//=============================================================================

/**
 * TEST: Euler step on simple decay
 * WHAT: Apply Euler step to exponential decay dx/dt = -x/tau
 * WHY:  Verify basic Euler integration
 */
TEST_F(LNNKernelTest, EulerStep_SimpleDecay_Correct) {
    RequireGPU();

    const float tau = 10.0f;
    const float dt = 1.0f;
    const float x0 = 1.0f;

    // Initial state
    nimcp_gpu_tensor_t* x = create_filled_tensor(SMALL_N_NEURONS, x0);
    ASSERT_NE(x, nullptr);

    // Derivative: dx/dt = -x/tau
    std::vector<float> dx_data(SMALL_N_NEURONS);
    for (size_t i = 0; i < SMALL_N_NEURONS; i++) {
        dx_data[i] = -x0 / tau;  // = -0.1
    }
    nimcp_gpu_tensor_t* dx_dt = create_tensor_from_data(dx_data.data(), SMALL_N_NEURONS);
    ASSERT_NE(dx_dt, nullptr);

    // Output tensor
    nimcp_gpu_tensor_t* x_new = create_zero_tensor(SMALL_N_NEURONS);
    ASSERT_NE(x_new, nullptr);

    bool result = nimcp_gpu_lnn_euler_step(ctx, x, dx_dt, dt, x_new);
    EXPECT_TRUE(result);

    // Expected: x_new = x + dt * dx_dt = 1.0 + 1.0 * (-0.1) = 0.9
    std::vector<float> x_new_host(SMALL_N_NEURONS);
    copy_to_host(x_new, x_new_host.data());

    for (float val : x_new_host) {
        EXPECT_NEAR(val, 0.9f, NUMERICAL_EPS);
    }

    nimcp_gpu_tensor_destroy(x);
    nimcp_gpu_tensor_destroy(dx_dt);
    nimcp_gpu_tensor_destroy(x_new);
}

/**
 * TEST: Euler step with NULL tensors
 * WHAT: Try Euler with NULL inputs
 * WHY:  Verify NULL-safety
 */
TEST_F(LNNKernelTest, EulerStep_NullTensors_ReturnsFalse) {
    RequireGPU();

    nimcp_gpu_tensor_t* x = create_filled_tensor(SMALL_N_NEURONS, 1.0f);
    nimcp_gpu_tensor_t* dx_dt = create_zero_tensor(SMALL_N_NEURONS);
    nimcp_gpu_tensor_t* x_new = create_zero_tensor(SMALL_N_NEURONS);

    EXPECT_FALSE(nimcp_gpu_lnn_euler_step(ctx, nullptr, dx_dt, 1.0f, x_new));
    EXPECT_FALSE(nimcp_gpu_lnn_euler_step(ctx, x, nullptr, 1.0f, x_new));
    EXPECT_FALSE(nimcp_gpu_lnn_euler_step(ctx, x, dx_dt, 1.0f, nullptr));

    nimcp_gpu_tensor_destroy(x);
    nimcp_gpu_tensor_destroy(dx_dt);
    nimcp_gpu_tensor_destroy(x_new);
}

/**
 * TEST: Euler step convergence
 * WHAT: Multiple Euler steps should converge to steady state
 * WHY:  Verify integration stability
 */
TEST_F(LNNKernelTest, EulerStep_MultipleSteps_Converges) {
    RequireGPU();

    const float tau = 10.0f;
    const float dt = 0.5f;  // Smaller dt for stability
    const float x_eq = 0.0f;  // Equilibrium for decay

    nimcp_gpu_tensor_t* x = create_filled_tensor(SMALL_N_NEURONS, 1.0f);
    nimcp_gpu_tensor_t* dx_dt = create_zero_tensor(SMALL_N_NEURONS);
    nimcp_gpu_tensor_t* x_new = create_zero_tensor(SMALL_N_NEURONS);
    ASSERT_NE(x, nullptr);
    ASSERT_NE(dx_dt, nullptr);
    ASSERT_NE(x_new, nullptr);

    // Run many steps
    for (int t = 0; t < 100; t++) {
        // Compute derivative: dx/dt = -x/tau
        std::vector<float> x_host(SMALL_N_NEURONS);
        copy_to_host(x, x_host.data());

        std::vector<float> dx_host(SMALL_N_NEURONS);
        for (size_t i = 0; i < SMALL_N_NEURONS; i++) {
            dx_host[i] = -x_host[i] / tau;
        }

        // Upload derivative
        nimcp_gpu_tensor_t* dx_temp = create_tensor_from_data(dx_host.data(), SMALL_N_NEURONS);
        nimcp_gpu_copy(ctx, dx_temp, dx_dt);
        nimcp_gpu_tensor_destroy(dx_temp);

        // Euler step
        nimcp_gpu_lnn_euler_step(ctx, x, dx_dt, dt, x_new);

        // Swap x and x_new
        nimcp_gpu_copy(ctx, x_new, x);
    }

    // Should be close to equilibrium
    std::vector<float> x_final(SMALL_N_NEURONS);
    copy_to_host(x, x_final.data());

    for (float val : x_final) {
        EXPECT_NEAR(val, x_eq, 0.01f) << "Should converge to equilibrium";
    }

    nimcp_gpu_tensor_destroy(x);
    nimcp_gpu_tensor_destroy(dx_dt);
    nimcp_gpu_tensor_destroy(x_new);
}

//=============================================================================
// RK4 ODE Solver Tests
//=============================================================================

/**
 * TEST: RK4 step accuracy
 * WHAT: RK4 should be more accurate than Euler for same dt
 * WHY:  Higher-order method provides better accuracy
 */
TEST_F(LNNKernelTest, RK4Step_MoreAccurateThanEuler) {
    RequireGPU();

    // Create a simple layer for RK4
    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    nimcp_lnn_ode_config_t config = create_default_ode_config(LNN_ODE_RK4);

    bool result = nimcp_gpu_lnn_rk4_step(ctx, layer, input, DEFAULT_DT, &config);
    EXPECT_TRUE(result) << "RK4 step should succeed";

    nimcp_gpu_tensor_destroy(input);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: RK4 with NULL layer
 * WHAT: Try RK4 with NULL layer
 * WHY:  Verify NULL-safety
 */
TEST_F(LNNKernelTest, RK4Step_NullLayer_ReturnsFalse) {
    RequireGPU();

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    nimcp_lnn_ode_config_t config = create_default_ode_config(LNN_ODE_RK4);

    bool result = nimcp_gpu_lnn_rk4_step(ctx, nullptr, input, DEFAULT_DT, &config);
    EXPECT_FALSE(result);

    nimcp_gpu_tensor_destroy(input);
}

//=============================================================================
// Heun (RK2) ODE Solver Tests
//=============================================================================

/**
 * TEST: Heun step execution
 * WHAT: Run Heun predictor-corrector step
 * WHY:  Verify 2nd-order method works
 */
TEST_F(LNNKernelTest, HeunStep_ExecutesCorrectly) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 0.5f);
    ASSERT_NE(input, nullptr);

    nimcp_lnn_ode_config_t config = create_default_ode_config(LNN_ODE_HEUN);

    bool result = nimcp_gpu_lnn_heun_step(ctx, layer, input, DEFAULT_DT, &config);
    EXPECT_TRUE(result);

    nimcp_gpu_tensor_destroy(input);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// DOPRI5 Adaptive ODE Solver Tests
//=============================================================================

/**
 * TEST: DOPRI5 step with adaptive stepping
 * WHAT: Run DOPRI5 with adaptive time step
 * WHY:  Verify automatic step size control
 */
TEST_F(LNNKernelTest, DOPRI5Step_AdaptiveStepSize) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    nimcp_lnn_ode_config_t config = create_default_ode_config(LNN_ODE_DOPRI5);
    config.adaptive_stepping = true;
    config.error_tolerance = 1e-3f;

    float dt = DEFAULT_DT;
    bool result = nimcp_gpu_lnn_dopri5_step(ctx, layer, input, &dt, &config);
    EXPECT_TRUE(result);

    // dt may have been adjusted
    EXPECT_GE(dt, config.dt_min) << "dt should be >= dt_min";
    EXPECT_LE(dt, config.dt_max) << "dt should be <= dt_max";

    nimcp_gpu_tensor_destroy(input);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: DOPRI5 with NULL dt pointer
 * WHAT: Try DOPRI5 without dt output
 * WHY:  Verify NULL-safety for dt_ptr
 */
TEST_F(LNNKernelTest, DOPRI5Step_NullDtPtr_ReturnsFalse) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    nimcp_lnn_ode_config_t config = create_default_ode_config(LNN_ODE_DOPRI5);

    bool result = nimcp_gpu_lnn_dopri5_step(ctx, layer, input, nullptr, &config);
    EXPECT_FALSE(result) << "Should reject NULL dt pointer";

    nimcp_gpu_tensor_destroy(input);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// Unified ODE Step Tests
//=============================================================================

/**
 * TEST: Unified ODE step with method selection
 * WHAT: Use unified interface to select ODE method
 * WHY:  Simplify caller code with single entry point
 */
TEST_F(LNNKernelTest, ODEStep_MethodSelection_Works) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    // Test each method
    std::vector<lnn_ode_method_t> methods = {
        LNN_ODE_EULER, LNN_ODE_HEUN, LNN_ODE_RK4
    };

    for (auto method : methods) {
        nimcp_lnn_ode_config_t config = create_default_ode_config(method);
        bool result = nimcp_gpu_lnn_ode_step(ctx, layer, input, &config);
        EXPECT_TRUE(result) << "ODE step should succeed for method " << static_cast<int>(method);
    }

    nimcp_gpu_tensor_destroy(input);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// LTC Derivative Computation Tests
//=============================================================================

/**
 * TEST: LTC derivative computation
 * WHAT: Compute dx/dt for LTC neurons
 * WHY:  Core of LNN dynamics
 */
TEST_F(LNNKernelTest, ComputeDerivative_ProducesOutput) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    nimcp_gpu_tensor_t* dx_dt = create_zero_tensor(SMALL_N_NEURONS);
    ASSERT_NE(input, nullptr);
    ASSERT_NE(dx_dt, nullptr);

    bool result = nimcp_gpu_lnn_compute_derivative(ctx, layer, input, dx_dt);
    EXPECT_TRUE(result);

    // Derivative should be non-zero with non-zero input
    std::vector<float> dx_host(SMALL_N_NEURONS);
    copy_to_host(dx_dt, dx_host.data());

    bool any_nonzero = false;
    for (float dx : dx_host) {
        if (std::abs(dx) > NUMERICAL_EPS) {
            any_nonzero = true;
            break;
        }
    }
    // Note: May be zero depending on weight initialization
    // This test just verifies the function executes

    nimcp_gpu_tensor_destroy(input);
    nimcp_gpu_tensor_destroy(dx_dt);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: LTC derivative with NULL inputs
 * WHAT: Try derivative computation with NULL
 * WHY:  Verify NULL-safety
 */
TEST_F(LNNKernelTest, ComputeDerivative_NullInputs_ReturnsFalse) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    nimcp_gpu_tensor_t* dx_dt = create_zero_tensor(SMALL_N_NEURONS);

    EXPECT_FALSE(nimcp_gpu_lnn_compute_derivative(ctx, nullptr, input, dx_dt));
    EXPECT_FALSE(nimcp_gpu_lnn_compute_derivative(ctx, layer, nullptr, dx_dt));
    EXPECT_FALSE(nimcp_gpu_lnn_compute_derivative(ctx, layer, input, nullptr));

    nimcp_gpu_tensor_destroy(input);
    nimcp_gpu_tensor_destroy(dx_dt);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// Tau (Time Constant) Update Tests
//=============================================================================

/**
 * TEST: Tau update computation
 * WHAT: Update input-dependent time constants
 * WHY:  Key feature of LTC neurons
 */
TEST_F(LNNKernelTest, UpdateTau_ModifiesTauTensor) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 2.0f);
    ASSERT_NE(input, nullptr);

    // Get tau before update
    std::vector<float> tau_before(SMALL_N_NEURONS);
    if (layer->tau) {
        copy_to_host(layer->tau, tau_before.data());
    }

    bool result = nimcp_gpu_lnn_update_tau(ctx, layer, input);
    EXPECT_TRUE(result);

    // Tau should be in valid range after update
    if (layer->tau) {
        std::vector<float> tau_after(SMALL_N_NEURONS);
        copy_to_host(layer->tau, tau_after.data());

        for (float tau : tau_after) {
            EXPECT_GT(tau, 0.0f) << "Tau should be positive";
        }
    }

    nimcp_gpu_tensor_destroy(input);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: Tau update with varying input
 * WHAT: Verify tau changes with input
 * WHY:  Input-dependence is key LTC property
 */
TEST_F(LNNKernelTest, UpdateTau_DifferentInputs_DifferentTau) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    // First input
    nimcp_gpu_tensor_t* input1 = create_filled_tensor(DEFAULT_N_INPUTS, 0.5f);
    ASSERT_NE(input1, nullptr);
    nimcp_gpu_lnn_update_tau(ctx, layer, input1);

    std::vector<float> tau1(SMALL_N_NEURONS);
    if (layer->tau) {
        copy_to_host(layer->tau, tau1.data());
    }

    // Second input (different)
    nimcp_gpu_tensor_t* input2 = create_filled_tensor(DEFAULT_N_INPUTS, 5.0f);
    ASSERT_NE(input2, nullptr);
    nimcp_gpu_lnn_update_tau(ctx, layer, input2);

    std::vector<float> tau2(SMALL_N_NEURONS);
    if (layer->tau) {
        copy_to_host(layer->tau, tau2.data());
    }

    // Tau values may differ (depends on W_tau initialization)
    // This test verifies the function runs without error

    nimcp_gpu_tensor_destroy(input1);
    nimcp_gpu_tensor_destroy(input2);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// Sparse Matrix Operations Tests
//=============================================================================

/**
 * TEST: Sparse matrix-vector product (CSR format)
 * WHAT: Compute y = A * x with sparse A
 * WHY:  Efficient for sparse NCP wiring
 */
TEST_F(LNNKernelTest, SparseMatVec_CorrectResult) {
    RequireGPU();

    // Small test case: 3x4 sparse matrix
    // A = [1 0 2 0]
    //     [0 3 0 0]
    //     [4 0 0 5]
    // CSR format:
    // values = [1, 2, 3, 4, 5]
    // col_idx = [0, 2, 1, 0, 3]
    // row_ptr = [0, 2, 3, 5]

    std::vector<uint32_t> row_ptr_data = {0, 2, 3, 5};
    std::vector<uint32_t> col_idx_data = {0, 2, 1, 0, 3};
    std::vector<float> values_data = {1.0f, 2.0f, 3.0f, 4.0f, 5.0f};

    // Create CSR tensors
    size_t row_dims[1] = {4};
    size_t col_dims[1] = {5};

    nimcp_gpu_tensor_t* row_ptr = nimcp_gpu_tensor_from_host(
        ctx, row_ptr_data.data(), row_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* col_idx = nimcp_gpu_tensor_from_host(
        ctx, col_idx_data.data(), col_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* values = create_tensor_from_data(values_data.data(), 5);

    if (!row_ptr || !col_idx || !values) {
        if (row_ptr) nimcp_gpu_tensor_destroy(row_ptr);
        if (col_idx) nimcp_gpu_tensor_destroy(col_idx);
        if (values) nimcp_gpu_tensor_destroy(values);
        GTEST_SKIP() << "Sparse tensor creation not supported";
    }

    // Input vector x = [1, 1, 1, 1]
    std::vector<float> x_data = {1.0f, 1.0f, 1.0f, 1.0f};
    nimcp_gpu_tensor_t* x = create_tensor_from_data(x_data.data(), 4);
    ASSERT_NE(x, nullptr);

    // Output vector y
    nimcp_gpu_tensor_t* y = create_zero_tensor(3);
    ASSERT_NE(y, nullptr);

    bool result = nimcp_gpu_sparse_matvec(ctx, row_ptr, col_idx, values, x, y, 3, 1.0f);
    EXPECT_TRUE(result);

    // Expected: y = [1+2, 3, 4+5] = [3, 3, 9]
    std::vector<float> y_host(3);
    copy_to_host(y, y_host.data());

    EXPECT_NEAR(y_host[0], 3.0f, NUMERICAL_EPS);
    EXPECT_NEAR(y_host[1], 3.0f, NUMERICAL_EPS);
    EXPECT_NEAR(y_host[2], 9.0f, NUMERICAL_EPS);

    nimcp_gpu_tensor_destroy(row_ptr);
    nimcp_gpu_tensor_destroy(col_idx);
    nimcp_gpu_tensor_destroy(values);
    nimcp_gpu_tensor_destroy(x);
    nimcp_gpu_tensor_destroy(y);
}

/**
 * TEST: Sparse matvec with alpha scaling
 * WHAT: y = alpha * A * x
 * WHY:  Support scaled operations
 */
TEST_F(LNNKernelTest, SparseMatVec_WithAlpha_Scales) {
    RequireGPU();

    // Identity-like sparse matrix (diagonal)
    std::vector<uint32_t> row_ptr_data = {0, 1, 2, 3};
    std::vector<uint32_t> col_idx_data = {0, 1, 2};
    std::vector<float> values_data = {1.0f, 1.0f, 1.0f};

    size_t row_dims[1] = {4};
    size_t col_dims[1] = {3};

    nimcp_gpu_tensor_t* row_ptr = nimcp_gpu_tensor_from_host(
        ctx, row_ptr_data.data(), row_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* col_idx = nimcp_gpu_tensor_from_host(
        ctx, col_idx_data.data(), col_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* values = create_tensor_from_data(values_data.data(), 3);

    if (!row_ptr || !col_idx || !values) {
        if (row_ptr) nimcp_gpu_tensor_destroy(row_ptr);
        if (col_idx) nimcp_gpu_tensor_destroy(col_idx);
        if (values) nimcp_gpu_tensor_destroy(values);
        GTEST_SKIP() << "Sparse tensor creation not supported";
    }

    std::vector<float> x_data = {2.0f, 3.0f, 4.0f};
    nimcp_gpu_tensor_t* x = create_tensor_from_data(x_data.data(), 3);
    nimcp_gpu_tensor_t* y = create_zero_tensor(3);

    float alpha = 0.5f;
    bool result = nimcp_gpu_sparse_matvec(ctx, row_ptr, col_idx, values, x, y, 3, alpha);
    EXPECT_TRUE(result);

    // Expected: y = 0.5 * [2, 3, 4] = [1, 1.5, 2]
    std::vector<float> y_host(3);
    copy_to_host(y, y_host.data());

    EXPECT_NEAR(y_host[0], 1.0f, NUMERICAL_EPS);
    EXPECT_NEAR(y_host[1], 1.5f, NUMERICAL_EPS);
    EXPECT_NEAR(y_host[2], 2.0f, NUMERICAL_EPS);

    nimcp_gpu_tensor_destroy(row_ptr);
    nimcp_gpu_tensor_destroy(col_idx);
    nimcp_gpu_tensor_destroy(values);
    nimcp_gpu_tensor_destroy(x);
    nimcp_gpu_tensor_destroy(y);
}

/**
 * TEST: Sparse matrix addition
 * WHAT: C = alpha * A + beta * B (CSR format)
 * WHY:  Support sparse matrix arithmetic
 */
TEST_F(LNNKernelTest, SparseAdd_ProducesSum) {
    RequireGPU();

    // Simple diagonal matrices for easy verification
    // A = diag([1, 2, 3]), B = diag([4, 5, 6])
    std::vector<uint32_t> row_ptr_data = {0, 1, 2, 3};
    std::vector<uint32_t> col_idx_data = {0, 1, 2};
    std::vector<float> A_values = {1.0f, 2.0f, 3.0f};
    std::vector<float> B_values = {4.0f, 5.0f, 6.0f};

    size_t row_dims[1] = {4};
    size_t col_dims[1] = {3};

    nimcp_gpu_tensor_t* A_row_ptr = nimcp_gpu_tensor_from_host(
        ctx, row_ptr_data.data(), row_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* A_col_idx = nimcp_gpu_tensor_from_host(
        ctx, col_idx_data.data(), col_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* A_vals = create_tensor_from_data(A_values.data(), 3);

    nimcp_gpu_tensor_t* B_row_ptr = nimcp_gpu_tensor_from_host(
        ctx, row_ptr_data.data(), row_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* B_col_idx = nimcp_gpu_tensor_from_host(
        ctx, col_idx_data.data(), col_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* B_vals = create_tensor_from_data(B_values.data(), 3);

    if (!A_row_ptr || !A_col_idx || !A_vals ||
        !B_row_ptr || !B_col_idx || !B_vals) {
        GTEST_SKIP() << "Sparse tensor creation not supported";
    }

    // Output tensors
    nimcp_gpu_tensor_t* C_row_ptr = nimcp_gpu_tensor_from_host(
        ctx, row_ptr_data.data(), row_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* C_col_idx = nimcp_gpu_tensor_from_host(
        ctx, col_idx_data.data(), col_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* C_vals = create_zero_tensor(3);

    bool result = nimcp_gpu_sparse_add(ctx,
        A_row_ptr, A_col_idx, A_vals,
        B_row_ptr, B_col_idx, B_vals,
        C_row_ptr, C_col_idx, C_vals,
        3, 1.0f, 1.0f);

    // Note: This may not be implemented
    if (!result) {
        // Clean up and skip if not implemented
        nimcp_gpu_tensor_destroy(A_row_ptr);
        nimcp_gpu_tensor_destroy(A_col_idx);
        nimcp_gpu_tensor_destroy(A_vals);
        nimcp_gpu_tensor_destroy(B_row_ptr);
        nimcp_gpu_tensor_destroy(B_col_idx);
        nimcp_gpu_tensor_destroy(B_vals);
        nimcp_gpu_tensor_destroy(C_row_ptr);
        nimcp_gpu_tensor_destroy(C_col_idx);
        nimcp_gpu_tensor_destroy(C_vals);
        GTEST_SKIP() << "Sparse add not implemented";
    }

    // Expected: C = [5, 7, 9]
    std::vector<float> C_host(3);
    copy_to_host(C_vals, C_host.data());

    EXPECT_NEAR(C_host[0], 5.0f, NUMERICAL_EPS);
    EXPECT_NEAR(C_host[1], 7.0f, NUMERICAL_EPS);
    EXPECT_NEAR(C_host[2], 9.0f, NUMERICAL_EPS);

    nimcp_gpu_tensor_destroy(A_row_ptr);
    nimcp_gpu_tensor_destroy(A_col_idx);
    nimcp_gpu_tensor_destroy(A_vals);
    nimcp_gpu_tensor_destroy(B_row_ptr);
    nimcp_gpu_tensor_destroy(B_col_idx);
    nimcp_gpu_tensor_destroy(B_vals);
    nimcp_gpu_tensor_destroy(C_row_ptr);
    nimcp_gpu_tensor_destroy(C_col_idx);
    nimcp_gpu_tensor_destroy(C_vals);
}

//=============================================================================
// Adjoint Method Gradient Tests
//=============================================================================

/**
 * TEST: Adjoint state initialization
 * WHAT: Initialize adjoint for backward pass
 * WHY:  First step in adjoint gradient computation
 */
TEST_F(LNNKernelTest, AdjointInit_CopiesGradOutput) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    // Gradient from next layer
    std::vector<float> grad_data(SMALL_N_NEURONS);
    for (size_t i = 0; i < SMALL_N_NEURONS; i++) {
        grad_data[i] = static_cast<float>(i + 1);
    }
    nimcp_gpu_tensor_t* grad_output = create_tensor_from_data(grad_data.data(), SMALL_N_NEURONS);
    nimcp_gpu_tensor_t* adjoint = create_zero_tensor(SMALL_N_NEURONS);
    ASSERT_NE(grad_output, nullptr);
    ASSERT_NE(adjoint, nullptr);

    bool result = nimcp_gpu_lnn_adjoint_init(ctx, layer, grad_output, adjoint);
    EXPECT_TRUE(result);

    // Adjoint should be initialized from grad_output
    std::vector<float> adjoint_host(SMALL_N_NEURONS);
    copy_to_host(adjoint, adjoint_host.data());

    for (size_t i = 0; i < SMALL_N_NEURONS; i++) {
        EXPECT_NEAR(adjoint_host[i], grad_data[i], NUMERICAL_EPS);
    }

    nimcp_gpu_tensor_destroy(grad_output);
    nimcp_gpu_tensor_destroy(adjoint);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: Adjoint step execution
 * WHAT: Run one adjoint ODE step
 * WHY:  Core of adjoint gradient method
 */
TEST_F(LNNKernelTest, AdjointStep_ExecutesCorrectly) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* adjoint = create_filled_tensor(SMALL_N_NEURONS, 1.0f);
    nimcp_gpu_tensor_t* x_at_t = create_filled_tensor(SMALL_N_NEURONS, 0.5f);
    nimcp_gpu_tensor_t* input_at_t = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(adjoint, nullptr);
    ASSERT_NE(x_at_t, nullptr);
    ASSERT_NE(input_at_t, nullptr);

    bool result = nimcp_gpu_lnn_adjoint_step(ctx, layer, adjoint, x_at_t, input_at_t, DEFAULT_DT);
    EXPECT_TRUE(result);

    nimcp_gpu_tensor_destroy(adjoint);
    nimcp_gpu_tensor_destroy(x_at_t);
    nimcp_gpu_tensor_destroy(input_at_t);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: Gradient accumulation
 * WHAT: Accumulate parameter gradients from adjoint
 * WHY:  Build up gradients over time integration
 */
TEST_F(LNNKernelTest, AccumulateGradients_UpdatesGradients) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* adjoint = create_filled_tensor(SMALL_N_NEURONS, 1.0f);
    nimcp_gpu_tensor_t* x_at_t = create_filled_tensor(SMALL_N_NEURONS, 0.5f);
    nimcp_gpu_tensor_t* input_at_t = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(adjoint, nullptr);
    ASSERT_NE(x_at_t, nullptr);
    ASSERT_NE(input_at_t, nullptr);

    bool result = nimcp_gpu_lnn_accumulate_gradients(ctx, layer, adjoint, x_at_t, input_at_t, DEFAULT_DT);
    EXPECT_TRUE(result);

    nimcp_gpu_tensor_destroy(adjoint);
    nimcp_gpu_tensor_destroy(x_at_t);
    nimcp_gpu_tensor_destroy(input_at_t);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// Layer Lifecycle Tests
//=============================================================================

/**
 * TEST: GPU layer creation from CPU layer
 * WHAT: Create GPU-resident layer from CPU layer
 * WHY:  Entry point for GPU acceleration
 */
TEST_F(LNNKernelTest, LayerCreate_FromCPU_Succeeds) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* gpu_layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);

    if (gpu_layer) {
        EXPECT_EQ(gpu_layer->n_neurons, SMALL_N_NEURONS);
        EXPECT_EQ(gpu_layer->n_inputs, DEFAULT_N_INPUTS);
        EXPECT_NE(gpu_layer->x, nullptr) << "State tensor should be allocated";

        nimcp_lnn_layer_gpu_destroy(gpu_layer);
    }
    // May return NULL if not implemented - that's acceptable

    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: GPU layer creation with NULL CPU layer
 * WHAT: Try to create GPU layer from NULL
 * WHY:  Verify NULL-safety
 */
TEST_F(LNNKernelTest, LayerCreate_NullCPU_ReturnsNull) {
    RequireGPU();

    nimcp_lnn_layer_gpu_t* gpu_layer = nimcp_lnn_layer_gpu_create(ctx, nullptr);
    EXPECT_EQ(gpu_layer, nullptr);
}

/**
 * TEST: GPU layer destruction with NULL
 * WHAT: Destroy NULL GPU layer
 * WHY:  Verify NULL-safety
 */
TEST_F(LNNKernelTest, LayerDestroy_Null_NoOp) {
    nimcp_lnn_layer_gpu_destroy(nullptr);
    SUCCEED() << "Should not crash";
}

/**
 * TEST: GPU to CPU layer copy
 * WHAT: Copy GPU layer state back to CPU
 * WHY:  Enable CPU-side analysis of GPU results
 */
TEST_F(LNNKernelTest, LayerGPUtoCPU_CopiesState) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* gpu_layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!gpu_layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    // Modify GPU state
    if (gpu_layer->x) {
        nimcp_gpu_fill(ctx, gpu_layer->x, 0.42f);
    }

    // Copy back to CPU
    bool result = nimcp_lnn_layer_gpu_to_cpu(gpu_layer, cpu_layer);
    EXPECT_TRUE(result);

    // Verify CPU state was updated
    if (cpu_layer->x) {
        std::vector<float> x_host(SMALL_N_NEURONS);
        // Would need to copy from CPU tensor - skipping detailed verification
    }

    nimcp_lnn_layer_gpu_destroy(gpu_layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: Zero gradients
 * WHAT: Reset all gradients to zero
 * WHY:  Required before each backward pass
 */
TEST_F(LNNKernelTest, LayerZeroGrad_ResetsGradients) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* gpu_layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!gpu_layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    bool result = nimcp_lnn_layer_gpu_zero_grad(ctx, gpu_layer);
    EXPECT_TRUE(result);

    nimcp_lnn_layer_gpu_destroy(gpu_layer);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// Integration Tests
//=============================================================================

/**
 * TEST: Full forward pass integration
 * WHAT: Complete forward pass through GPU LNN layer
 * WHY:  Verify all components work together
 */
TEST_F(LNNKernelTest, Integration_FullForwardPass) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    nimcp_lnn_ode_config_t config = create_default_ode_config(LNN_ODE_RK4);

    // Run multiple timesteps
    for (int t = 0; t < 50; t++) {
        // Update tau based on input
        bool tau_result = nimcp_gpu_lnn_update_tau(ctx, layer, input);
        ASSERT_TRUE(tau_result) << "Tau update at t=" << t << " should succeed";

        // ODE step
        bool ode_result = nimcp_gpu_lnn_ode_step(ctx, layer, input, &config);
        ASSERT_TRUE(ode_result) << "ODE step at t=" << t << " should succeed";
    }

    // Verify state is finite
    if (layer->x) {
        std::vector<float> x_host(SMALL_N_NEURONS);
        copy_to_host(layer->x, x_host.data());

        for (float x : x_host) {
            EXPECT_TRUE(std::isfinite(x)) << "State should be finite after simulation";
        }
    }

    nimcp_gpu_tensor_destroy(input);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: Forward-backward integration
 * WHAT: Complete forward and backward pass
 * WHY:  Verify end-to-end training capability
 */
TEST_F(LNNKernelTest, Integration_ForwardBackward) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    nimcp_lnn_ode_config_t config = create_default_ode_config(LNN_ODE_RK4);

    // Forward pass
    const int n_steps = 10;
    std::vector<nimcp_gpu_tensor_t*> state_history;

    for (int t = 0; t < n_steps; t++) {
        // Save state for backward pass
        if (layer->x) {
            nimcp_gpu_tensor_t* x_copy = nimcp_gpu_tensor_clone(layer->x);
            if (x_copy) state_history.push_back(x_copy);
        }

        nimcp_gpu_lnn_update_tau(ctx, layer, input);
        nimcp_gpu_lnn_ode_step(ctx, layer, input, &config);
    }

    // Backward pass (adjoint method)
    nimcp_gpu_tensor_t* grad_output = create_filled_tensor(SMALL_N_NEURONS, 1.0f);
    nimcp_gpu_tensor_t* adjoint = create_zero_tensor(SMALL_N_NEURONS);
    ASSERT_NE(grad_output, nullptr);
    ASSERT_NE(adjoint, nullptr);

    nimcp_gpu_lnn_adjoint_init(ctx, layer, grad_output, adjoint);

    for (int t = n_steps - 1; t >= 0; t--) {
        if (t < static_cast<int>(state_history.size())) {
            nimcp_gpu_lnn_adjoint_step(ctx, layer, adjoint, state_history[t], input, DEFAULT_DT);
            nimcp_gpu_lnn_accumulate_gradients(ctx, layer, adjoint, state_history[t], input, DEFAULT_DT);
        }
    }

    // Clean up
    for (auto& tensor : state_history) {
        nimcp_gpu_tensor_destroy(tensor);
    }
    nimcp_gpu_tensor_destroy(input);
    nimcp_gpu_tensor_destroy(grad_output);
    nimcp_gpu_tensor_destroy(adjoint);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// Large Scale Tests
//=============================================================================

/**
 * TEST: Large network simulation
 * WHAT: Run LNN on large network
 * WHY:  Verify scalability
 */
TEST_F(LNNKernelTest, LargeScale_LNNSimulation) {
    RequireGPU();

    // Create larger layer using helper (with proper tensor initialization)
    lnn_layer_t* cpu_layer = create_mock_cpu_layer(LARGE_N_NEURONS, DEFAULT_N_INPUTS);
    ASSERT_NE(cpu_layer, nullptr);

    nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
    if (!layer) {
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "GPU layer creation not supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    nimcp_lnn_ode_config_t config = create_default_ode_config(LNN_ODE_RK4);

    // Time the simulation
    auto start = std::chrono::high_resolution_clock::now();

    for (int t = 0; t < 100; t++) {
        nimcp_gpu_lnn_update_tau(ctx, layer, input);
        bool result = nimcp_gpu_lnn_ode_step(ctx, layer, input, &config);
        ASSERT_TRUE(result);
    }

    // Synchronize to ensure all work is done
    nimcp_gpu_context_synchronize(ctx);

    auto end = std::chrono::high_resolution_clock::now();
    auto duration = std::chrono::duration_cast<std::chrono::milliseconds>(end - start);

    // Should complete in reasonable time
    EXPECT_LT(duration.count(), 10000) << "100 timesteps should complete within 10 seconds";

    nimcp_gpu_tensor_destroy(input);
    nimcp_lnn_layer_gpu_destroy(layer);
    free_mock_cpu_layer(cpu_layer);
}

/**
 * TEST: ODE solver comparison
 * WHAT: Compare accuracy of different ODE methods
 * WHY:  Verify higher-order methods are more accurate
 */
TEST_F(LNNKernelTest, ODEComparison_HigherOrderMoreAccurate) {
    RequireGPU();

    lnn_layer_t* cpu_layer = create_mock_cpu_layer();
    ASSERT_NE(cpu_layer, nullptr);

    // Create three layers with different methods
    std::vector<lnn_ode_method_t> methods = {LNN_ODE_EULER, LNN_ODE_HEUN, LNN_ODE_RK4};
    std::vector<nimcp_lnn_layer_gpu_t*> layers;

    for (auto method : methods) {
        nimcp_lnn_layer_gpu_t* layer = nimcp_lnn_layer_gpu_create(ctx, cpu_layer);
        if (layer) {
            layers.push_back(layer);
        }
    }

    if (layers.size() < methods.size()) {
        for (auto layer : layers) {
            nimcp_lnn_layer_gpu_destroy(layer);
        }
        free_mock_cpu_layer(cpu_layer);
        GTEST_SKIP() << "Not all methods supported";
    }

    nimcp_gpu_tensor_t* input = create_filled_tensor(DEFAULT_N_INPUTS, 1.0f);
    ASSERT_NE(input, nullptr);

    // Run all methods for same number of steps
    for (size_t i = 0; i < methods.size(); i++) {
        nimcp_lnn_ode_config_t config = create_default_ode_config(methods[i]);

        for (int t = 0; t < 20; t++) {
            nimcp_gpu_lnn_update_tau(ctx, layers[i], input);
            nimcp_gpu_lnn_ode_step(ctx, layers[i], input, &config);
        }
    }

    // All should produce finite results
    for (size_t i = 0; i < layers.size(); i++) {
        if (layers[i]->x) {
            std::vector<float> x_host(SMALL_N_NEURONS);
            copy_to_host(layers[i]->x, x_host.data());

            for (float x : x_host) {
                EXPECT_TRUE(std::isfinite(x))
                    << "Method " << static_cast<int>(methods[i]) << " produced non-finite result";
            }
        }
    }

    // Clean up
    for (auto layer : layers) {
        nimcp_lnn_layer_gpu_destroy(layer);
    }
    nimcp_gpu_tensor_destroy(input);
    free_mock_cpu_layer(cpu_layer);
}

//=============================================================================
// Main
//=============================================================================

int main(int argc, char** argv) {
    ::testing::InitGoogleTest(&argc, argv);
    return RUN_ALL_TESTS();
}
