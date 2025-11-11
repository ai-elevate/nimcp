/**
 * @file test_multigpu_mock.cpp
 * @brief Mock Tests for Multi-GPU Functionality
 *
 * WHAT: Test multi-GPU API without requiring real GPU hardware
 * WHY:  Enable CI/CD testing on CPU-only systems
 * HOW:  Test device enumeration, partitioning, memory management, synchronization
 *
 * @author NIMCP Development Team
 * @date 2025
 */

#include <gtest/gtest.h>

extern "C" {
    #include "gpu/nimcp_multigpu.h"
}

//=============================================================================
// Test Fixtures
//=============================================================================

class MultiGPUMockTest : public ::testing::Test {
protected:
    void SetUp() override {
        // Test setup
    }

    void TearDown() override {
        // Test cleanup
    }
};

//=============================================================================
// Device Enumeration Tests
//=============================================================================

TEST_F(MultiGPUMockTest, EnumerateDevices_Success) {
    // WHAT: Test device enumeration returns mock GPUs
    // WHY:  Need to verify mock backend is working
    // HOW:  Call enumerate and check count > 0

    multigpu_device_info_t devices[8];
    uint32_t count = 0;

    bool result = multigpu_enumerate_devices(devices, 8, &count);

    EXPECT_TRUE(result);
    EXPECT_GT(count, 0u) << "Should detect at least one mock GPU";
    EXPECT_LE(count, 8u) << "Should not exceed max_devices";

    // Verify first device has valid info
    if (count > 0) {
        EXPECT_GE(devices[0].device_id, 0);
        EXPECT_GT(devices[0].total_memory_bytes, 0u);
        EXPECT_GT(strlen(devices[0].name), 0u);
    }
}

TEST_F(MultiGPUMockTest, EnumerateDevices_NullDevices) {
    // WHAT: Test NULL device array handling
    // WHY:  Guard clause validation
    // HOW:  Pass NULL, expect false

    uint32_t count = 0;
    bool result = multigpu_enumerate_devices(nullptr, 8, &count);

    EXPECT_FALSE(result);
}

TEST_F(MultiGPUMockTest, EnumerateDevices_NullCount) {
    // WHAT: Test NULL count handling
    // WHY:  Guard clause validation
    // HOW:  Pass NULL count, expect false

    multigpu_device_info_t devices[8];
    bool result = multigpu_enumerate_devices(devices, 8, nullptr);

    EXPECT_FALSE(result);
}

TEST_F(MultiGPUMockTest, EnumerateDevices_ZeroMaxDevices) {
    // WHAT: Test zero max_devices
    // WHY:  Guard clause validation
    // HOW:  Pass 0, expect false

    multigpu_device_info_t devices[8];
    uint32_t count = 0;

    bool result = multigpu_enumerate_devices(devices, 0, &count);

    EXPECT_FALSE(result);
    EXPECT_EQ(count, 0u);
}

TEST_F(MultiGPUMockTest, CheckPeerAccess_SameDevice) {
    // WHAT: Test P2P access check for same device
    // WHY:  Device should always access itself
    // HOW:  Check device 0 -> device 0

    bool result = multigpu_check_peer_access(0, 0);

    EXPECT_TRUE(result) << "Device should always access itself";
}

TEST_F(MultiGPUMockTest, CheckPeerAccess_DifferentDevices) {
    // WHAT: Test P2P access between different mock devices
    // WHY:  Mock backend should support P2P
    // HOW:  Check device 0 -> device 1

    bool result = multigpu_check_peer_access(0, 1);

    EXPECT_TRUE(result) << "Mock devices should support P2P";
}

TEST_F(MultiGPUMockTest, GetRecommendedCount_SmallNetwork) {
    // WHAT: Test GPU recommendation for small network
    // WHY:  Should recommend 1 GPU (overhead not worth it)
    // HOW:  Pass 10K neurons, expect 1

    uint32_t recommended = multigpu_get_recommended_count(10000, 100, 4);

    EXPECT_EQ(recommended, 1u) << "Small network should use 1 GPU";
}

TEST_F(MultiGPUMockTest, GetRecommendedCount_MediumNetwork) {
    // WHAT: Test GPU recommendation for medium network
    // WHY:  Should recommend 2 GPUs
    // HOW:  Pass 500K neurons, expect 2

    uint32_t recommended = multigpu_get_recommended_count(500000, 100, 4);

    EXPECT_EQ(recommended, 2u) << "Medium network should use 2 GPUs";
}

