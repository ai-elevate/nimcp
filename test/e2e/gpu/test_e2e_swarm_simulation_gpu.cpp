/**
 * @file test_e2e_swarm_simulation_gpu.cpp
 * @brief E2E Tests for GPU-Accelerated Swarm Simulation
 *
 * WHAT: End-to-end testing of multi-agent swarm simulations on GPU
 * WHY:  Verify complete swarm intelligence pipelines with GPU acceleration
 * HOW:  Test flocking, consensus, pheromone, quorum sensing, and task allocation
 *
 * TEST PIPELINES:
 * - FlockingBoids: Reynolds flocking with separation, alignment, cohesion
 * - SwarmConsensus: Distributed consensus reaching among agents
 * - PheromoneSimulation: Ant colony pheromone deposit and diffusion
 * - QuorumSensing: Bacterial-inspired quorum detection
 * - TaskAllocation: Multi-agent task assignment via auctions
 * - CollisionAvoidance: Large-scale collision detection
 * - ScalabilityBenchmark: Test with increasing agent counts
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
#include "gpu/swarm/nimcp_swarm_gpu.h"
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

struct SwarmMetrics {
    double gpu_time_ms;
    double cpu_time_ms;
    double speedup;
    size_t memory_usage_bytes;
    double numerical_accuracy;
    double agents_per_second;
    uint64_t total_agents;
    uint64_t timesteps_simulated;
    double collision_rate;
};

//=============================================================================
// Test Fixture
//=============================================================================

class SwarmSimulationGPUE2ETest : public ::testing::Test {
protected:
    nimcp_gpu_context_t* gpu_ctx_ = nullptr;
    hardware_capabilities_t caps_;
    bool has_gpu_ = false;
    std::mt19937 rng_;
    SwarmMetrics metrics_;

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

    void InitializeRandomPositions(std::vector<float>& positions, size_t n_agents,
                                   float min_val, float max_val) {
        positions.resize(n_agents * 4);  // x, y, z, w (w for mass/padding)
        std::uniform_real_distribution<float> dist(min_val, max_val);
        for (size_t i = 0; i < n_agents; i++) {
            positions[i * 4 + 0] = dist(rng_);  // x
            positions[i * 4 + 1] = dist(rng_);  // y
            positions[i * 4 + 2] = dist(rng_);  // z
            positions[i * 4 + 3] = 1.0f;        // w (mass)
        }
    }

    void InitializeRandomVelocities(std::vector<float>& velocities, size_t n_agents,
                                    float max_speed) {
        velocities.resize(n_agents * 4);
        std::uniform_real_distribution<float> dist(-max_speed, max_speed);
        for (size_t i = 0; i < n_agents; i++) {
            velocities[i * 4 + 0] = dist(rng_);
            velocities[i * 4 + 1] = dist(rng_);
            velocities[i * 4 + 2] = dist(rng_);
            velocities[i * 4 + 3] = 0.0f;
        }
    }

    void PrintMetrics(const std::string& test_name) {
        std::cout << "\n=== " << test_name << " Metrics ===" << std::endl;
        std::cout << "  GPU Time: " << metrics_.gpu_time_ms << " ms" << std::endl;
        std::cout << "  CPU Time: " << metrics_.cpu_time_ms << " ms" << std::endl;
        std::cout << "  Speedup: " << metrics_.speedup << "x" << std::endl;
        std::cout << "  Memory Usage: " << (metrics_.memory_usage_bytes / 1024.0 / 1024.0)
                  << " MB" << std::endl;
        std::cout << "  Agents/sec: " << metrics_.agents_per_second << std::endl;
        std::cout << "  Total agents: " << metrics_.total_agents << std::endl;
        std::cout << "  Timesteps: " << metrics_.timesteps_simulated << std::endl;
    }
};

//=============================================================================
// Pipeline 1: Flocking/Boids Simulation
//=============================================================================

TEST_F(SwarmSimulationGPUE2ETest, FlockingBoidsGPU) {
    E2E_PIPELINE_START("Flocking Boids Simulation on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const size_t N_AGENTS = 10000;
    const size_t MAX_NEIGHBORS = 32;
    const size_t N_TIMESTEPS = 100;
    const float DT = 0.016f;  // ~60 FPS

    // Stage 1: Create flocking state
    E2E_STAGE_BEGIN("Create flocking state", 2000);

    nimcp_flocking_gpu_params_t params;
    nimcp_flocking_gpu_default_params(&params);
    params.separation_weight = 1.5f;
    params.alignment_weight = 1.0f;
    params.cohesion_weight = 1.0f;
    params.separation_radius = 2.0f;
    params.alignment_radius = 5.0f;
    params.cohesion_radius = 5.0f;
    params.max_speed = 10.0f;
    params.max_force = 2.0f;
    params.dt = DT;

    nimcp_flocking_gpu_state_t* flock = nimcp_flocking_gpu_create(
        gpu_ctx_, N_AGENTS, MAX_NEIGHBORS, &params);
    E2E_ASSERT_NOT_NULL(flock, "Failed to create flocking state");

    std::cout << "\n  Flocking Configuration:" << std::endl;
    std::cout << "    Agents: " << N_AGENTS << std::endl;
    std::cout << "    Max neighbors: " << MAX_NEIGHBORS << std::endl;
    std::cout << "    Separation radius: " << params.separation_radius << std::endl;

    E2E_STAGE_END();

    // Stage 2: Initialize positions and velocities
    E2E_STAGE_BEGIN("Initialize agent states", 1000);

    std::vector<float> positions;
    std::vector<float> velocities;
    InitializeRandomPositions(positions, N_AGENTS, -50.0f, 50.0f);
    InitializeRandomVelocities(velocities, N_AGENTS, params.max_speed * 0.5f);

    nimcp_gpu_memcpy(gpu_ctx_, flock->positions->data, positions.data(),
                     positions.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);
    nimcp_gpu_memcpy(gpu_ctx_, flock->velocities->data, velocities.data(),
                     velocities.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);
    nimcp_gpu_zeros(gpu_ctx_, flock->accelerations);
    nimcp_gpu_zeros(gpu_ctx_, flock->forces);

    E2E_STAGE_END();

    // Stage 3: Build spatial hash for neighbor search
    E2E_STAGE_BEGIN("Build spatial hash", 1000);

    nimcp_spatial_hash_t* hash = nimcp_spatial_hash_create(
        gpu_ctx_, params.cohesion_radius, 64, 64, 64, N_AGENTS);
    E2E_ASSERT_NOT_NULL(hash, "Failed to create spatial hash");

    bool success = nimcp_gpu_spatial_hash_build(gpu_ctx_, hash, flock->positions, N_AGENTS);
    E2E_ASSERT(success, "Failed to build spatial hash");

    E2E_STAGE_END();

    // Stage 4: Run simulation
    E2E_STAGE_BEGIN("Run flocking simulation", 30000);

    auto sim_start = std::chrono::high_resolution_clock::now();

    for (size_t t = 0; t < N_TIMESTEPS; t++) {
        // Find neighbors using spatial hash
        success = nimcp_gpu_flocking_find_neighbors(gpu_ctx_, flock, params.cohesion_radius);
        E2E_ASSERT(success, "Neighbor finding failed");

        // Compute flocking forces (separation + alignment + cohesion)
        success = nimcp_gpu_flocking_compute_forces(gpu_ctx_, flock);
        E2E_ASSERT(success, "Force computation failed");

        // Update positions and velocities
        success = nimcp_gpu_flocking_update(gpu_ctx_, flock, DT);
        E2E_ASSERT(success, "Flocking update failed");

        // Rebuild spatial hash
        if (t % 5 == 0) {  // Rebuild every 5 steps
            success = nimcp_gpu_spatial_hash_build(gpu_ctx_, hash, flock->positions, N_AGENTS);
            E2E_ASSERT(success, "Spatial hash rebuild failed");
        }
    }

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto sim_end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(sim_end - sim_start).count();

    metrics_.timesteps_simulated = N_TIMESTEPS;
    metrics_.total_agents = N_AGENTS;
    metrics_.agents_per_second = (N_AGENTS * N_TIMESTEPS) / (metrics_.gpu_time_ms / 1000.0);

    std::cout << "\n  Simulation completed:" << std::endl;
    std::cout << "    Total time: " << metrics_.gpu_time_ms << " ms" << std::endl;
    std::cout << "    Time per step: " << (metrics_.gpu_time_ms / N_TIMESTEPS) << " ms" << std::endl;
    std::cout << "    Agent updates/sec: " << metrics_.agents_per_second << std::endl;

    E2E_STAGE_END();

    // Stage 5: Verify swarm behavior
    E2E_STAGE_BEGIN("Verify swarm behavior", 1000);

    std::vector<float> final_positions(N_AGENTS * 4);
    std::vector<float> final_velocities(N_AGENTS * 4);

    nimcp_gpu_memcpy(gpu_ctx_, final_positions.data(), flock->positions->data,
                     final_positions.size() * sizeof(float), GPU_MEMCPY_DEVICE_TO_HOST);
    nimcp_gpu_memcpy(gpu_ctx_, final_velocities.data(), flock->velocities->data,
                     final_velocities.size() * sizeof(float), GPU_MEMCPY_DEVICE_TO_HOST);

    // Compute velocity alignment (a measure of swarm coherence)
    float avg_vx = 0, avg_vy = 0, avg_vz = 0;
    for (size_t i = 0; i < N_AGENTS; i++) {
        avg_vx += final_velocities[i * 4 + 0];
        avg_vy += final_velocities[i * 4 + 1];
        avg_vz += final_velocities[i * 4 + 2];
    }
    avg_vx /= N_AGENTS;
    avg_vy /= N_AGENTS;
    avg_vz /= N_AGENTS;

    float avg_speed = std::sqrt(avg_vx * avg_vx + avg_vy * avg_vy + avg_vz * avg_vz);
    std::cout << "\n  Swarm coherence:" << std::endl;
    std::cout << "    Average velocity direction magnitude: " << avg_speed << std::endl;

    // Swarm should show some alignment after simulation
    EXPECT_GT(avg_speed, 0.1f) << "Swarm should show velocity alignment";

    E2E_STAGE_END();

    // Cleanup
    nimcp_spatial_hash_destroy(hash);
    nimcp_flocking_gpu_destroy(flock);

    PrintMetrics("Flocking Boids GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 2: Swarm Consensus
//=============================================================================

TEST_F(SwarmSimulationGPUE2ETest, SwarmConsensusGPU) {
    E2E_PIPELINE_START("Swarm Consensus on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const size_t N_AGENTS = 5000;
    const size_t BELIEF_DIM = 16;
    const size_t MAX_ITERATIONS = 200;

    // Stage 1: Create consensus state
    E2E_STAGE_BEGIN("Create consensus state", 1000);

    nimcp_consensus_gpu_params_t params;
    nimcp_consensus_gpu_default_params(&params);
    params.learning_rate = 0.1f;
    params.min_confidence = 0.1f;
    params.max_iterations = MAX_ITERATIONS;

    nimcp_consensus_gpu_state_t* consensus = nimcp_consensus_gpu_create(
        gpu_ctx_, N_AGENTS, BELIEF_DIM, &params);
    E2E_ASSERT_NOT_NULL(consensus, "Failed to create consensus state");

    std::cout << "\n  Consensus Configuration:" << std::endl;
    std::cout << "    Agents: " << N_AGENTS << std::endl;
    std::cout << "    Belief dimension: " << BELIEF_DIM << std::endl;
    std::cout << "    Learning rate: " << params.learning_rate << std::endl;

    E2E_STAGE_END();

    // Stage 2: Initialize beliefs (different initial opinions)
    E2E_STAGE_BEGIN("Initialize agent beliefs", 1000);

    std::vector<float> beliefs(N_AGENTS * BELIEF_DIM);
    std::vector<float> confidences(N_AGENTS);
    std::uniform_real_distribution<float> belief_dist(-1.0f, 1.0f);
    std::uniform_real_distribution<float> conf_dist(0.5f, 1.0f);

    for (size_t i = 0; i < N_AGENTS; i++) {
        for (size_t d = 0; d < BELIEF_DIM; d++) {
            beliefs[i * BELIEF_DIM + d] = belief_dist(rng_);
        }
        confidences[i] = conf_dist(rng_);
    }

    nimcp_gpu_memcpy(gpu_ctx_, consensus->beliefs->data, beliefs.data(),
                     beliefs.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);
    nimcp_gpu_memcpy(gpu_ctx_, consensus->confidences->data, confidences.data(),
                     confidences.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    // Initialize random weights (adjacency matrix - sparse connectivity)
    std::vector<float> weights(N_AGENTS * N_AGENTS, 0.0f);
    std::uniform_real_distribution<float> weight_dist(0.0f, 1.0f);
    std::bernoulli_distribution conn_dist(0.01);  // 1% connectivity

    for (size_t i = 0; i < N_AGENTS; i++) {
        float row_sum = 0.0f;
        for (size_t j = 0; j < N_AGENTS; j++) {
            if (i != j && conn_dist(rng_)) {
                weights[i * N_AGENTS + j] = weight_dist(rng_);
                row_sum += weights[i * N_AGENTS + j];
            }
        }
        // Normalize row
        if (row_sum > 0) {
            for (size_t j = 0; j < N_AGENTS; j++) {
                weights[i * N_AGENTS + j] /= row_sum;
            }
        }
    }

    nimcp_gpu_memcpy(gpu_ctx_, consensus->weights->data, weights.data(),
                     weights.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    // Compute initial belief variance
    float initial_variance = 0.0f;
    for (size_t d = 0; d < BELIEF_DIM; d++) {
        float mean = 0.0f;
        for (size_t i = 0; i < N_AGENTS; i++) {
            mean += beliefs[i * BELIEF_DIM + d];
        }
        mean /= N_AGENTS;
        for (size_t i = 0; i < N_AGENTS; i++) {
            float diff = beliefs[i * BELIEF_DIM + d] - mean;
            initial_variance += diff * diff;
        }
    }
    initial_variance /= (N_AGENTS * BELIEF_DIM);

    std::cout << "\n  Initial belief variance: " << initial_variance << std::endl;

    E2E_STAGE_END();

    // Stage 3: Run consensus algorithm
    E2E_STAGE_BEGIN("Run consensus iterations", 10000);

    auto consensus_start = std::chrono::high_resolution_clock::now();

    bool converged = false;
    float variance = 0.0f;
    size_t iterations = 0;

    for (iterations = 0; iterations < MAX_ITERATIONS && !converged; iterations++) {
        bool success = nimcp_gpu_consensus_averaging(gpu_ctx_, consensus);
        E2E_ASSERT(success, "Consensus averaging failed");

        // Check convergence every 10 iterations
        if (iterations % 10 == 0) {
            success = nimcp_gpu_consensus_check_convergence(gpu_ctx_, consensus, &converged, &variance);
            E2E_ASSERT(success, "Convergence check failed");
        }
    }

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto consensus_end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(
        consensus_end - consensus_start).count();

    std::cout << "\n  Consensus result:" << std::endl;
    std::cout << "    Iterations: " << iterations << std::endl;
    std::cout << "    Final variance: " << variance << std::endl;
    std::cout << "    Converged: " << (converged ? "yes" : "no") << std::endl;
    std::cout << "    Time: " << metrics_.gpu_time_ms << " ms" << std::endl;

    E2E_STAGE_END();

    // Stage 4: Verify consensus achieved
    E2E_STAGE_BEGIN("Verify consensus quality", 1000);

    std::vector<float> final_beliefs(N_AGENTS * BELIEF_DIM);
    nimcp_gpu_memcpy(gpu_ctx_, final_beliefs.data(), consensus->beliefs->data,
                     final_beliefs.size() * sizeof(float), GPU_MEMCPY_DEVICE_TO_HOST);

    float final_variance = 0.0f;
    for (size_t d = 0; d < BELIEF_DIM; d++) {
        float mean = 0.0f;
        for (size_t i = 0; i < N_AGENTS; i++) {
            mean += final_beliefs[i * BELIEF_DIM + d];
        }
        mean /= N_AGENTS;
        for (size_t i = 0; i < N_AGENTS; i++) {
            float diff = final_beliefs[i * BELIEF_DIM + d] - mean;
            final_variance += diff * diff;
        }
    }
    final_variance /= (N_AGENTS * BELIEF_DIM);

    float variance_reduction = (initial_variance - final_variance) / initial_variance;

    std::cout << "\n  Variance reduction: " << (variance_reduction * 100) << "%" << std::endl;

    EXPECT_GT(variance_reduction, 0.5f) << "Should reduce variance significantly";

    E2E_STAGE_END();

    // Cleanup
    nimcp_consensus_gpu_destroy(consensus);

    metrics_.total_agents = N_AGENTS;
    metrics_.timesteps_simulated = iterations;
    PrintMetrics("Swarm Consensus GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 3: Pheromone Simulation
//=============================================================================

TEST_F(SwarmSimulationGPUE2ETest, PheromoneSimulationGPU) {
    E2E_PIPELINE_START("Pheromone Simulation on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const uint32_t GRID_SIZE = 128;
    const uint32_t N_TYPES = 2;  // Food and nest pheromones
    const size_t N_AGENTS = 1000;
    const size_t N_TIMESTEPS = 100;
    const float VOXEL_SIZE = 1.0f;

    // Stage 1: Create pheromone grid
    E2E_STAGE_BEGIN("Create pheromone grid", 2000);

    nimcp_pheromone_gpu_params_t params;
    nimcp_pheromone_gpu_default_params(&params);
    params.diffusion_rate = 0.1f;
    params.evaporation_rate = 0.02f;
    params.decay_rates[0] = 0.01f;  // Food pheromone decay
    params.decay_rates[1] = 0.01f;  // Nest pheromone decay
    params.max_concentration = 100.0f;
    params.deposit_amount = 1.0f;

    nimcp_pheromone_gpu_state_t* pheromone = nimcp_pheromone_gpu_create(
        gpu_ctx_, GRID_SIZE, GRID_SIZE, 1, N_TYPES, VOXEL_SIZE, &params);
    E2E_ASSERT_NOT_NULL(pheromone, "Failed to create pheromone grid");

    std::cout << "\n  Pheromone Grid Configuration:" << std::endl;
    std::cout << "    Grid size: " << GRID_SIZE << "x" << GRID_SIZE << std::endl;
    std::cout << "    Pheromone types: " << N_TYPES << std::endl;
    std::cout << "    Diffusion rate: " << params.diffusion_rate << std::endl;

    E2E_STAGE_END();

    // Stage 2: Create agent positions
    E2E_STAGE_BEGIN("Initialize ant agents", 1000);

    size_t pos_dims[] = {N_AGENTS, 3};
    size_t type_dims[] = {N_AGENTS};
    size_t amount_dims[] = {N_AGENTS};

    nimcp_gpu_tensor_t* agent_positions = nimcp_gpu_tensor_create(
        gpu_ctx_, pos_dims, 2, NIMCP_GPU_PRECISION_FP32);
    nimcp_gpu_tensor_t* pheromone_types = nimcp_gpu_tensor_create(
        gpu_ctx_, type_dims, 1, NIMCP_GPU_PRECISION_UINT32);
    nimcp_gpu_tensor_t* deposit_amounts = nimcp_gpu_tensor_create(
        gpu_ctx_, amount_dims, 1, NIMCP_GPU_PRECISION_FP32);

    // Initialize agents in center of grid
    std::vector<float> positions(N_AGENTS * 3);
    std::vector<uint32_t> types(N_AGENTS);
    std::vector<float> amounts(N_AGENTS, params.deposit_amount);

    std::uniform_real_distribution<float> pos_dist(GRID_SIZE * 0.3f, GRID_SIZE * 0.7f);
    std::bernoulli_distribution type_dist(0.5);

    for (size_t i = 0; i < N_AGENTS; i++) {
        positions[i * 3 + 0] = pos_dist(rng_);
        positions[i * 3 + 1] = pos_dist(rng_);
        positions[i * 3 + 2] = 0.0f;
        types[i] = type_dist(rng_) ? 0 : 1;
    }

    nimcp_gpu_memcpy(gpu_ctx_, agent_positions->data, positions.data(),
                     positions.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);
    nimcp_gpu_memcpy(gpu_ctx_, pheromone_types->data, types.data(),
                     types.size() * sizeof(uint32_t), GPU_MEMCPY_HOST_TO_DEVICE);
    nimcp_gpu_memcpy(gpu_ctx_, deposit_amounts->data, amounts.data(),
                     amounts.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    E2E_STAGE_END();

    // Stage 3: Run pheromone simulation
    E2E_STAGE_BEGIN("Run pheromone simulation", 15000);

    const float DT = 0.1f;
    size_t sample_dims[] = {N_AGENTS};
    nimcp_gpu_tensor_t* sampled = nimcp_gpu_tensor_create(
        gpu_ctx_, sample_dims, 1, NIMCP_GPU_PRECISION_FP32);
    size_t grad_dims[] = {N_AGENTS, 3};
    nimcp_gpu_tensor_t* gradients = nimcp_gpu_tensor_create(
        gpu_ctx_, grad_dims, 2, NIMCP_GPU_PRECISION_FP32);

    auto sim_start = std::chrono::high_resolution_clock::now();

    for (size_t t = 0; t < N_TIMESTEPS; t++) {
        // Deposit pheromones
        bool success = nimcp_gpu_pheromone_deposit(gpu_ctx_, pheromone,
                                                    agent_positions, pheromone_types,
                                                    deposit_amounts, N_AGENTS);
        E2E_ASSERT(success, "Pheromone deposit failed");

        // Diffusion
        success = nimcp_gpu_pheromone_diffusion(gpu_ctx_, pheromone, DT);
        E2E_ASSERT(success, "Pheromone diffusion failed");

        // Decay
        success = nimcp_gpu_pheromone_decay(gpu_ctx_, pheromone, DT);
        E2E_ASSERT(success, "Pheromone decay failed");

        // Sample concentrations at agent positions
        success = nimcp_gpu_pheromone_sample(gpu_ctx_, pheromone,
                                              agent_positions, 0, sampled);
        E2E_ASSERT(success, "Pheromone sampling failed");

        // Compute gradients for agent navigation
        success = nimcp_gpu_pheromone_gradient(gpu_ctx_, pheromone,
                                                agent_positions, 0, gradients);
        E2E_ASSERT(success, "Gradient computation failed");

        // Move agents based on gradient (simplified)
        // In a real simulation, would update positions based on gradients
    }

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto sim_end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(sim_end - sim_start).count();

    std::cout << "\n  Simulation completed:" << std::endl;
    std::cout << "    Time: " << metrics_.gpu_time_ms << " ms" << std::endl;
    std::cout << "    Time per step: " << (metrics_.gpu_time_ms / N_TIMESTEPS) << " ms" << std::endl;

    E2E_STAGE_END();

    // Stage 4: Verify pheromone distribution
    E2E_STAGE_BEGIN("Verify pheromone distribution", 1000);

    std::vector<float> sampled_data(N_AGENTS);
    nimcp_gpu_memcpy(gpu_ctx_, sampled_data.data(), sampled->data,
                     sampled_data.size() * sizeof(float), GPU_MEMCPY_DEVICE_TO_HOST);

    float avg_concentration = std::accumulate(sampled_data.begin(), sampled_data.end(), 0.0f) / N_AGENTS;
    float max_concentration = *std::max_element(sampled_data.begin(), sampled_data.end());

    std::cout << "\n  Pheromone distribution:" << std::endl;
    std::cout << "    Average concentration at agents: " << avg_concentration << std::endl;
    std::cout << "    Max concentration sampled: " << max_concentration << std::endl;

    EXPECT_GT(avg_concentration, 0.0f) << "Should have positive pheromone concentration";

    E2E_STAGE_END();

    // Cleanup
    nimcp_gpu_tensor_destroy(agent_positions);
    nimcp_gpu_tensor_destroy(pheromone_types);
    nimcp_gpu_tensor_destroy(deposit_amounts);
    nimcp_gpu_tensor_destroy(sampled);
    nimcp_gpu_tensor_destroy(gradients);
    nimcp_pheromone_gpu_destroy(pheromone);

    metrics_.total_agents = N_AGENTS;
    metrics_.timesteps_simulated = N_TIMESTEPS;
    PrintMetrics("Pheromone Simulation GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 4: Quorum Sensing
//=============================================================================

TEST_F(SwarmSimulationGPUE2ETest, QuorumSensingGPU) {
    E2E_PIPELINE_START("Quorum Sensing on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const size_t N_AGENTS = 10000;
    const size_t N_SIGNAL_TYPES = 4;
    const size_t N_TIMESTEPS = 50;

    // Stage 1: Create quorum state
    E2E_STAGE_BEGIN("Create quorum sensing state", 1000);

    nimcp_quorum_gpu_params_t params;
    nimcp_quorum_gpu_default_params(&params);
    params.base_threshold = 0.5f;
    params.decay_rate = 0.1f;
    params.amplification = 1.2f;
    params.commitment_low = 0.3f;
    params.commitment_high = 0.7f;

    nimcp_quorum_gpu_state_t* quorum = nimcp_quorum_gpu_create(
        gpu_ctx_, N_AGENTS, N_SIGNAL_TYPES, &params);
    E2E_ASSERT_NOT_NULL(quorum, "Failed to create quorum state");

    std::cout << "\n  Quorum Sensing Configuration:" << std::endl;
    std::cout << "    Agents: " << N_AGENTS << std::endl;
    std::cout << "    Signal types: " << N_SIGNAL_TYPES << std::endl;
    std::cout << "    Threshold: " << params.base_threshold << std::endl;

    E2E_STAGE_END();

    // Stage 2: Initialize agent signals
    E2E_STAGE_BEGIN("Initialize agent signals", 500);

    std::vector<float> signals(N_AGENTS * N_SIGNAL_TYPES);
    std::uniform_real_distribution<float> signal_dist(0.0f, 0.1f);

    // Initialize with low random signals
    for (auto& s : signals) s = signal_dist(rng_);

    // Make some agents "leaders" with higher initial signals
    std::uniform_int_distribution<size_t> leader_type(0, N_SIGNAL_TYPES - 1);
    size_t n_leaders = N_AGENTS / 100;  // 1% leaders
    for (size_t i = 0; i < n_leaders; i++) {
        size_t agent_idx = (i * 100) % N_AGENTS;
        size_t sig_type = leader_type(rng_);
        signals[agent_idx * N_SIGNAL_TYPES + sig_type] = 0.8f;
    }

    nimcp_gpu_memcpy(gpu_ctx_, quorum->agent_signals->data, signals.data(),
                     signals.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    E2E_STAGE_END();

    // Stage 3: Run quorum sensing simulation
    E2E_STAGE_BEGIN("Run quorum sensing", 5000);

    const float DT = 0.1f;
    auto quorum_start = std::chrono::high_resolution_clock::now();

    std::vector<bool> thresholds_reached(N_SIGNAL_TYPES, false);

    for (size_t t = 0; t < N_TIMESTEPS; t++) {
        // Compute global signal concentration
        bool success = nimcp_gpu_quorum_compute_concentration(gpu_ctx_, quorum);
        E2E_ASSERT(success, "Concentration computation failed");

        // Check if thresholds are reached
        success = nimcp_gpu_quorum_check_thresholds(gpu_ctx_, quorum);
        E2E_ASSERT(success, "Threshold check failed");

        // Update agent commitments based on signals
        success = nimcp_gpu_quorum_update_commitments(gpu_ctx_, quorum);
        E2E_ASSERT(success, "Commitment update failed");

        // Apply signal decay
        success = nimcp_gpu_quorum_decay_signals(gpu_ctx_, quorum, DT);
        E2E_ASSERT(success, "Signal decay failed");
    }

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto quorum_end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(
        quorum_end - quorum_start).count();

    std::cout << "\n  Quorum sensing completed in " << metrics_.gpu_time_ms << " ms" << std::endl;

    E2E_STAGE_END();

    // Stage 4: Analyze final state
    E2E_STAGE_BEGIN("Analyze quorum state", 1000);

    std::vector<float> concentrations(N_SIGNAL_TYPES);
    std::vector<uint8_t> thresholds(N_SIGNAL_TYPES);

    nimcp_gpu_memcpy(gpu_ctx_, concentrations.data(), quorum->signal_concentrations->data,
                     N_SIGNAL_TYPES * sizeof(float), GPU_MEMCPY_DEVICE_TO_HOST);
    nimcp_gpu_memcpy(gpu_ctx_, thresholds.data(), quorum->threshold_reached->data,
                     N_SIGNAL_TYPES * sizeof(uint8_t), GPU_MEMCPY_DEVICE_TO_HOST);

    std::cout << "\n  Final signal concentrations:" << std::endl;
    int reached_count = 0;
    for (size_t i = 0; i < N_SIGNAL_TYPES; i++) {
        std::cout << "    Signal " << i << ": " << concentrations[i]
                  << (thresholds[i] ? " (THRESHOLD REACHED)" : "") << std::endl;
        if (thresholds[i]) reached_count++;
    }

    // Get commitment distribution
    std::vector<uint32_t> commitments(N_AGENTS);
    nimcp_gpu_memcpy(gpu_ctx_, commitments.data(), quorum->agent_commitments->data,
                     N_AGENTS * sizeof(uint32_t), GPU_MEMCPY_DEVICE_TO_HOST);

    std::vector<size_t> commitment_counts(N_SIGNAL_TYPES + 1, 0);  // +1 for uncommitted
    for (auto c : commitments) {
        if (c < N_SIGNAL_TYPES + 1) commitment_counts[c]++;
    }

    std::cout << "\n  Agent commitments:" << std::endl;
    std::cout << "    Uncommitted: " << commitment_counts[0] << std::endl;
    for (size_t i = 0; i < N_SIGNAL_TYPES; i++) {
        std::cout << "    Signal " << i << ": " << commitment_counts[i + 1] << std::endl;
    }

    E2E_STAGE_END();

    // Cleanup
    nimcp_quorum_gpu_destroy(quorum);

    metrics_.total_agents = N_AGENTS;
    metrics_.timesteps_simulated = N_TIMESTEPS;
    PrintMetrics("Quorum Sensing GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 5: Task Allocation via Auction
//=============================================================================

TEST_F(SwarmSimulationGPUE2ETest, TaskAllocationGPU) {
    E2E_PIPELINE_START("Task Allocation on GPU");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    const size_t N_AGENTS = 1000;
    const size_t N_TASKS = 500;
    const size_t N_CAP_TYPES = 8;
    const size_t MAX_ROUNDS = 50;

    // Stage 1: Create task allocation state
    E2E_STAGE_BEGIN("Create task allocation state", 1000);

    nimcp_task_alloc_gpu_params_t params;
    nimcp_task_alloc_gpu_default_params(&params);
    params.bid_increment = 0.1f;
    params.epsilon = 0.01f;
    params.max_rounds = MAX_ROUNDS;

    nimcp_task_alloc_gpu_state_t* alloc = nimcp_task_alloc_gpu_create(
        gpu_ctx_, N_AGENTS, N_TASKS, N_CAP_TYPES, &params);
    E2E_ASSERT_NOT_NULL(alloc, "Failed to create task allocation state");

    std::cout << "\n  Task Allocation Configuration:" << std::endl;
    std::cout << "    Agents: " << N_AGENTS << std::endl;
    std::cout << "    Tasks: " << N_TASKS << std::endl;
    std::cout << "    Capability types: " << N_CAP_TYPES << std::endl;

    E2E_STAGE_END();

    // Stage 2: Initialize agent capabilities and task requirements
    E2E_STAGE_BEGIN("Initialize capabilities and requirements", 1000);

    std::vector<float> agent_caps(N_AGENTS * N_CAP_TYPES);
    std::vector<float> task_reqs(N_TASKS * N_CAP_TYPES);

    std::uniform_real_distribution<float> cap_dist(0.0f, 1.0f);
    std::uniform_real_distribution<float> req_dist(0.0f, 0.5f);  // Lower requirements

    for (auto& c : agent_caps) c = cap_dist(rng_);
    for (auto& r : task_reqs) r = req_dist(rng_);

    nimcp_gpu_memcpy(gpu_ctx_, alloc->agent_capabilities->data, agent_caps.data(),
                     agent_caps.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);
    nimcp_gpu_memcpy(gpu_ctx_, alloc->task_requirements->data, task_reqs.data(),
                     task_reqs.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

    // Initialize prices to zero
    nimcp_gpu_zeros(gpu_ctx_, alloc->prices);

    // Initialize assignments to -1 (unassigned)
    std::vector<int32_t> initial_assignments(N_AGENTS, -1);
    nimcp_gpu_memcpy(gpu_ctx_, alloc->assignments->data, initial_assignments.data(),
                     initial_assignments.size() * sizeof(int32_t), GPU_MEMCPY_HOST_TO_DEVICE);

    E2E_STAGE_END();

    // Stage 3: Compute capability matches
    E2E_STAGE_BEGIN("Compute capability matches", 2000);

    bool success = nimcp_gpu_task_compute_matches(gpu_ctx_, alloc);
    E2E_ASSERT(success, "Match computation failed");

    E2E_STAGE_END();

    // Stage 4: Run auction algorithm
    E2E_STAGE_BEGIN("Run auction rounds", 10000);

    auto auction_start = std::chrono::high_resolution_clock::now();

    size_t rounds_completed = 0;
    for (size_t round = 0; round < MAX_ROUNDS; round++) {
        // Agents bid on tasks
        success = nimcp_gpu_task_auction_round(gpu_ctx_, alloc);
        E2E_ASSERT(success, "Auction round failed");

        // Update task prices based on bids
        success = nimcp_gpu_task_update_prices(gpu_ctx_, alloc);
        E2E_ASSERT(success, "Price update failed");

        rounds_completed++;
    }

    // Finalize assignments
    success = nimcp_gpu_task_finalize_assignments(gpu_ctx_, alloc);
    E2E_ASSERT(success, "Assignment finalization failed");

    nimcp_gpu_context_synchronize(gpu_ctx_);
    auto auction_end = std::chrono::high_resolution_clock::now();
    metrics_.gpu_time_ms = std::chrono::duration<double, std::milli>(
        auction_end - auction_start).count();

    std::cout << "\n  Auction completed:" << std::endl;
    std::cout << "    Rounds: " << rounds_completed << std::endl;
    std::cout << "    Time: " << metrics_.gpu_time_ms << " ms" << std::endl;

    E2E_STAGE_END();

    // Stage 5: Analyze assignments
    E2E_STAGE_BEGIN("Analyze assignments", 1000);

    std::vector<int32_t> assignments(N_AGENTS);
    nimcp_gpu_memcpy(gpu_ctx_, assignments.data(), alloc->assignments->data,
                     assignments.size() * sizeof(int32_t), GPU_MEMCPY_DEVICE_TO_HOST);

    size_t assigned_count = 0;
    std::vector<int> task_agent_count(N_TASKS, 0);

    for (size_t i = 0; i < N_AGENTS; i++) {
        if (assignments[i] >= 0 && static_cast<size_t>(assignments[i]) < N_TASKS) {
            assigned_count++;
            task_agent_count[assignments[i]]++;
        }
    }

    size_t tasks_with_agents = 0;
    for (auto count : task_agent_count) {
        if (count > 0) tasks_with_agents++;
    }

    std::cout << "\n  Assignment results:" << std::endl;
    std::cout << "    Agents assigned: " << assigned_count << "/" << N_AGENTS << std::endl;
    std::cout << "    Tasks with agents: " << tasks_with_agents << "/" << N_TASKS << std::endl;
    std::cout << "    Assignment rate: " << (100.0 * assigned_count / N_AGENTS) << "%" << std::endl;

    EXPECT_GT(assigned_count, N_AGENTS / 2) << "Majority of agents should be assigned";

    E2E_STAGE_END();

    // Cleanup
    nimcp_task_alloc_gpu_destroy(alloc);

    metrics_.total_agents = N_AGENTS;
    metrics_.timesteps_simulated = rounds_completed;
    PrintMetrics("Task Allocation GPU");

    E2E_PIPELINE_END();
}

//=============================================================================
// Pipeline 6: Scalability Benchmark
//=============================================================================

TEST_F(SwarmSimulationGPUE2ETest, SwarmScalabilityBenchmark) {
    E2E_PIPELINE_START("Swarm Scalability Benchmark");

    if (!HasGPU()) {
        std::cout << "Skipping GPU test - no GPU available" << std::endl;
        E2E_PIPELINE_END();
        GTEST_SKIP() << "No GPU available";
    }

    // Test scaling from 1K to 100K agents
    std::vector<size_t> agent_counts = {1000, 5000, 10000, 25000, 50000, 100000};
    const size_t N_TIMESTEPS = 50;
    const size_t MAX_NEIGHBORS = 32;

    std::cout << "\n=== Swarm Scalability Benchmark ===" << std::endl;
    std::cout << "| Agents  | Time(ms) | Agents/sec   | Memory(MB) |" << std::endl;
    std::cout << "|---------|----------|--------------|------------|" << std::endl;

    for (size_t n_agents : agent_counts) {
        // Create flocking state
        nimcp_flocking_gpu_params_t params;
        nimcp_flocking_gpu_default_params(&params);
        params.dt = 0.016f;

        nimcp_flocking_gpu_state_t* flock = nimcp_flocking_gpu_create(
            gpu_ctx_, n_agents, MAX_NEIGHBORS, &params);

        if (!flock) {
            std::cout << "| " << n_agents << " | FAILED - memory allocation |" << std::endl;
            continue;
        }

        // Initialize
        std::vector<float> positions;
        std::vector<float> velocities;
        InitializeRandomPositions(positions, n_agents, -100.0f, 100.0f);
        InitializeRandomVelocities(velocities, n_agents, params.max_speed);

        nimcp_gpu_memcpy(gpu_ctx_, flock->positions->data, positions.data(),
                         positions.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);
        nimcp_gpu_memcpy(gpu_ctx_, flock->velocities->data, velocities.data(),
                         velocities.size() * sizeof(float), GPU_MEMCPY_HOST_TO_DEVICE);

        // Create spatial hash
        nimcp_spatial_hash_t* hash = nimcp_spatial_hash_create(
            gpu_ctx_, params.cohesion_radius, 64, 64, 64, n_agents);

        // Warm up
        nimcp_gpu_spatial_hash_build(gpu_ctx_, hash, flock->positions, n_agents);
        nimcp_gpu_flocking_find_neighbors(gpu_ctx_, flock, params.cohesion_radius);
        nimcp_gpu_flocking_compute_forces(gpu_ctx_, flock);
        nimcp_gpu_flocking_update(gpu_ctx_, flock, params.dt);
        nimcp_gpu_context_synchronize(gpu_ctx_);

        // Benchmark
        auto start = std::chrono::high_resolution_clock::now();

        for (size_t t = 0; t < N_TIMESTEPS; t++) {
            if (t % 10 == 0) {
                nimcp_gpu_spatial_hash_build(gpu_ctx_, hash, flock->positions, n_agents);
            }
            nimcp_gpu_flocking_find_neighbors(gpu_ctx_, flock, params.cohesion_radius);
            nimcp_gpu_flocking_compute_forces(gpu_ctx_, flock);
            nimcp_gpu_flocking_update(gpu_ctx_, flock, params.dt);
        }

        nimcp_gpu_context_synchronize(gpu_ctx_);
        auto end = std::chrono::high_resolution_clock::now();
        double time_ms = std::chrono::duration<double, std::milli>(end - start).count();

        double agents_per_sec = (n_agents * N_TIMESTEPS) / (time_ms / 1000.0);

        // Get memory usage
        size_t allocated = 0, peak = 0, free_mem = 0;
        nimcp_gpu_memory_stats(gpu_ctx_, &allocated, &peak, &free_mem);
        double memory_mb = peak / (1024.0 * 1024.0);

        std::cout << "| " << n_agents << " | " << time_ms << " | "
                  << agents_per_sec << " | " << memory_mb << " |" << std::endl;

        nimcp_spatial_hash_destroy(hash);
        nimcp_flocking_gpu_destroy(flock);
    }

    E2E_PIPELINE_END();
}

//=============================================================================
// Main
//=============================================================================

int main(int argc, char** argv) {
    ::testing::InitGoogleTest(&argc, argv);
    return RUN_ALL_TESTS();
}
