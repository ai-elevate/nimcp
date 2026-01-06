/**
 * @file e2e_test_gw_snn_plasticity_pipeline.cpp
 * @brief End-to-end tests for Global Workspace-SNN-Plasticity learning pipeline
 * @version 1.0.0
 * @date 2026-01-06
 *
 * WHAT: Complete Global Workspace pipeline with SNN and Plasticity
 * WHY:  Verify full dataflow from workspace state -> SNN encoding -> conscious access
 *       -> plasticity learning -> ignition calibration evolution
 * HOW:  Test realistic scenarios combining broadcast encoding, STDP learning,
 *       reward-modulated plasticity, and protected synapse integrity
 *
 * Test Coverage:
 * - Full workspace state to conscious access pipeline via SNN
 * - STDP and reward-modulated learning for broadcast calibration
 * - Ignition detection and threshold adaptation
 * - Broadcast and Integration synapse protection
 * - Multi-scenario conscious access learning
 * - Access threshold evolution through experience
 * - Protected synapse integrity under stress
 */

#include <gtest/gtest.h>

extern "C" {
#include "cognitive/global_workspace/nimcp_gw_snn_bridge.h"
#include "cognitive/global_workspace/nimcp_gw_plasticity_bridge.h"
#include "utils/memory/nimcp_memory.h"
#include "utils/time/nimcp_time.h"
}

#include <cstring>
#include <cmath>
#include <vector>
#include <chrono>
#include <numeric>

//=============================================================================
// Test Fixtures
//=============================================================================

class GWSNNPlasticityE2E : public ::testing::Test {
protected:
    gw_snn_bridge_t* snn_bridge = nullptr;
    gw_plasticity_bridge_t* plasticity_bridge = nullptr;

    // Learning statistics
    struct LearningStats {
        int broadcast_successful = 0;
        int broadcast_failed = 0;
        int ignition_detected = 0;
        int total_evaluations = 0;
        std::vector<float> broadcast_history;
        std::vector<float> ignition_scores;
    } stats;

    void SetUp() override {
        // Create SNN bridge with full GW dimensions
        gw_snn_config_t snn_config = gw_snn_config_default();
        snn_config.num_dimensions = GW_DIM_COUNT;
        snn_config.neurons_per_dim = 32;
        snn_config.dt_ms = 1.0f;
        snn_config.enable_competition = true;
        snn_config.enable_bio_async = false;

        snn_bridge = gw_snn_create(&snn_config);
        ASSERT_NE(snn_bridge, nullptr) << "Failed to create SNN bridge";

        // Create Plasticity bridge with all learning mechanisms
        gw_plasticity_config_t plasticity_config = gw_plasticity_config_default();
        plasticity_config.base_learning_rate = 0.01f;
        plasticity_config.stdp_a_plus = 0.01f;
        plasticity_config.stdp_a_minus = 0.012f;

        plasticity_bridge = gw_plasticity_create(&plasticity_config);
        ASSERT_NE(plasticity_bridge, nullptr) << "Failed to create Plasticity bridge";

        // Register base synapses for plasticity
        for (uint32_t i = 0; i < GW_DIM_COUNT; i++) {
            gw_plasticity_register_synapse(plasticity_bridge, i,
                GW_SYNAPSE_COALITION, 0.5f);
        }

        // Register protected synapses
        gw_plasticity_register_synapse(plasticity_bridge, 100,
            GW_SYNAPSE_BROADCAST, 1.0f);
        gw_plasticity_register_synapse(plasticity_bridge, 101,
            GW_SYNAPSE_INTEGRATION, 0.9f);
    }

    void TearDown() override {
        if (snn_bridge) {
            gw_snn_destroy(snn_bridge);
            snn_bridge = nullptr;
        }
        if (plasticity_bridge) {
            gw_plasticity_destroy(plasticity_bridge);
            plasticity_bridge = nullptr;
        }
    }

