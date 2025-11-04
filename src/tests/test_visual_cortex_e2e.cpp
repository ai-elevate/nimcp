/**
 * @file test_visual_cortex_e2e.cpp
 * @brief End-to-End tests for visual cortex in realistic scenarios
 *
 * WHAT: Real-world visual perception scenarios
 * WHY:  Validate visual cortex works in practical applications
 * HOW:  Simulated robot vision, LLM grounding, active learning
 *
 * @author NIMCP Development Team
 * @date 2025
 * @version 2.6
 */

#include <gtest/gtest.h>
#include "include/perception/nimcp_visual_cortex.h"
#include "utils/memory/nimcp_memory.h"
#include <vector>
#include <cstring>
#include <cmath>
#include <algorithm>
#include <chrono>

//=============================================================================
// Test Fixtures
//=============================================================================

class VisualCortexE2ETest : public ::testing::Test {
protected:
    visual_cortex_t* cortex;

    void SetUp() override {
        visual_cortex_config_t config = {
            .input_width = 128,
            .input_height = 128,
            .num_v1_filters = 16,
            .feature_dim = 256,
            .enable_attention = true,
            .enable_memory = true
        };

        cortex = visual_cortex_create(&config);
        ASSERT_NE(cortex, nullptr);
    }

    void TearDown() override {
        if (cortex) {
            visual_cortex_destroy(cortex);
        }
    }

    // Helper: Create realistic image patterns
    std::vector<uint8_t> create_scene(const char* scene_type, uint32_t width, uint32_t height) {
        std::vector<uint8_t> image(width * height);

        if (strcmp(scene_type, "corridor") == 0) {
            // Simulate corridor: vertical edges on sides
            for (uint32_t y = 0; y < height; y++) {
                for (uint32_t x = 0; x < width; x++) {
                    if (x < 20 || x > width - 20) {
                        image[y * width + x] = 200;  // Walls
                    } else {
                        image[y * width + x] = 80;   // Floor
                    }
                }
            }
        } else if (strcmp(scene_type, "doorway") == 0) {
            // Doorway: vertical edges + horizontal top
            for (uint32_t y = 0; y < height; y++) {
                for (uint32_t x = 0; x < width; x++) {
                    if ((x > 40 && x < 50) || (x > width - 50 && x < width - 40) || (y > 30 && y < 35)) {
                        image[y * width + x] = 220;  // Door frame
                    } else {
                        image[y * width + x] = 60;
                    }
                }
            }
        } else if (strcmp(scene_type, "object_table") == 0) {
            // Table with object on top
            for (uint32_t y = 0; y < height; y++) {
                for (uint32_t x = 0; x < width; x++) {
                    if (y > height / 2 && y < height / 2 + 10) {
                        image[y * width + x] = 150;  // Table surface
                    } else if (x > width / 2 - 15 && x < width / 2 + 15 &&
                               y > height / 2 - 30 && y < height / 2) {
                        image[y * width + x] = 200;  // Object on table
                    } else {
                        image[y * width + x] = 40;
                    }
                }
            }
        } else if (strcmp(scene_type, "face_like") == 0) {
            // Face-like pattern (two eyes, mouth)
            std::fill(image.begin(), image.end(), 120);

            // Eyes
            uint32_t eye_y = height / 3;
            uint32_t left_eye_x = width / 3;
            uint32_t right_eye_x = 2 * width / 3;

            for (int dy = -5; dy <= 5; dy++) {
                for (int dx = -5; dx <= 5; dx++) {
                    if (dy * dy + dx * dx <= 25) {
                        image[(eye_y + dy) * width + (left_eye_x + dx)] = 30;
                        image[(eye_y + dy) * width + (right_eye_x + dx)] = 30;
                    }
                }
            }

            // Mouth
            uint32_t mouth_y = 2 * height / 3;
            for (uint32_t x = width / 3; x < 2 * width / 3; x++) {
                image[mouth_y * width + x] = 30;
            }
        } else {
            // Default: empty scene
            std::fill(image.begin(), image.end(), 100);
        }

        return image;
    }

    std::vector<float> extract_features(const std::vector<uint8_t>& image, uint32_t w, uint32_t h) {
        std::vector<float> features(256);
        visual_cortex_process(cortex, image.data(), w, h, 1, features.data());
        return features;
    }

    float compute_similarity(const std::vector<float>& f1, const std::vector<float>& f2) {
        float dot = 0.0f;
        for (size_t i = 0; i < f1.size(); i++) {
            dot += f1[i] * f2[i];
        }
        return dot;
    }
};

//=============================================================================
// E2E Test 1: Robot Navigation
//=============================================================================