TEST_F(MultiGPUMockTest, GetRecommendedCount_LargeNetwork) {
    // WHAT: Test GPU recommendation for large network
    // WHY:  Should recommend 4 GPUs
    // HOW:  Pass 5M neurons, expect 4

    uint32_t recommended = multigpu_get_recommended_count(5000000, 100, 8);

    EXPECT_EQ(recommended, 4u) << "Large network should use 4 GPUs";
}

TEST_F(MultiGPUMockTest, GetRecommendedCount_NoGPUs) {
    // WHAT: Test recommendation when no GPUs available
    // WHY:  Guard clause validation
    // HOW:  Pass 0 available, expect 0

    uint32_t recommended = multigpu_get_recommended_count(1000000, 100, 0);

    EXPECT_EQ(recommended, 0u) << "No GPUs available should return 0";
}

//=============================================================================
// Context Management Tests
//=============================================================================

TEST_F(MultiGPUMockTest, ContextCreate_DefaultConfig) {
    // WHAT: Test context creation with default config
    // WHY:  Most common use case
    // HOW:  Create with default config, verify non-NULL

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);

    ASSERT_NE(ctx, nullptr) << "Context creation should succeed";

    uint32_t device_count = multigpu_get_device_count(ctx);
    EXPECT_GT(device_count, 0u) << "Should have at least one device";

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, ContextCreate_NullConfig) {
    // WHAT: Test NULL config handling
    // WHY:  Guard clause validation
    // HOW:  Pass NULL, expect NULL context

    multigpu_context_t ctx = multigpu_context_create(nullptr);

    EXPECT_EQ(ctx, nullptr);
}

TEST_F(MultiGPUMockTest, ContextCreate_SpecificDeviceCount) {
    // WHAT: Test creating context with specific device count
    // WHY:  User may want to use subset of GPUs
    // HOW:  Request 2 devices, verify

    multigpu_config_t config = multigpu_default_config();
    config.num_devices = 2;

    multigpu_context_t ctx = multigpu_context_create(&config);

    ASSERT_NE(ctx, nullptr);

    uint32_t device_count = multigpu_get_device_count(ctx);
    EXPECT_EQ(device_count, 2u) << "Should have exactly 2 devices";

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, ContextDestroy_NullContext) {
    // WHAT: Test NULL context handling in destroy
    // WHY:  Guard clause validation (should not crash)
    // HOW:  Pass NULL, verify no crash

    EXPECT_NO_THROW(multigpu_context_destroy(nullptr));
}

TEST_F(MultiGPUMockTest, GetDeviceCount_NullContext) {
    // WHAT: Test device count with NULL context
    // WHY:  Guard clause validation
    // HOW:  Pass NULL, expect 0

    uint32_t count = multigpu_get_device_count(nullptr);

    EXPECT_EQ(count, 0u);
}

TEST_F(MultiGPUMockTest, GetDeviceInfo_Success) {
    // WHAT: Test getting device info
    // WHY:  Verify device info is accessible
    // HOW:  Create context, query device 0

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);

    ASSERT_NE(ctx, nullptr);

    multigpu_device_info_t info;
    bool result = multigpu_get_device_info(ctx, 0, &info);

    EXPECT_TRUE(result);
    EXPECT_GE(info.device_id, 0);
    EXPECT_GT(info.total_memory_bytes, 0u);

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, GetDeviceInfo_InvalidIndex) {
    // WHAT: Test invalid device index
    // WHY:  Guard clause validation
    // HOW:  Query out-of-range index, expect false

    multigpu_config_t config = multigpu_default_config();
    config.num_devices = 2;
    multigpu_context_t ctx = multigpu_context_create(&config);

    ASSERT_NE(ctx, nullptr);

    multigpu_device_info_t info;
    bool result = multigpu_get_device_info(ctx, 999, &info);

    EXPECT_FALSE(result) << "Invalid index should return false";

    multigpu_context_destroy(ctx);
}

//=============================================================================
// Work Distribution Tests
//=============================================================================