    // Helper: Generate workspace context scenario
    void generate_scenario(float* dims, int scenario_type) {
        memset(dims, 0, sizeof(float) * GW_DIM_COUNT);

        switch (scenario_type) {
            case 0: // Strong broadcast (should succeed)
                dims[GW_DIM_BROADCAST] = 0.9f;
                dims[GW_DIM_IGNITION] = 0.85f;
                dims[GW_DIM_COMPETITION] = 0.7f;
                dims[GW_DIM_ACCESS_CONSCIOUSNESS] = 0.8f;
                break;
            case 1: // Weak broadcast (subthreshold)
                dims[GW_DIM_BROADCAST] = 0.3f;
                dims[GW_DIM_IGNITION] = 0.2f;
                dims[GW_DIM_COMPETITION] = 0.4f;
                dims[GW_DIM_ACCESS_CONSCIOUSNESS] = 0.2f;
                break;
            case 2: // High competition scenario
                dims[GW_DIM_COMPETITION] = 0.95f;
                dims[GW_DIM_COALITION_STRENGTH] = 0.9f;
                dims[GW_DIM_ATTENTION_WINNER] = 0.8f;
                dims[GW_DIM_BROADCAST] = 0.6f;
                break;
            case 3: // Feature binding scenario
                dims[GW_DIM_BINDING] = 0.95f;
                dims[GW_DIM_INTEGRATION] = 0.9f;
                dims[GW_DIM_CONSCIOUS_CONTENT] = 0.85f;
                dims[GW_DIM_BROADCAST] = 0.75f;
                break;
            default: // Random mid-range
                for (int i = 0; i < GW_DIM_COUNT; i++) {
                    dims[i] = 0.4f + 0.2f * (float)(rand() % 10) / 10.0f;
                }
                break;
        }
    }

    // Helper: Run full pipeline iteration
    void run_pipeline_iteration(float* dims, bool expected_success) {
        // 1. Encode workspace state
        int spikes = gw_snn_encode_state(snn_bridge, dims, GW_DIM_COUNT);
        EXPECT_GE(spikes, 0);

        // 2. Simulate SNN processing
        EXPECT_EQ(gw_snn_simulate(snn_bridge, 30.0f), 0);

        // 3. Get conscious access result
        gw_conscious_access_t access;
        EXPECT_EQ(gw_snn_get_conscious_access(snn_bridge, &access), 0);

        stats.broadcast_history.push_back(access.broadcast_strength);
        stats.ignition_scores.push_back(access.ignition_level);
        stats.total_evaluations++;

        // 4. Apply learning based on outcome
        if (access.broadcast_strength > 0.5f) {
            stats.broadcast_successful++;
            for (uint32_t i = 0; i < GW_DIM_COUNT; i++) {
                gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_SUCCESS,
                                    access.broadcast_strength, i, dims[i]);
            }
        } else {
            stats.broadcast_failed++;
            for (uint32_t i = 0; i < GW_DIM_COUNT; i++) {
                gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_FAILURE,
                                    1.0f - access.broadcast_strength, i, dims[i]);
            }
        }

        // 5. Check ignition
        if (access.ignition_detected) {
            stats.ignition_detected++;
            gw_plasticity_learn(plasticity_bridge, GW_LEARN_IGNITION_TRIGGERED,
                                access.ignition_level, 0, 1.0f);
        }

        // 6. Update traces and BCM
        gw_plasticity_update_traces(plasticity_bridge, 10.0f);
        gw_plasticity_update_bcm(plasticity_bridge, 10.0f);
    }
};

//=============================================================================
// Full Pipeline E2E Tests
//=============================================================================

TEST_F(GWSNNPlasticityE2E, FullBroadcastToLearningPipeline) {
    float dims[GW_DIM_COUNT];

    // Run strong broadcast scenario
    generate_scenario(dims, 0);
    run_pipeline_iteration(dims, true);

    // Run weak broadcast scenario
    generate_scenario(dims, 1);
    run_pipeline_iteration(dims, false);

    // Verify statistics
    EXPECT_GE(stats.total_evaluations, 2);
}