TEST_F(VisualCortexE2ETest, RobotNavigationScenario) {
    // SCENARIO: Mobile robot navigating indoor environment
    // OBJECTIVE: Recognize corridors vs doorways for navigation decisions
    //
    // Robot workflow:
    // 1. Capture camera frame
    // 2. Visual cortex extracts features
    // 3. Classify scene type (corridor/doorway/room)
    // 4. Make navigation decision

    // 1. Build visual memory of different scene types during "training"
    auto corridor1 = create_scene("corridor", 128, 128);
    auto corridor2 = create_scene("corridor", 128, 128);
    auto doorway1 = create_scene("doorway", 128, 128);

    auto corridor_features = extract_features(corridor1, 128, 128);
    auto doorway_features = extract_features(doorway1, 128, 128);

    // Store scene templates
    visual_cortex_store_memory(cortex, corridor_features.data(), 0.8f);
    visual_cortex_store_memory(cortex, doorway_features.data(), 0.8f);

    // 2. During navigation: identify current scene
    auto current_scene = create_scene("corridor", 128, 128);
    auto current_features = extract_features(current_scene, 128, 128);

    // Recall similar scene
    visual_memory_t** recalled = nullptr;
    int num_recalled = 0;
    visual_cortex_recall_memory(cortex, current_features.data(), 1, &recalled, &num_recalled);

    ASSERT_GT(num_recalled, 0);
    ASSERT_NE(recalled, nullptr);

    // 3. Verify scene recognition
    // Corridor features should be most similar to stored corridor
    float sim_to_corridor = compute_similarity(current_features, corridor_features);
    float sim_to_doorway = compute_similarity(current_features, doorway_features);

    EXPECT_GT(sim_to_corridor, sim_to_doorway);

    // Robot would use this to make navigation decision:
    // If corridor → continue straight
    // If doorway → prepare to turn

    if (recalled) {
        nimcp_free(recalled);
    }
}

//=============================================================================
// E2E Test 2: Object Recognition for LLM Grounding
//=============================================================================

TEST_F(VisualCortexE2ETest, LLMGroundingScenario) {
    // SCENARIO: Language model needs to ground visual concepts
    // EXAMPLE: User says "What's on the table?" → LLM needs visual perception
    //
    // Integration flow:
    // Camera → Visual Cortex → Feature Vector → LLM Context
    // LLM uses visual features to ground language understanding

    // 1. Scene: table with object
    auto table_scene = create_scene("object_table", 128, 128);
    auto empty_scene = create_scene("corridor", 128, 128);

    auto table_features = extract_features(table_scene, 128, 128);
    auto empty_features = extract_features(empty_scene, 128, 128);

    // 2. Visual cortex detects presence of object structure
    float sim = compute_similarity(table_features, empty_features);
    EXPECT_LT(sim, 0.8f);  // Different scenes should have different features

    // 3. Store visual concept "table_with_object"
    visual_cortex_consolidate_memory(cortex, table_features.data(), 0.9f, "table_with_object");

    // 4. Later: LLM asks "Is there an object on the table?"
    // Visual cortex provides features → LLM grounds answer in vision
    auto query_scene = create_scene("object_table", 128, 128);
    auto query_features = extract_features(query_scene, 128, 128);

    visual_memory_t** recalled = nullptr;
    int num_recalled = 0;
    visual_cortex_recall_memory(cortex, query_features.data(), 1, &recalled, &num_recalled);

    ASSERT_GT(num_recalled, 0);

    // LLM would respond: "Yes, I see an object on the table" (grounded in visual features)

    if (recalled) {
        nimcp_free(recalled);
    }
}

//=============================================================================
// E2E Test 3: Curiosity-Driven Exploration
//=============================================================================