TEST_F(MultiGPUMockTest, PartitionNetwork_LayerStrategy) {
    // WHAT: Test layer-based partitioning
    // WHY:  Most common strategy for deep networks
    // HOW:  Create network with 8 layers, partition across 2 GPUs

    multigpu_config_t config = multigpu_default_config();
    config.num_devices = 2;
    config.partition_strategy = MULTIGPU_PARTITION_LAYER;

    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    uint32_t num_layers = 8;
    uint32_t neurons_per_layer[8] = {100, 200, 200, 200, 200, 200, 200, 100};

    bool result = multigpu_partition_network(ctx, num_layers, neurons_per_layer);

    EXPECT_TRUE(result);

    // Check layer assignments
    int assignment0 = multigpu_get_layer_assignment(ctx, 0);
    int assignment7 = multigpu_get_layer_assignment(ctx, 7);

    EXPECT_GE(assignment0, 0) << "Layer 0 should be assigned";
    EXPECT_GE(assignment7, 0) << "Layer 7 should be assigned";
    EXPECT_LT(assignment0, 2) << "Assignment should be < num_devices";
    EXPECT_LT(assignment7, 2) << "Assignment should be < num_devices";

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, PartitionNetwork_NullContext) {
    // WHAT: Test NULL context in partition
    // WHY:  Guard clause validation
    // HOW:  Pass NULL, expect false

    uint32_t neurons[4] = {100, 200, 200, 100};
    bool result = multigpu_partition_network(nullptr, 4, neurons);

    EXPECT_FALSE(result);
}

TEST_F(MultiGPUMockTest, PartitionNetwork_ZeroLayers) {
    // WHAT: Test zero layers
    // WHY:  Guard clause validation
    // HOW:  Pass 0 layers, expect false

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    uint32_t neurons[1] = {100};
    bool result = multigpu_partition_network(ctx, 0, neurons);

    EXPECT_FALSE(result);

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, GetLayerAssignment_NotPartitioned) {
    // WHAT: Test getting assignment before partitioning
    // WHY:  Should return -1 if not partitioned
    // HOW:  Create context, query without partitioning

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    int assignment = multigpu_get_layer_assignment(ctx, 0);

    EXPECT_EQ(assignment, -1) << "Should return -1 if not partitioned";

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, RebalanceWork_Success) {
    // WHAT: Test work rebalancing
    // WHY:  Should handle imbalanced workloads
    // HOW:  Create context, partition, attempt rebalance

    multigpu_config_t config = multigpu_default_config();
    config.num_devices = 2;
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    uint32_t neurons[4] = {100, 200, 200, 100};
    multigpu_partition_network(ctx, 4, neurons);

    // Note: Rebalancing may or may not occur depending on utilization
    bool result = multigpu_rebalance_work(ctx);

    // Result can be true (rebalanced) or false (already balanced)
    // Just verify it doesn't crash
    EXPECT_TRUE(result == true || result == false);

    multigpu_context_destroy(ctx);
}

//=============================================================================
// Memory Management Tests
//=============================================================================

TEST_F(MultiGPUMockTest, Alloc_Success) {
    // WHAT: Test distributed memory allocation
    // WHY:  Core functionality for multi-GPU
    // HOW:  Allocate 1 MB, verify non-NULL

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    size_t total_size = 1024 * 1024;  // 1 MB
    void** device_ptrs = multigpu_alloc(ctx, total_size);

    ASSERT_NE(device_ptrs, nullptr) << "Allocation should succeed";

    // Verify each device got a pointer
    uint32_t num_devices = multigpu_get_device_count(ctx);
    for (uint32_t i = 0; i < num_devices; i++) {
        EXPECT_NE(device_ptrs[i], nullptr) << "Device " << i << " should have memory";
    }

    multigpu_free(ctx, device_ptrs);
    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, Alloc_ZeroSize) {
    // WHAT: Test zero-size allocation
    // WHY:  Guard clause validation
    // HOW:  Allocate 0 bytes, expect NULL

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    void** device_ptrs = multigpu_alloc(ctx, 0);

    EXPECT_EQ(device_ptrs, nullptr);

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, Free_NullPointers) {
    // WHAT: Test free with NULL pointers
    // WHY:  Guard clause validation (should not crash)
    // HOW:  Call free with NULL, verify no crash

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    EXPECT_NO_THROW(multigpu_free(ctx, nullptr));

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, Broadcast_Success) {
    // WHAT: Test broadcasting data to all GPUs
    // WHY:  Common operation for parameter sync
    // HOW:  Allocate, broadcast, verify success

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    size_t size = 1024;
    void** device_ptrs = multigpu_alloc(ctx, size * multigpu_get_device_count(ctx));
    ASSERT_NE(device_ptrs, nullptr);

    float host_data[256];
    for (int i = 0; i < 256; i++) {
        host_data[i] = (float)i;
    }

    bool result = multigpu_broadcast(ctx, host_data, device_ptrs, sizeof(host_data));

    EXPECT_TRUE(result);

    multigpu_free(ctx, device_ptrs);
    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, Gather_Success) {
    // WHAT: Test gathering data from all GPUs
    // WHY:  Common operation for result aggregation
    // HOW:  Allocate, gather, verify success

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    uint32_t num_devices = multigpu_get_device_count(ctx);
    size_t size_per_gpu = 256 * sizeof(float);
    void** device_ptrs = multigpu_alloc(ctx, size_per_gpu * num_devices);
    ASSERT_NE(device_ptrs, nullptr);

    float* host_data = (float*)malloc(size_per_gpu * num_devices);
    ASSERT_NE(host_data, nullptr);

    bool result = multigpu_gather(ctx, device_ptrs, host_data, size_per_gpu);

    EXPECT_TRUE(result);

    free(host_data);
    multigpu_free(ctx, device_ptrs);
    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, SyncDevices_SameDevice) {
    // WHAT: Test syncing same device (no-op)
    // WHY:  Guard clause validation
    // HOW:  Sync device 0 -> device 0, expect success

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    float data[10] = {1, 2, 3, 4, 5, 6, 7, 8, 9, 10};
    bool result = multigpu_sync_devices(ctx, 0, 0, data, sizeof(data));

    EXPECT_TRUE(result) << "Same device sync should succeed (no-op)";

    multigpu_context_destroy(ctx);
}