TEST_F(GWSNNPlasticityE2E, IgnitionCascadeLearning) {
    float dims[GW_DIM_COUNT];

    // Generate scenario with high ignition
    generate_scenario(dims, 0);
    dims[GW_DIM_IGNITION] = 0.95f;

    // Encode and simulate
    gw_snn_encode_state(snn_bridge, dims, GW_DIM_COUNT);
    gw_snn_simulate(snn_bridge, 50.0f);

    // Get access with ignition
    gw_conscious_access_t access;
    gw_snn_get_conscious_access(snn_bridge, &access);

    // Learn from ignition cascade
    gw_plasticity_learn(plasticity_bridge, GW_LEARN_IGNITION_TRIGGERED,
                        access.ignition_level, 0, 1.0f);

    // Verify ignition event tracked
    gw_plasticity_stats_t pl_stats;
    gw_plasticity_get_stats(plasticity_bridge, &pl_stats);
    EXPECT_GE(pl_stats.ignition_events, 1u);
}

TEST_F(GWSNNPlasticityE2E, CompetitionWinnerLearning) {
    float dims[GW_DIM_COUNT];

    // Generate high competition scenario
    generate_scenario(dims, 2);

    // Encode and simulate
    gw_snn_encode_state(snn_bridge, dims, GW_DIM_COUNT);
    gw_snn_simulate(snn_bridge, 50.0f);

    // Register competition synapse
    gw_plasticity_register_synapse(plasticity_bridge, 200, GW_SYNAPSE_COMPETITION, 0.5f);

    gw_plasticity_synapse_t before;
    gw_plasticity_get_synapse(plasticity_bridge, 200, &before);

    // Learn from competition win
    gw_plasticity_learn(plasticity_bridge, GW_LEARN_COMPETITION_WON,
                        dims[GW_DIM_COMPETITION], 200, 1.0f);

    gw_plasticity_synapse_t after;
    gw_plasticity_get_synapse(plasticity_bridge, 200, &after);

    // Weight should increase
    EXPECT_GT(after.weight, before.weight);
}

TEST_F(GWSNNPlasticityE2E, FeatureBindingLearning) {
    float dims[GW_DIM_COUNT];

    // Generate binding scenario
    generate_scenario(dims, 3);

    // Encode and simulate
    gw_snn_encode_state(snn_bridge, dims, GW_DIM_COUNT);
    gw_snn_simulate(snn_bridge, 50.0f);

    // Get access with binding
    gw_conscious_access_t access;
    gw_snn_get_conscious_access(snn_bridge, &access);

    // Register binding synapse
    gw_plasticity_register_synapse(plasticity_bridge, 201, GW_SYNAPSE_BINDING, 0.5f);

    // Learn from binding
    gw_plasticity_learn(plasticity_bridge, GW_LEARN_BINDING_FORMED,
                        access.binding_strength, 201, 1.0f);

    // Verify learning occurred
    gw_plasticity_stats_t pl_stats;
    gw_plasticity_get_stats(plasticity_bridge, &pl_stats);
    EXPECT_GT(pl_stats.total_learning_events, 0u);
}

//=============================================================================
// Protection Mechanism E2E Tests
//=============================================================================

TEST_F(GWSNNPlasticityE2E, BroadcastSynapseProtectionUnderStress) {
    // Get initial weight of protected broadcast synapse
    gw_plasticity_synapse_t initial;
    gw_plasticity_get_synapse(plasticity_bridge, 100, &initial);
    EXPECT_TRUE(initial.is_protected);
    float initial_weight = initial.weight;

    // Apply many learning events
    float dims[GW_DIM_COUNT];
    for (int i = 0; i < 50; i++) {
        generate_scenario(dims, i % 4);
        gw_snn_encode_state(snn_bridge, dims, GW_DIM_COUNT);
        gw_snn_simulate(snn_bridge, 20.0f);

        gw_conscious_access_t access;
        gw_snn_get_conscious_access(snn_bridge, &access);

        // Try to modify protected synapse
        gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_SUCCESS,
                            access.broadcast_strength, 100, 1.0f);
        gw_plasticity_apply_stdp(plasticity_bridge, 100, 0.0f, 10.0f);
    }

    // Verify weight unchanged
    gw_plasticity_synapse_t final;
    gw_plasticity_get_synapse(plasticity_bridge, 100, &final);
    EXPECT_NEAR(final.weight, initial_weight, 0.001f);
}