TEST_F(VisualCortexE2ETest, CuriosityDrivenExploration) {
    // SCENARIO: Robot explores environment driven by visual novelty
    // BEHAVIOR: High novelty → explore, Low novelty → move on
    //
    // Exploration loop:
    // 1. Look at scene
    // 2. Compute novelty
    // 3. If novel → investigate (store memory)
    // 4. If familiar → ignore and continue

    std::vector<const char*> exploration_sequence = {
        "corridor",      // Novel (first time)
        "corridor",      // Familiar (just saw it)
        "doorway",       // Novel (new pattern)
        "object_table",  // Novel (new pattern)
        "corridor",      // Familiar (seen before)
        "face_like"      // Novel (new pattern)
    };

    std::vector<float> novelty_timeline;
    std::vector<bool> exploration_decisions;

    for (const char* scene_type : exploration_sequence) {
        // 1. Perceive scene
        auto scene = create_scene(scene_type, 128, 128);
        auto features = extract_features(scene, 128, 128);

        // 2. Compute novelty
        float novelty = visual_cortex_compute_novelty(cortex, features.data());
        novelty_timeline.push_back(novelty);

        // 3. Curiosity-driven decision
        const float novelty_threshold = 0.5f;
        bool should_explore = (novelty > novelty_threshold);
        exploration_decisions.push_back(should_explore);

        // 4. If novel → store memory (we've explored it)
        if (should_explore) {
            visual_cortex_consolidate_memory(cortex, features.data(), novelty, scene_type);
        }
    }

    // Verify exploration behavior
    EXPECT_GT(novelty_timeline[0], 0.8f);  // First corridor: very novel
    EXPECT_LT(novelty_timeline[1], 0.5f);  // Second corridor: familiar
    EXPECT_GT(novelty_timeline[2], 0.5f);  // Doorway: novel
    EXPECT_GT(novelty_timeline[3], 0.5f);  // Table: novel
    EXPECT_LT(novelty_timeline[4], 0.5f);  // Third corridor: familiar

    // Verify correct exploration decisions
    EXPECT_TRUE(exploration_decisions[0]);   // Explore first corridor
    EXPECT_FALSE(exploration_decisions[1]);  // Skip second corridor
    EXPECT_TRUE(exploration_decisions[2]);   // Explore doorway
    EXPECT_TRUE(exploration_decisions[3]);   // Explore table
    EXPECT_FALSE(exploration_decisions[4]);  // Skip third corridor

    // Result: Robot efficiently explores novel areas, ignores familiar ones
}

//=============================================================================
// E2E Test 4: Active Visual Learning
//=============================================================================

TEST_F(VisualCortexE2ETest, ActiveVisualLearning) {
    // SCENARIO: Robot actively learns to recognize different object categories
    // APPROACH: Active learning - query most uncertain/novel examples
    //
    // Learning loop:
    // 1. See object
    // 2. Compute confidence (based on memory similarity)
    // 3. If uncertain → request label from human
    // 4. Store labeled example

    struct LabeledExample {
        std::vector<float> features;
        const char* label;
        float confidence;
    };

    std::vector<LabeledExample> training_set;

    // Training phase
    std::vector<const char*> object_sequence = {
        "corridor",
        "doorway",
        "corridor",
        "object_table",
        "doorway"
    };

    for (const char* obj : object_sequence) {
        auto scene = create_scene(obj, 128, 128);
        auto features = extract_features(scene, 128, 128);

        // Compute confidence (inverse novelty)
        float novelty = visual_cortex_compute_novelty(cortex, features.data());
        float confidence = 1.0f - novelty;

        LabeledExample example;
        example.features = features;
        example.label = obj;
        example.confidence = confidence;

        // Active learning decision
        const float confidence_threshold = 0.7f;
        if (confidence < confidence_threshold) {
            // Uncertain → request label and store
            visual_cortex_consolidate_memory(cortex, features.data(), 0.8f, obj);
            training_set.push_back(example);
        }
    }

    // Verify active learning behavior
    // Should have stored novel examples but skipped familiar ones
    visual_cortex_stats_t stats;
    visual_cortex_get_stats(cortex, &stats);

    EXPECT_GT(stats.memories_stored, 0);
    EXPECT_LT(stats.memories_stored, object_sequence.size());  // Not all stored (some were familiar)

    // Efficiency: Only labeled novel examples, saved human annotation time
}

//=============================================================================
// E2E Test 5: Multi-Modal Learning (Vision + Language)
//=============================================================================

TEST_F(VisualCortexE2ETest, MultiModalLearning) {
    // SCENARIO: Learn visual-language associations
    // EXAMPLE: "This is a door" (language) + doorway image (vision)
    //
    // Integration:
    // Visual Cortex (features) + LLM Embeddings → Joint representation
    // Enables: Visual question answering, Image captioning, Grounded reasoning

    struct MultiModalMemory {
        std::vector<float> visual_features;
        const char* language_description;
    };

    std::vector<MultiModalMemory> knowledge_base;

    // 1. Learning phase: Associate language with vision
    struct {
        const char* scene;
        const char* description;
    } associations[] = {
        {"corridor", "a long hallway with walls on both sides"},
        {"doorway", "an entrance with a door frame"},
        {"object_table", "a table with an object on top"},
        {"face_like", "a pattern resembling a face"}
    };

    for (const auto& assoc : associations) {
        auto scene = create_scene(assoc.scene, 128, 128);
        auto features = extract_features(scene, 128, 128);

        // Store multi-modal memory
        visual_cortex_consolidate_memory(cortex, features.data(), 0.9f, assoc.description);

        MultiModalMemory mm;
        mm.visual_features = features;
        mm.language_description = assoc.description;
        knowledge_base.push_back(mm);
    }

    // 2. Query phase: Visual question answering
    // Q: "What am I looking at?" (show doorway image)
    auto query_scene = create_scene("doorway", 128, 128);
    auto query_features = extract_features(query_scene, 128, 128);

    // Find most similar visual memory
    float max_sim = -1.0f;
    const char* answer = nullptr;

    for (const auto& mm : knowledge_base) {
        float sim = compute_similarity(query_features, mm.visual_features);
        if (sim > max_sim) {
            max_sim = sim;
            answer = mm.language_description;
        }
    }

    ASSERT_NE(answer, nullptr);
    EXPECT_STREQ(answer, "an entrance with a door frame");

    // Result: System can answer visual questions by grounding language in perception
}