//=============================================================================
// Synchronization Tests
//=============================================================================

TEST_F(MultiGPUMockTest, Synchronize_Success) {
    // WHAT: Test synchronizing all GPUs
    // WHY:  Core functionality for consistency
    // HOW:  Create context, synchronize, verify success

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    bool result = multigpu_synchronize(ctx);

    EXPECT_TRUE(result);

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, Synchronize_NullContext) {
    // WHAT: Test synchronize with NULL context
    // WHY:  Guard clause validation
    // HOW:  Pass NULL, expect false

    bool result = multigpu_synchronize(nullptr);

    EXPECT_FALSE(result);
}

TEST_F(MultiGPUMockTest, IsIdle_AfterCreation) {
    // WHAT: Test idle check after creation
    // WHY:  New context should be idle
    // HOW:  Create context, check idle

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    bool is_idle = multigpu_is_idle(ctx);

    EXPECT_TRUE(is_idle) << "New context should be idle";

    multigpu_context_destroy(ctx);
}

//=============================================================================
// Performance Monitoring Tests
//=============================================================================

TEST_F(MultiGPUMockTest, GetPerformanceStats_Success) {
    // WHAT: Test getting aggregate performance stats
    // WHY:  Monitor multi-GPU efficiency
    // HOW:  Create context, query stats, verify

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    uint64_t total_ops;
    double total_time_ms;
    float avg_util;
    float imbalance;

    bool result = multigpu_get_performance_stats(ctx, &total_ops, &total_time_ms,
                                                 &avg_util, &imbalance);

    EXPECT_TRUE(result);
    EXPECT_GE(total_ops, 0u);
    EXPECT_GE(total_time_ms, 0.0);
    EXPECT_GE(avg_util, 0.0f);
    EXPECT_LE(avg_util, 1.0f);
    EXPECT_GE(imbalance, 0.0f);
    EXPECT_LE(imbalance, 1.0f);

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, GetDeviceStats_Success) {
    // WHAT: Test getting per-device stats
    // WHY:  Identify bottleneck GPUs
    // HOW:  Create context, query device 0 stats

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    uint64_t ops;
    double time_ms;
    float util;

    bool result = multigpu_get_device_stats(ctx, 0, &ops, &time_ms, &util);

    EXPECT_TRUE(result);
    EXPECT_GE(ops, 0u);
    EXPECT_GE(time_ms, 0.0);
    EXPECT_GE(util, 0.0f);
    EXPECT_LE(util, 1.0f);

    multigpu_context_destroy(ctx);
}