TEST_F(GWSNNPlasticityE2E, IntegrationSynapseProtectionUnderStress) {
    // Get initial weight of protected integration synapse
    gw_plasticity_synapse_t initial;
    gw_plasticity_get_synapse(plasticity_bridge, 101, &initial);
    EXPECT_TRUE(initial.is_protected);
    float initial_weight = initial.weight;

    // Apply stress
    for (int i = 0; i < 50; i++) {
        gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_SUCCESS, 1.0f, 101, 1.0f);
        gw_plasticity_apply_reward(plasticity_bridge, 1.0f);
    }

    // Verify protected
    gw_plasticity_synapse_t final;
    gw_plasticity_get_synapse(plasticity_bridge, 101, &final);
    EXPECT_NEAR(final.weight, initial_weight, 0.001f);
}

//=============================================================================
// Multi-Scenario Learning E2E Tests
//=============================================================================

TEST_F(GWSNNPlasticityE2E, ExtendedLearningCycle) {
    float dims[GW_DIM_COUNT];

    // Run 100 learning iterations with various scenarios
    for (int i = 0; i < 100; i++) {
        generate_scenario(dims, i % 4);
        run_pipeline_iteration(dims, (i % 4) == 0);

        // Periodic homeostatic update
        if (i % 10 == 0) {
            gw_plasticity_homeostatic_update(plasticity_bridge, 100.0f);
        }
    }

    // Verify statistics
    EXPECT_EQ(stats.total_evaluations, 100);
    EXPECT_GT(stats.broadcast_successful + stats.broadcast_failed, 0);

    // Verify plasticity stats
    gw_plasticity_stats_t pl_stats;
    gw_plasticity_get_stats(plasticity_bridge, &pl_stats);
    EXPECT_GT(pl_stats.total_learning_events, 0u);
    EXPECT_GT(pl_stats.weight_updates, 0u);
}

TEST_F(GWSNNPlasticityE2E, AccessCalibrationEvolution) {
    // Get initial access learning state
    gw_access_learning_state_t initial_state;
    gw_plasticity_get_access_learning_state(plasticity_bridge, &initial_state);

    float dims[GW_DIM_COUNT];

    // Run calibration cycle
    for (int i = 0; i < 50; i++) {
        // Alternate between success and failure scenarios
        if (i % 2 == 0) {
            generate_scenario(dims, 0);  // Strong broadcast
        } else {
            generate_scenario(dims, 1);  // Weak broadcast
        }

        gw_snn_encode_state(snn_bridge, dims, GW_DIM_COUNT);
        gw_snn_simulate(snn_bridge, 30.0f);

        gw_conscious_access_t access;
        gw_snn_get_conscious_access(snn_bridge, &access);

        // Apply appropriate learning
        if (access.broadcast_strength > 0.5f) {
            gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_SUCCESS,
                                access.broadcast_strength, 0, 1.0f);
        } else {
            gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_FAILURE,
                                0.5f, 0, 1.0f);
        }

        gw_plasticity_homeostatic_update(plasticity_bridge, 50.0f);
    }

    // Get final access learning state
    gw_access_learning_state_t final_state;
    gw_plasticity_get_access_learning_state(plasticity_bridge, &final_state);

    // State should have evolved
    EXPECT_NE(final_state.ignition_calibration, initial_state.ignition_calibration);
}

//=============================================================================
// STDP Learning E2E Tests
//=============================================================================