//=============================================================================
// E2E Test 6: Visual Attention for Robotic Grasping
//=============================================================================

TEST_F(VisualCortexE2ETest, RoboticGraspingScenario) {
    // SCENARIO: Robot needs to grasp object on table
    // CHALLENGE: Locate salient object for grasp planning
    //
    // Workflow:
    // 1. Visual cortex computes attention map
    // 2. Find peak (most salient location)
    // 3. Guide robot arm to grasp location

    // Scene: table with object
    auto scene = create_scene("object_table", 128, 128);

    // Compute attention
    attention_map_t* attn = attention_map_create(128, 128);
    ASSERT_NE(attn, nullptr);

    bool success = visual_cortex_compute_attention(cortex, scene.data(), 128, 128, attn);
    EXPECT_TRUE(success);

    // Find grasp target (attention peak)
    uint32_t target_x, target_y;
    float salience;
    success = visual_cortex_get_attention_peak(attn, &target_x, &target_y, &salience);
    EXPECT_TRUE(success);

    // Peak should be near object location (center-top region)
    EXPECT_GT(salience, 0.0f);
    EXPECT_GT(target_x, 40);   // Object is in center
    EXPECT_LT(target_x, 88);
    EXPECT_LT(target_y, 64);   // Object is in top half

    // Robot would use (target_x, target_y) for grasp planning

    attention_map_destroy(attn);
}

//=============================================================================
// E2E Test 7: Long-Term Visual Memory
//=============================================================================

TEST_F(VisualCortexE2ETest, LongTermVisualMemory) {
    // SCENARIO: Robot patrols environment over many days
    // CHALLENGE: Build long-term visual memory, recognize familiar places
    //
    // Simulation: Multiple patrols through same environment

    // Day 1: First patrol (everything novel)
    std::vector<const char*> patrol_route = {
        "corridor", "doorway", "object_table", "corridor"
    };

    std::vector<std::vector<float>> day1_features;

    for (const char* location : patrol_route) {
        auto scene = create_scene(location, 128, 128);
        auto features = extract_features(scene, 128, 128);
        day1_features.push_back(features);

        // Store in long-term memory
        visual_cortex_consolidate_memory(cortex, features.data(), 0.8f, location);
    }

    // Day 2: Second patrol (should recognize familiar locations)
    std::vector<float> day2_novelty;

    for (size_t i = 0; i < patrol_route.size(); i++) {
        auto scene = create_scene(patrol_route[i], 128, 128);
        auto features = extract_features(scene, 128, 128);

        float novelty = visual_cortex_compute_novelty(cortex, features.data());
        day2_novelty.push_back(novelty);
    }

    // Verify: Day 2 patrol should show low novelty (familiar locations)
    for (float novelty : day2_novelty) {
        EXPECT_LT(novelty, 0.5f);  // All locations should be familiar
    }

    // Result: Robot has built long-term spatial memory
}

//=============================================================================
// E2E Test 8: Performance Under Load
//=============================================================================

TEST_F(VisualCortexE2ETest, PerformanceUnderLoad) {
    // SCENARIO: High-frequency video processing (30 FPS)
    // REQUIREMENT: Process frames fast enough for real-time operation
    //
    // Target: < 33ms per frame (for 30 FPS)

    const int num_frames = 100;
    auto scene = create_scene("corridor", 128, 128);
    std::vector<float> features(256);

    auto start = std::chrono::high_resolution_clock::now();

    for (int i = 0; i < num_frames; i++) {
        visual_cortex_process(cortex, scene.data(), 128, 128, 1, features.data());
    }

    auto end = std::chrono::high_resolution_clock::now();
    auto duration = std::chrono::duration_cast<std::chrono::milliseconds>(end - start).count();

    float avg_time_per_frame = (float)duration / num_frames;

    // For unoptimized implementation, be lenient
    EXPECT_LT(avg_time_per_frame, 100.0f);  // Should be under 100ms per frame

    // Future optimization target: < 33ms for 30 FPS real-time
}

// Note: main() provided by GTest::Main from CMakeLists.txt