TEST_F(MultiGPUMockTest, GetDeviceStats_InvalidIndex) {
    // WHAT: Test getting stats for invalid device
    // WHY:  Guard clause validation
    // HOW:  Query out-of-range index, expect false

    multigpu_config_t config = multigpu_default_config();
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    uint64_t ops;
    double time_ms;
    float util;

    bool result = multigpu_get_device_stats(ctx, 999, &ops, &time_ms, &util);

    EXPECT_FALSE(result);

    multigpu_context_destroy(ctx);
}

//=============================================================================
// Configuration Tests
//=============================================================================

TEST_F(MultiGPUMockTest, DefaultConfig_ValuesValid) {
    // WHAT: Test default configuration has valid values
    // WHY:  Verify sensible defaults
    // HOW:  Get default config, check fields

    multigpu_config_t config = multigpu_default_config();

    EXPECT_EQ(config.num_devices, 0u) << "Should use all devices by default";
    EXPECT_TRUE(config.enable_peer_access);
    EXPECT_EQ(config.partition_strategy, MULTIGPU_PARTITION_HYBRID);
    EXPECT_EQ(config.loadbalance_strategy, MULTIGPU_LOADBALANCE_DYNAMIC);
    EXPECT_GT(config.streams_per_device, 0u);
    EXPECT_GT(config.loadbalance_interval, 0u);
    EXPECT_GT(config.imbalance_threshold, 0.0f);
}

TEST_F(MultiGPUMockTest, OptimalConfig_SmallNetwork) {
    // WHAT: Test optimal config for small network
    // WHY:  Should use appropriate settings
    // HOW:  Get optimal config for 10K neurons

    multigpu_config_t config = multigpu_get_optimal_config(10000, 10, 4);

    EXPECT_EQ(config.num_devices, 1u) << "Small network should use 1 GPU";
}

TEST_F(MultiGPUMockTest, OptimalConfig_LargeNetwork) {
    // WHAT: Test optimal config for large network
    // WHY:  Should use multiple GPUs
    // HOW:  Get optimal config for 5M neurons

    multigpu_config_t config = multigpu_get_optimal_config(5000000, 100, 8);

    EXPECT_GT(config.num_devices, 1u) << "Large network should use multiple GPUs";
    EXPECT_LE(config.num_devices, 8u) << "Should not exceed available";
}

//=============================================================================
// Integration Tests
//=============================================================================

TEST_F(MultiGPUMockTest, FullWorkflow_AllocPartitionSync) {
    // WHAT: Test complete multi-GPU workflow
    // WHY:  Verify all components work together
    // HOW:  Create context, partition, allocate, broadcast, sync, gather, free

    multigpu_config_t config = multigpu_default_config();
    config.num_devices = 2;

    // 1. Create context
    multigpu_context_t ctx = multigpu_context_create(&config);
    ASSERT_NE(ctx, nullptr);

    // 2. Partition network
    uint32_t neurons[4] = {100, 200, 200, 100};
    bool partition_result = multigpu_partition_network(ctx, 4, neurons);
    EXPECT_TRUE(partition_result);

    // 3. Allocate memory
    size_t total_size = 4096;
    void** device_ptrs = multigpu_alloc(ctx, total_size);
    ASSERT_NE(device_ptrs, nullptr);

    // 4. Broadcast data
    // Note: Each GPU gets total_size/num_devices bytes, so broadcast must fit in that
    size_t size_per_gpu = total_size / 2;  // 2 GPUs = 2048 bytes each
    float host_data[512];  // 512 floats × 4 bytes = 2048 bytes
    for (int i = 0; i < 512; i++) {
        host_data[i] = (float)i;
    }
    bool broadcast_result = multigpu_broadcast(ctx, host_data, device_ptrs, sizeof(host_data));
    EXPECT_TRUE(broadcast_result);

    // 5. Synchronize
    bool sync_result = multigpu_synchronize(ctx);
    EXPECT_TRUE(sync_result);

    // 6. Check idle
    bool is_idle = multigpu_is_idle(ctx);
    EXPECT_TRUE(is_idle);

    // 7. Gather results
    float* result_data = (float*)malloc(total_size);
    bool gather_result = multigpu_gather(ctx, device_ptrs, result_data, total_size / 2);
    EXPECT_TRUE(gather_result);
    free(result_data);

    // 8. Free memory
    multigpu_free(ctx, device_ptrs);

    // 9. Destroy context
    multigpu_context_destroy(ctx);
}

//=============================================================================
// Main
//=============================================================================

int main(int argc, char** argv) {
    ::testing::InitGoogleTest(&argc, argv);
    return RUN_ALL_TESTS();
}