TEST_F(GWSNNPlasticityE2E, STDPPotentiationDepression) {
    // Register test synapse
    gw_plasticity_register_synapse(plasticity_bridge, 300, GW_SYNAPSE_COALITION, 0.5f);

    gw_plasticity_synapse_t initial;
    gw_plasticity_get_synapse(plasticity_bridge, 300, &initial);

    // Apply potentiation (post after pre)
    float pot_delta = gw_plasticity_apply_stdp(plasticity_bridge, 300, 0.0f, 15.0f);
    EXPECT_GT(pot_delta, 0.0f);

    gw_plasticity_synapse_t after_pot;
    gw_plasticity_get_synapse(plasticity_bridge, 300, &after_pot);
    EXPECT_GT(after_pot.weight, initial.weight);

    // Apply depression (pre after post)
    float dep_delta = gw_plasticity_apply_stdp(plasticity_bridge, 300, 15.0f, 0.0f);
    EXPECT_LT(dep_delta, 0.0f);

    gw_plasticity_synapse_t after_dep;
    gw_plasticity_get_synapse(plasticity_bridge, 300, &after_dep);
    EXPECT_LT(after_dep.weight, after_pot.weight);
}

TEST_F(GWSNNPlasticityE2E, RewardModulatedLearningPipeline) {
    // Register synapse with eligibility
    gw_plasticity_register_synapse(plasticity_bridge, 301, GW_SYNAPSE_COALITION, 0.5f);

    // Build eligibility through activity
    float dims[GW_DIM_COUNT];
    generate_scenario(dims, 0);
    gw_snn_encode_state(snn_bridge, dims, GW_DIM_COUNT);
    gw_snn_simulate(snn_bridge, 50.0f);

    // Learn to build eligibility
    gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_SUCCESS, 0.8f, 301, 1.0f);

    // Apply positive reward
    EXPECT_EQ(gw_plasticity_apply_reward(plasticity_bridge, 0.8f), 0);

    // Apply negative reward
    EXPECT_EQ(gw_plasticity_apply_reward(plasticity_bridge, -0.5f), 0);

    // Verify stats
    gw_plasticity_stats_t pl_stats;
    gw_plasticity_get_stats(plasticity_bridge, &pl_stats);
    EXPECT_GT(pl_stats.weight_updates, 0u);
}

//=============================================================================
// Performance E2E Tests
//=============================================================================

TEST_F(GWSNNPlasticityE2E, PipelinePerformanceUnder1000Iterations) {
    float dims[GW_DIM_COUNT];

    auto start = std::chrono::high_resolution_clock::now();

    for (int i = 0; i < 1000; i++) {
        generate_scenario(dims, i % 4);
        gw_snn_encode_state(snn_bridge, dims, GW_DIM_COUNT);
        gw_snn_simulate(snn_bridge, 10.0f);

        gw_conscious_access_t access;
        gw_snn_get_conscious_access(snn_bridge, &access);

        gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_SUCCESS,
                            access.broadcast_strength, i % GW_DIM_COUNT, 1.0f);
        gw_plasticity_update_traces(plasticity_bridge, 1.0f);
    }

    auto end = std::chrono::high_resolution_clock::now();
    auto duration = std::chrono::duration_cast<std::chrono::milliseconds>(end - start);

    // Should complete in under 5 seconds
    EXPECT_LT(duration.count(), 5000) << "Pipeline too slow: " << duration.count() << "ms";
}

//=============================================================================
// Consolidation E2E Tests
//=============================================================================

TEST_F(GWSNNPlasticityE2E, ConsolidationPreservesLearning) {
    // Register synapse and apply learning
    gw_plasticity_register_synapse(plasticity_bridge, 400, GW_SYNAPSE_COALITION, 0.5f);

    // Apply multiple learning events
    for (int i = 0; i < 10; i++) {
        gw_plasticity_learn(plasticity_bridge, GW_LEARN_BROADCAST_SUCCESS, 0.9f, 400, 1.0f);
    }

    gw_plasticity_synapse_t before_consolidation;
    gw_plasticity_get_synapse(plasticity_bridge, 400, &before_consolidation);

    // Consolidate
    EXPECT_EQ(gw_plasticity_consolidate(plasticity_bridge), 0);

    gw_plasticity_synapse_t after_consolidation;
    gw_plasticity_get_synapse(plasticity_bridge, 400, &after_consolidation);

    // Weight should be preserved
    EXPECT_NEAR(before_consolidation.weight, after_consolidation.weight, 0.001f);

    // But eligibility trace should be cleared
    EXPECT_LT(after_consolidation.eligibility_trace, 0.01f);
}
