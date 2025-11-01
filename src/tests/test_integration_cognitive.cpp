//=============================================================================
// test_integration_cognitive.cpp - Multi-Module Cognitive Integration Tests
//=============================================================================
//
// COMPREHENSIVE INTEGRATION TESTS FOR COGNITIVE AND HIGH-LEVEL SYSTEMS
//
// This file tests the interaction and emergent behaviors of 3+ major modules
// working together to create higher-level cognitive functions.
//
// Test Categories:
// 1. Knowledge + Learning Integration (neural encoding, retrieval, consolidation)
// 2. Ethics + Decision Making (Golden Rule, policy filtering, harm prevention)
// 3. Curiosity + Exploration (gap detection, question generation, learning loops)
// 4. Brain + Consolidation (memory transfer, replay, forgetting)
// 5. Introspection + Salience (self-monitoring, attention, adaptive behavior)
// 6. Full System Integration (complete autonomous agent scenarios)
//
//=============================================================================

#include <gtest/gtest.h>
#include <chrono>
#include <string>
#include <thread>
#include <vector>
#include "test_helpers.h"

extern "C" {
#include "../include/nimcp_brain.h"
#include "../include/nimcp_consolidation.h"
#include "../include/nimcp_curiosity.h"
#include "../include/nimcp_ethics.h"
#include "../include/nimcp_introspection.h"
#include "../include/nimcp_knowledge.h"
#include "../include/nimcp_neuralnet.h"
#include "../include/nimcp_salience.h"
}

//=============================================================================
// Test Fixtures and Helpers
//=============================================================================

// Helper to create test features
std::vector<float> create_feature_vector(int size, float base_value = 0.5f)
{
    std::vector<float> features(size);
    for (int i = 0; i < size; i++) {
        features[i] = base_value + (i * 0.01f);
    }
    return features;
}

// Helper for timing operations
class ScopedTimer {
   public:
    ScopedTimer(const char* name) : name_(name), start_(std::chrono::high_resolution_clock::now())
    {
    }
    ~ScopedTimer()
    {
        auto end = std::chrono::high_resolution_clock::now();
        auto duration = std::chrono::duration_cast<std::chrono::milliseconds>(end - start_);
        printf("[TIMING] %s: %ldms\n", name_, duration.count());
    }

   private:
    const char* name_;
    std::chrono::time_point<std::chrono::high_resolution_clock> start_;
};

//=============================================================================
// 1. KNOWLEDGE + LEARNING INTEGRATION TESTS
//=============================================================================

// Test: Network learns pattern → Knowledge stored → Retrieved correctly
TEST(KnowledgeLearningIntegration, NetworkLearnStoreRetrieve)
{
    ScopedTimer timer("NetworkLearnStoreRetrieve");

    // Create brain for pattern learning
    brain_t brain =
        brain_create("knowledge_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 3);
    ASSERT_NE(brain, nullptr);

    // Create knowledge system
    knowledge_system_t knowledge = knowledge_system_create("test_learner");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Learn a simple concept through examples
    auto features1 = create_feature_vector(10, 0.8f);
    float loss1 = brain_learn_example(brain, features1.data(), 10, "cat", 0.9f);
    EXPECT_GE(loss1, 0.0f);

    auto features2 = create_feature_vector(10, 0.2f);
    float loss2 = brain_learn_example(brain, features2.data(), 10, "dog", 0.9f);
    EXPECT_GE(loss2, 0.0f);

    // Store learned concept in knowledge base
    bool learned = knowledge_learn_from_text(knowledge, "A cat is a small furry animal that meows",
                                             KNOWLEDGE_DOMAIN_GENERAL);
    EXPECT_GT(learned, 0);

    // Retrieve knowledge
    knowledge_item_t item;
    bool retrieved = knowledge_retrieve(knowledge, "cat", &item);
    EXPECT_TRUE(retrieved);
    EXPECT_STREQ(item.concept, "cat");
    EXPECT_GT(item.confidence, 0.0f);

    // Verify brain can recognize the pattern
    brain_decision_t* decision = brain_decide(brain, features1.data(), 10);
    ASSERT_NE(decision, nullptr);
    EXPECT_STREQ(decision->label, "cat");
    EXPECT_GT(decision->confidence, 0.5f);

    printf("[EMERGENT] Neural pattern and symbolic knowledge both recognize 'cat'\n");

    brain_free_decision(decision);
    knowledge_system_destroy(knowledge);
    brain_destroy(brain);
}

// Test: Narrative learning with neural encoding
TEST(KnowledgeLearningIntegration, NarrativeLearningNeuralEncoding)
{
    ScopedTimer timer("NarrativeLearningNeuralEncoding");

    brain_t brain =
        brain_create("narrative_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_PATTERN_MATCHING, 20, 1);
    ASSERT_NE(brain, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("storyteller");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Learn from a simple narrative
    narrative_knowledge_t story;
    memset(&story, 0, sizeof(story));
    strncpy(story.title, "The Helpful Fox", sizeof(story.title) - 1);
    strncpy(story.author, "Aesop", sizeof(story.author) - 1);
    strncpy(story.summary, "A fox helps a trapped bird, showing kindness to others",
            sizeof(story.summary) - 1);

    const char* themes[] = {"kindness", "helping", "compassion"};
    story.themes = const_cast<char**>(themes);
    story.num_themes = 3;

    const char* lessons[] = {"Help others in need"};
    story.moral_lessons = const_cast<char**>(lessons);
    story.num_lessons = 1;
    story.primary_domain = KNOWLEDGE_DOMAIN_ETHICS;

    bool learned = knowledge_learn_from_story(knowledge, &story);
    EXPECT_TRUE(learned);

    // Encode narrative themes as neural patterns
    auto kindness_features = create_feature_vector(20, 0.7f);
    brain_learn_example(brain, kindness_features.data(), 20, "kindness", 0.95f);

    // Verify story knowledge was stored
    knowledge_item_t item;
    bool retrieved = knowledge_retrieve(knowledge, "kindness", &item);
    EXPECT_TRUE(retrieved || item.concept[0] != '\0');  // May store differently

    printf("[EMERGENT] Story themes encoded in both symbolic and neural representations\n");

    knowledge_system_destroy(knowledge);
    brain_destroy(brain);
}

// Test: Aesthetic knowledge with emotional associations
TEST(KnowledgeLearningIntegration, AestheticEmotionalAssociation)
{
    ScopedTimer timer("AestheticEmotionalAssociation");

    brain_t brain = brain_create("aesthetic_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_REGRESSION, 15, 5);
    ASSERT_NE(brain, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("art_critic");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Learn aesthetic appreciation
    aesthetic_knowledge_t artwork;
    memset(&artwork, 0, sizeof(artwork));
    strncpy(artwork.work_title, "Starry Night", sizeof(artwork.work_title) - 1);
    strncpy(artwork.creator, "Van Gogh", sizeof(artwork.creator) - 1);
    strncpy(artwork.medium, "painting", sizeof(artwork.medium) - 1);
    strncpy(artwork.emotional_impact, "Peaceful, contemplative, wonder",
            sizeof(artwork.emotional_impact) - 1);

    const char* qualities[] = {"beautiful", "swirling", "dreamy"};
    artwork.aesthetic_qualities = const_cast<char**>(qualities);
    artwork.num_qualities = 3;

    bool learned = knowledge_learn_from_art(knowledge, &artwork);
    EXPECT_TRUE(learned);

    // Neural encoding of emotional response
    auto peaceful_features = create_feature_vector(15, 0.3f);
    brain_learn_example(brain, peaceful_features.data(), 15, "peaceful", 0.85f);

    printf("[EMERGENT] Aesthetic experience bridges symbolic knowledge and emotional neural "
           "response\n");

    knowledge_system_destroy(knowledge);
    brain_destroy(brain);
}

// Test: Knowledge consolidation over time
TEST(KnowledgeLearningIntegration, KnowledgeConsolidationOverTime)
{
    ScopedTimer timer("KnowledgeConsolidationOverTime");

    brain_t brain =
        brain_create("consolidation_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 5);
    ASSERT_NE(brain, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("consolidator");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Learn multiple facts, then consolidate

    // Initial learning phase
    for (int i = 0; i < 10; i++) {
        auto features = create_feature_vector(10, 0.1f * i);
        char label[32];
        snprintf(label, sizeof(label), "concept_%d", i);
        brain_learn_example(brain, features.data(), 10, label, 0.8f);

        char text[128];
        snprintf(text, sizeof(text), "Concept %d is about topic %d", i, i);
        knowledge_learn_from_text(knowledge, text, KNOWLEDGE_DOMAIN_GENERAL);
    }

    // Get stats before consolidation
    brain_stats_t stats_before;
    ASSERT_TRUE(brain_get_stats(brain, &stats_before));

    // Consolidate neural memories
    consolidation_config_t config = consolidation_default_config();
    config.consolidation_cycles = 5;
    bool consolidated = brain_consolidate_memory(brain, &config);
    EXPECT_TRUE(consolidated);

    // Get stats after consolidation
    brain_stats_t stats_after;
    ASSERT_TRUE(brain_get_stats(brain, &stats_after));

    // Consolidation should prune some connections
    EXPECT_LE(stats_after.num_active_synapses, stats_before.num_active_synapses);

    printf("[EMERGENT] Consolidation strengthened important patterns, pruned weak ones\n");
    printf("  Synapses before: %u, after: %u (pruned: %u)\n", stats_before.num_active_synapses,
           stats_after.num_active_synapses,
           stats_before.num_active_synapses - stats_after.num_active_synapses);

    knowledge_system_destroy(knowledge);
    brain_destroy(brain);
}

// Test: Cross-domain knowledge transfer
TEST(KnowledgeLearningIntegration, CrossDomainKnowledgeTransfer)
{
    ScopedTimer timer("CrossDomainKnowledgeTransfer");

    brain_t brain =
        brain_create("transfer_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 12, 4);
    ASSERT_NE(brain, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("polymath");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Learn in one domain, apply to another

    // Learn mathematics pattern
    knowledge_learn_from_text(knowledge, "Patterns repeat in predictable ways",
                              KNOWLEDGE_DOMAIN_MATHEMATICS);

    // Learn art pattern
    knowledge_learn_from_text(knowledge, "Music has repeating rhythmic patterns",
                              KNOWLEDGE_DOMAIN_ART);

    // Transfer learning: Apply math pattern understanding to music
    char application[256];
    bool transferred = knowledge_transfer_learning(
        knowledge, KNOWLEDGE_DOMAIN_MATHEMATICS, KNOWLEDGE_DOMAIN_ART,
        "analyzing musical composition", application, sizeof(application));

    EXPECT_TRUE(transferred || application[0] != '\0');

    printf("[EMERGENT] Knowledge transferred across domains (Math → Art)\n");
    if (application[0]) {
        printf("  Application: %s\n", application);
    }

    knowledge_system_destroy(knowledge);
    brain_destroy(brain);
}

// Test: Learning with reinforcement
TEST(KnowledgeLearningIntegration, ReinforcedLearning)
{
    ScopedTimer timer("ReinforcedLearning");

    brain_t brain =
        brain_create("reinforced_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 8, 2);
    ASSERT_NE(brain, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("reinforced_learner");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Repeated exposure strengthens learning

    const char* concept = "important_fact";

    // First exposure
    knowledge_learn_from_text(knowledge, "Water is essential for life", KNOWLEDGE_DOMAIN_SCIENCE);

    // Reinforce multiple times
    for (int i = 0; i < 5; i++) {
        knowledge_reinforce(knowledge, "water", "Humans need water to survive");
    }

    // Neural reinforcement
    auto water_features = create_feature_vector(8, 0.6f);
    for (int i = 0; i < 5; i++) {
        brain_learn_example(brain, water_features.data(), 8, "essential", 0.95f);
    }

    // Verify strong learning
    brain_decision_t* decision = brain_decide(brain, water_features.data(), 8);
    ASSERT_NE(decision, nullptr);
    EXPECT_GT(decision->confidence, 0.7f);  // Should be highly confident after reinforcement

    printf("[EMERGENT] Reinforcement increased confidence: %.2f\n", decision->confidence);

    brain_free_decision(decision);
    knowledge_system_destroy(knowledge);
    brain_destroy(brain);
}

//=============================================================================
// 2. ETHICS + DECISION MAKING INTEGRATION TESTS
//=============================================================================

// Test: Network proposes action → Ethics evaluates → Decision made
TEST(EthicsDecisionIntegration, NetworkProposalEthicsEvaluation)
{
    ScopedTimer timer("NetworkProposalEthicsEvaluation");

    brain_t brain =
        brain_create("ethical_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 3);
    ASSERT_NE(brain, nullptr);

    // Create ethics engine
    ethics_config_t ethics_config;
    memset(&ethics_config, 0, sizeof(ethics_config));
    ethics_config.action_feature_size = 10;
    ethics_config.max_agents = 5;
    ethics_config.golden_rule_threshold = 0.0f;
    ethics_config.empathy_weight = 0.7f;
    ethics_config.enable_learning = true;

    ethics_engine_t ethics = ethics_engine_create(&ethics_config);
    ASSERT_NE(ethics, nullptr);

    // SCENARIO: Brain proposes action, ethics evaluates

    // Brain learns to propose helpful actions
    auto helpful_features = create_feature_vector(10, 0.8f);
    brain_learn_example(brain, helpful_features.data(), 10, "help", 0.9f);

    // Brain learns harmful actions are bad
    auto harmful_features = create_feature_vector(10, 0.2f);
    brain_learn_example(brain, harmful_features.data(), 10, "harm", 0.1f);

    // Propose a helpful action
    action_context_t helpful_action;
    memset(&helpful_action, 0, sizeof(helpful_action));
    helpful_action.features = helpful_features.data();
    helpful_action.num_features = 10;
    helpful_action.predicted_harm = 0.1f;

    agent_id_t affected_agents[] = {1, 2};
    helpful_action.affected_agents = affected_agents;
    helpful_action.num_affected_agents = 2;

    ethics_evaluation_t eval_helpful = ethics_engine_evaluate_action(ethics, &helpful_action);
    EXPECT_TRUE(eval_helpful.allowed);
    EXPECT_GT(eval_helpful.confidence, 0.5f);
    EXPECT_GE(eval_helpful.golden_rule_score, 0.0f);  // Positive or neutral

    // Propose a harmful action
    action_context_t harmful_action;
    memset(&harmful_action, 0, sizeof(harmful_action));
    harmful_action.features = harmful_features.data();
    harmful_action.num_features = 10;
    harmful_action.predicted_harm = 0.9f;
    harmful_action.affected_agents = affected_agents;
    harmful_action.num_affected_agents = 2;

    ethics_evaluation_t eval_harmful = ethics_engine_evaluate_action(ethics, &harmful_action);
    EXPECT_FALSE(eval_harmful.allowed);  // Should block harmful action

    printf("[EMERGENT] Ethics engine correctly evaluated helpful vs harmful actions\n");
    printf("  Helpful: allowed=%d, score=%.2f\n", eval_helpful.allowed,
           eval_helpful.golden_rule_score);
    printf("  Harmful: allowed=%d, score=%.2f\n", eval_harmful.allowed,
           eval_harmful.golden_rule_score);

    ethics_engine_destroy(ethics);
    brain_destroy(brain);
}

// Test: Golden Rule application in context
TEST(EthicsDecisionIntegration, GoldenRuleApplication)
{
    ScopedTimer timer("GoldenRuleApplication");

    ethics_config_t config;
    memset(&config, 0, sizeof(config));
    config.action_feature_size = 8;
    config.max_agents = 3;
    config.golden_rule_threshold = 0.0f;
    config.empathy_weight = 0.8f;

    ethics_engine_t ethics = ethics_engine_create(&config);
    ASSERT_NE(ethics, nullptr);

    // SCENARIO: "Do unto others as you would have them do unto you"

    // Action: Sharing resources (positive)
    auto sharing_features = create_feature_vector(8, 0.7f);
    action_context_t sharing_action;
    memset(&sharing_action, 0, sizeof(sharing_action));
    sharing_action.features = sharing_features.data();
    sharing_action.num_features = 8;
    sharing_action.predicted_harm = 0.0f;

    agent_id_t agents[] = {1, 2, 3};
    sharing_action.affected_agents = agents;
    sharing_action.num_affected_agents = 3;

    ethics_evaluation_t eval = ethics_engine_evaluate_action(ethics, &sharing_action);
    EXPECT_TRUE(eval.allowed);
    EXPECT_GE(eval.golden_rule_score, 0.0f);

    printf("[EMERGENT] Golden Rule approved prosocial behavior: %.2f\n", eval.golden_rule_score);

    ethics_engine_destroy(ethics);
}

// Test: Policy-based filtering
TEST(EthicsDecisionIntegration, PolicyBasedFiltering)
{
    ScopedTimer timer("PolicyBasedFiltering");

    ethics_config_t config;
    memset(&config, 0, sizeof(config));
    config.action_feature_size = 10;
    config.max_agents = 5;

    ethics_engine_t ethics = ethics_engine_create(&config);
    ASSERT_NE(ethics, nullptr);

    // Add a policy: Block deceptive actions
    ethics_policy_t policy;
    memset(&policy, 0, sizeof(policy));
    policy.policy_id = 1;
    strncpy(policy.name, "no_deception", sizeof(policy.name) - 1);
    strncpy(policy.description, "Block all deceptive actions", sizeof(policy.description) - 1);
    policy.violation_type = ETHICS_VIOLATION_DECEPTION;
    policy.action = ETHICS_ACTION_BLOCK;
    policy.enabled = true;
    policy.confidence_required = 0.7f;

    bool added = ethics_engine_add_policy(ethics, &policy);
    EXPECT_TRUE(added);

    // Try a deceptive action
    auto deceptive_features = create_feature_vector(10, 0.3f);
    action_context_t deceptive_action;
    memset(&deceptive_action, 0, sizeof(deceptive_action));
    deceptive_action.features = deceptive_features.data();
    deceptive_action.num_features = 10;
    deceptive_action.deception_level = 0.9f;  // High deception

    agent_id_t agents[] = {1};
    deceptive_action.affected_agents = agents;
    deceptive_action.num_affected_agents = 1;

    ethics_evaluation_t eval = ethics_engine_evaluate_action(ethics, &deceptive_action);
    EXPECT_EQ(eval.recommended_action, ETHICS_ACTION_BLOCK);

    printf("[EMERGENT] Policy system blocked deceptive action\n");

    ethics_engine_destroy(ethics);
}

// Test: Ethical constraint learning
TEST(EthicsDecisionIntegration, EthicalConstraintLearning)
{
    ScopedTimer timer("EthicalConstraintLearning");

    ethics_config_t config;
    memset(&config, 0, sizeof(config));
    config.action_feature_size = 10;
    config.max_agents = 3;
    config.enable_learning = true;

    ethics_engine_t ethics = ethics_engine_create(&config);
    ASSERT_NE(ethics, nullptr);

    brain_t brain =
        brain_create("ethics_learner", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 2);
    ASSERT_NE(brain, nullptr);

    // SCENARIO: Learn ethical constraints from outcomes

    // Action that seemed okay but had bad outcome
    auto action_features = create_feature_vector(10, 0.5f);
    action_context_t action;
    memset(&action, 0, sizeof(action));
    action.features = action_features.data();
    action.num_features = 10;
    action.predicted_harm = 0.2f;

    agent_id_t agents[] = {1};
    action.affected_agents = agents;
    action.num_affected_agents = 1;

    // Outcome was actually harmful
    action_outcome_t outcome;
    memset(&outcome, 0, sizeof(outcome));
    outcome.affected_agent = 1;
    outcome.actual_harm = 0.8f;  // Much worse than predicted!
    outcome.emotional_impact = -0.7f;

    // Learn from this mistake
    bool learned = ethics_learn_from_outcome(ethics, &action, &outcome);
    EXPECT_TRUE(learned);

    // Train brain to avoid similar actions
    brain_learn_example(brain, action_features.data(), 10, "avoid", 0.9f);

    printf("[EMERGENT] System learned to avoid actions with unexpectedly harmful outcomes\n");

    brain_destroy(brain);
    ethics_engine_destroy(ethics);
}

// Test: Harm prevention in multi-agent scenario
TEST(EthicsDecisionIntegration, MultiAgentHarmPrevention)
{
    ScopedTimer timer("MultiAgentHarmPrevention");

    ethics_config_t config;
    memset(&config, 0, sizeof(config));
    config.action_feature_size = 12;
    config.max_agents = 10;
    config.golden_rule_threshold = 0.0f;
    config.empathy_weight = 0.9f;  // High empathy

    ethics_engine_t ethics = ethics_engine_create(&config);
    ASSERT_NE(ethics, nullptr);

    // SCENARIO: Action affects multiple agents, some positively, some negatively

    auto mixed_features = create_feature_vector(12, 0.5f);
    action_context_t mixed_action;
    memset(&mixed_action, 0, sizeof(mixed_action));
    mixed_action.features = mixed_features.data();
    mixed_action.num_features = 12;

    // Affects 5 agents
    agent_id_t agents[] = {1, 2, 3, 4, 5};
    mixed_action.affected_agents = agents;
    mixed_action.num_affected_agents = 5;
    mixed_action.predicted_harm = 0.6f;  // Moderate predicted harm

    ethics_evaluation_t eval = ethics_engine_evaluate_action(ethics, &mixed_action);

    // With high empathy and moderate harm, should be cautious
    printf("[EMERGENT] Multi-agent evaluation with empathy weight %.2f\n", config.empathy_weight);
    printf("  Allowed: %d, Confidence: %.2f, Golden Rule: %.2f\n", eval.allowed, eval.confidence,
           eval.golden_rule_score);

    ethics_engine_destroy(ethics);
}

//=============================================================================
// 3. CURIOSITY + EXPLORATION INTEGRATION TESTS
//=============================================================================

// Test: Gap detection → Question generation → Learning
TEST(CuriosityExplorationIntegration, GapDetectionQuestionLearning)
{
    ScopedTimer timer("GapDetectionQuestionLearning");

    curiosity_engine_t curiosity = curiosity_engine_create("explorer");
    ASSERT_NE(curiosity, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("curious_learner");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Encounter unknown concept → Generate questions → Learn answers

    // Detect knowledge gap about "photosynthesis"
    knowledge_gap_t gap = curiosity_detect_knowledge_gap(curiosity, "photosynthesis");
    EXPECT_GT(gap.gap_size, 0.5f);  // Should be a large gap for unknown concept
    EXPECT_GT(gap.curiosity_intensity, 0.0f);

    // Generate questions about the gap
    generated_question_t questions[10];
    uint32_t num_questions = curiosity_generate_questions(curiosity, &gap, questions, 10);
    EXPECT_GT(num_questions, 0);

    printf("[EMERGENT] Curiosity generated %u questions about unknown concept\n", num_questions);

    // Learn from answers
    for (uint32_t i = 0; i < std::min(num_questions, 3u); i++) {
        curiosity_learn_answer(curiosity, questions[i].question,
                               "Plants use sunlight to make food");
    }

    // Check if curiosity about this topic decreased
    float familiarity = curiosity_check_familiarity(curiosity, "photosynthesis");
    EXPECT_GT(familiarity, 0.0f);  // Should be more familiar now

    printf("  Familiarity after learning: %.2f\n", familiarity);

    knowledge_system_destroy(knowledge);
    curiosity_engine_destroy(curiosity);
}

// Test: Novelty-driven exploration
TEST(CuriosityExplorationIntegration, NoveltyDrivenExploration)
{
    ScopedTimer timer("NoveltyDrivenExploration");

    curiosity_engine_t curiosity = curiosity_engine_create("explorer");
    ASSERT_NE(curiosity, nullptr);

    brain_t brain =
        brain_create("novelty_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_PATTERN_MATCHING, 15, 1);
    ASSERT_NE(brain, nullptr);

    // Set high intrinsic curiosity (like an infant)
    curiosity_set_baseline(curiosity, 0.85f);

    // SCENARIO: Explore new patterns driven by novelty

    // Familiar pattern (seen before)
    auto familiar_features = create_feature_vector(15, 0.5f);
    brain_learn_example(brain, familiar_features.data(), 15, "familiar", 1.0f);

    // Novel pattern (never seen)
    auto novel_features = create_feature_vector(15, 0.9f);

    // Check motivation for familiar vs novel
    motivation_state_t motivation_familiar = curiosity_assess_motivation(curiosity, "familiar");
    motivation_state_t motivation_novel = curiosity_assess_motivation(curiosity, "novel");

    // Novel should have higher intrinsic motivation
    EXPECT_GT(motivation_novel.intrinsic_curiosity, motivation_familiar.intrinsic_curiosity);

    printf("[EMERGENT] Novelty drives higher exploration motivation\n");
    printf("  Familiar: %.2f, Novel: %.2f\n", motivation_familiar.intrinsic_curiosity,
           motivation_novel.intrinsic_curiosity);

    brain_destroy(brain);
    curiosity_engine_destroy(curiosity);
}

// Test: Intrinsic motivation for learning
TEST(CuriosityExplorationIntegration, IntrinsicMotivation)
{
    ScopedTimer timer("IntrinsicMotivation");

    curiosity_engine_t curiosity = curiosity_engine_create("motivated_learner");
    ASSERT_NE(curiosity, nullptr);

    // SCENARIO: Track learning driven by pure curiosity

    curiosity_set_baseline(curiosity, 0.9f);  // Very curious!

    float drive = curiosity_get_drive(curiosity);
    EXPECT_GT(drive, 0.8f);  // High intrinsic drive

    // Learn from experience driven by curiosity
    auto sensory_data = create_feature_vector(10, 0.6f);
    bool learned = curiosity_learn_experience(curiosity, "Observed interesting phenomenon",
                                              sensory_data.data(), 10);
    EXPECT_TRUE(learned);

    // Check learning progress
    learning_progress_t progress;
    bool got_progress = curiosity_get_progress(curiosity, &progress);
    EXPECT_TRUE(got_progress);
    EXPECT_GT(progress.total_experiences, 0);

    printf("[EMERGENT] Intrinsic motivation drove experiential learning\n");
    printf("  Drive: %.2f, Experiences: %lu\n", drive, progress.total_experiences);

    curiosity_engine_destroy(curiosity);
}

// Test: Curiosity-guided knowledge acquisition
TEST(CuriosityExplorationIntegration, CuriosityGuidedAcquisition)
{
    ScopedTimer timer("CuriosityGuidedAcquisition");

    curiosity_engine_t curiosity = curiosity_engine_create("guided_learner");
    ASSERT_NE(curiosity, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("knowledge_seeker");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Curiosity guides what knowledge to acquire next

    // Learn some initial concepts
    knowledge_learn_from_text(knowledge, "Birds can fly", KNOWLEDGE_DOMAIN_SCIENCE);
    knowledge_learn_from_text(knowledge, "Fish swim in water", KNOWLEDGE_DOMAIN_SCIENCE);

    // Curiosity detects gaps
    knowledge_gap_t gap = curiosity_detect_knowledge_gap(curiosity, "mammals");

    // Use gap to guide learning
    if (gap.gap_size > 0.5f) {
        knowledge_learn_from_text(knowledge,
                                  "Mammals are warm-blooded animals that nurse their young",
                                  KNOWLEDGE_DOMAIN_SCIENCE);
    }

    // Assess domain coverage
    float science_coverage = curiosity_get_domain_coverage(curiosity, "science");
    EXPECT_GE(science_coverage, 0.0f);

    printf("[EMERGENT] Curiosity-guided learning filled knowledge gaps\n");
    printf("  Science domain coverage: %.2f%%\n", science_coverage * 100.0f);

    knowledge_system_destroy(knowledge);
    curiosity_engine_destroy(curiosity);
}

//=============================================================================
// 4. BRAIN + CONSOLIDATION INTEGRATION TESTS
//=============================================================================

// Test: Short-term → Long-term memory transfer
TEST(BrainConsolidationIntegration, ShortToLongTermTransfer)
{
    ScopedTimer timer("ShortToLongTermTransfer");

    brain_t brain =
        brain_create("memory_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 3);
    ASSERT_NE(brain, nullptr);

    // SCENARIO: Learn many items in "working memory", consolidate to "long-term"

    // Rapid learning phase (like working memory)
    for (int i = 0; i < 20; i++) {
        auto features = create_feature_vector(10, 0.05f * i);
        char label[16];
        snprintf(label, sizeof(label), "item_%d", i);
        brain_learn_example(brain, features.data(), 10, label, 0.8f);
    }

    brain_stats_t stats_before;
    ASSERT_TRUE(brain_get_stats(brain, &stats_before));

    // Sleep-like consolidation
    consolidation_config_t config = consolidation_default_config();
    config.consolidation_cycles = 10;
    config.enable_replay = true;
    config.replay_count = 100;
    config.enable_pruning = true;

    bool consolidated = brain_consolidate_memory(brain, &config);
    EXPECT_TRUE(consolidated);

    brain_stats_t stats_after;
    ASSERT_TRUE(brain_get_stats(brain, &stats_after));

    // Test recall after consolidation
    auto test_features = create_feature_vector(10, 0.25f);  // Mid-range
    brain_decision_t* decision = brain_decide(brain, test_features.data(), 10);
    ASSERT_NE(decision, nullptr);
    EXPECT_GT(decision->confidence, 0.0f);  // Should still remember

    printf("[EMERGENT] Consolidation transferred memories from short to long term\n");
    printf("  Confidence after consolidation: %.2f\n", decision->confidence);

    brain_free_decision(decision);
    brain_destroy(brain);
}

// Test: Sleep-like consolidation process
TEST(BrainConsolidationIntegration, SleepLikeConsolidation)
{
    ScopedTimer timer("SleepLikeConsolidation");

    brain_t brain =
        brain_create("sleeping_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_PATTERN_MATCHING, 12, 1);
    ASSERT_NE(brain, nullptr);

    // Learn during "wake"
    for (int i = 0; i < 15; i++) {
        auto features = create_feature_vector(12, 0.1f * i);
        brain_learn_example(brain, features.data(), 12, (i % 2 == 0) ? "important" : "trivial",
                            (i % 2 == 0) ? 0.95f : 0.3f);
    }

    // "Sleep" - background consolidation
    consolidation_config_t config = consolidation_default_config();
    config.prioritize_novel = true;
    config.prune_weak = true;
    config.weakness_threshold = 0.2f;

    consolidation_handle_t handle =
        brain_start_background_consolidation(brain, 1, &config);  // Every 1 second
    ASSERT_NE(handle, nullptr);

    // Let it consolidate
    std::this_thread::sleep_for(std::chrono::seconds(2));

    // Check if consolidation happened
    consolidation_stats_t stats;
    bool got_stats = consolidation_get_stats(handle, &stats);
    EXPECT_TRUE(got_stats);

    if (got_stats && stats.total_consolidations > 0) {
        printf("[EMERGENT] Background 'sleep' consolidation occurred %lu times\n",
               stats.total_consolidations);
        printf("  Patterns replayed: %lu, Connections pruned: %lu\n", stats.patterns_replayed,
               stats.connections_pruned);
    }

    brain_stop_background_consolidation(handle);
    brain_destroy(brain);
}

// Test: Memory replay and strengthening
TEST(BrainConsolidationIntegration, MemoryReplayStrengthening)
{
    ScopedTimer timer("MemoryReplayStrengthening");

    brain_t brain =
        brain_create("replay_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 2);
    ASSERT_NE(brain, nullptr);

    // Learn important pattern
    auto important_features = create_feature_vector(10, 0.8f);
    for (int i = 0; i < 3; i++) {
        brain_learn_example(brain, important_features.data(), 10, "critical", 0.95f);
    }

    // Test before replay
    brain_decision_t* decision_before = brain_decide(brain, important_features.data(), 10);
    ASSERT_NE(decision_before, nullptr);
    float confidence_before = decision_before->confidence;
    brain_free_decision(decision_before);

    // Explicit pattern replay (like dream rehearsal)
    bool replayed = brain_replay_pattern(brain, "critical", 10, 0.5f);
    EXPECT_TRUE(replayed);

    // Test after replay
    brain_decision_t* decision_after = brain_decide(brain, important_features.data(), 10);
    ASSERT_NE(decision_after, nullptr);
    float confidence_after = decision_after->confidence;
    brain_free_decision(decision_after);

    printf("[EMERGENT] Memory replay strengthened pattern\n");
    printf("  Confidence before: %.2f, after: %.2f\n", confidence_before, confidence_after);

    brain_destroy(brain);
}

// Test: Forgetting and memory decay
TEST(BrainConsolidationIntegration, ForgettingAndDecay)
{
    ScopedTimer timer("ForgettingAndDecay");

    brain_t brain =
        brain_create("forgetting_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 8, 3);
    ASSERT_NE(brain, nullptr);

    // Learn weak memory
    auto weak_features = create_feature_vector(8, 0.4f);
    brain_learn_example(brain, weak_features.data(), 8, "weak_memory", 0.3f);

    // Learn strong memory
    auto strong_features = create_feature_vector(8, 0.7f);
    for (int i = 0; i < 5; i++) {
        brain_learn_example(brain, strong_features.data(), 8, "strong_memory", 0.95f);
    }

    // Aggressive pruning (forgetting weak memories)
    uint32_t pruned = brain_prune_weak_connections(brain, 0.3f);
    EXPECT_GT(pruned, 0);

    // Strong memory should remain
    brain_decision_t* strong_decision = brain_decide(brain, strong_features.data(), 8);
    ASSERT_NE(strong_decision, nullptr);
    EXPECT_GT(strong_decision->confidence, 0.5f);

    printf("[EMERGENT] Forgetting pruned %u weak connections\n", pruned);
    printf("  Strong memory preserved with confidence: %.2f\n", strong_decision->confidence);

    brain_free_decision(strong_decision);
    brain_destroy(brain);
}

//=============================================================================
// 5. INTROSPECTION + SALIENCE INTEGRATION TESTS
//=============================================================================

// Test: Network state → Introspection → Salience scoring
TEST(IntrospectionSalienceIntegration, StateAnalysisSalienceScoring)
{
    ScopedTimer timer("StateAnalysisSalienceScoring");

    brain_t brain =
        brain_create("introspective_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 2);
    ASSERT_NE(brain, nullptr);

    // Train on some patterns
    auto normal_features = create_feature_vector(10, 0.5f);
    brain_learn_example(brain, normal_features.data(), 10, "normal", 0.8f);

    // Create introspection context
    introspection_config_t intro_config = introspection_default_config();
    introspection_context_t intro_ctx = introspection_context_create(brain, &intro_config);
    ASSERT_NE(intro_ctx, nullptr);

    // Create salience evaluator
    salience_config_t sal_config = salience_default_config();
    salience_evaluator_t sal_eval = salience_evaluator_create(brain, &sal_config);
    ASSERT_NE(sal_eval, nullptr);

    // SCENARIO: Analyze internal state, compute salience for inputs

    // Get internal state
    brain_state_t state = brain_get_internal_state(intro_ctx, STATE_STRATEGY_BALANCED);
    EXPECT_GT(state.dimension, 0);

    // Evaluate salience of novel input
    auto novel_features = create_feature_vector(10, 0.9f);
    brain_salience_t salience = brain_evaluate_salience(sal_eval, novel_features.data(), 10);

    EXPECT_GE(salience.novelty, 0.0f);
    EXPECT_GE(salience.salience, 0.0f);

    printf("[EMERGENT] Introspection + Salience detected novelty\n");
    printf("  State dimension: %u, Novelty score: %.2f\n", state.dimension, salience.novelty);

    brain_state_free(&state);
    salience_evaluator_destroy(sal_eval);
    introspection_context_destroy(intro_ctx);
    brain_destroy(brain);
}

// Test: Attention mechanism based on salience
TEST(IntrospectionSalienceIntegration, AttentionMechanism)
{
    ScopedTimer timer("AttentionMechanism");

    brain_t brain =
        brain_create("attention_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_PATTERN_MATCHING, 12, 1);
    ASSERT_NE(brain, nullptr);

    salience_config_t config = salience_default_config();
    config.high_salience_threshold = 0.7f;
    config.high_novelty_threshold = 0.8f;

    salience_evaluator_t evaluator = salience_evaluator_create(brain, &config);
    ASSERT_NE(evaluator, nullptr);

    // SCENARIO: Allocate attention based on salience scores

    std::vector<std::vector<float>> inputs;
    std::vector<brain_salience_t> salience_scores;

    // Generate diverse inputs
    for (int i = 0; i < 10; i++) {
        inputs.push_back(create_feature_vector(12, 0.1f * i));
    }

    // Evaluate salience for all
    for (const auto& input : inputs) {
        brain_salience_t s = brain_evaluate_salience(evaluator, input.data(), 12);
        salience_scores.push_back(s);
    }

    // Find most salient inputs (where attention should go)
    int high_salience_count = 0;
    for (const auto& s : salience_scores) {
        if (s.salience > config.high_salience_threshold) {
            high_salience_count++;
        }
    }

    printf("[EMERGENT] Attention allocated to %d/%zu high-salience inputs\n", high_salience_count,
           salience_scores.size());

    salience_evaluator_destroy(evaluator);
    brain_destroy(brain);
}

// Test: Self-monitoring and anomaly detection
TEST(IntrospectionSalienceIntegration, SelfMonitoringAnomalyDetection)
{
    ScopedTimer timer("SelfMonitoringAnomalyDetection");

    brain_t brain =
        brain_create("monitoring_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 3);
    ASSERT_NE(brain, nullptr);

    introspection_config_t config = introspection_default_config();
    introspection_context_t ctx = introspection_context_create(brain, &config);
    ASSERT_NE(ctx, nullptr);

    // Train on normal patterns
    for (int i = 0; i < 10; i++) {
        auto features = create_feature_vector(10, 0.5f + (i * 0.01f));
        brain_learn_example(brain, features.data(), 10, "normal", 0.8f);
    }

    // Get baseline state
    brain_state_t baseline_state = brain_get_internal_state(ctx, STATE_STRATEGY_BALANCED);

    // Introduce anomaly (very different pattern)
    auto anomalous_features = create_feature_vector(10, 0.95f);
    brain_decision_t* decision = brain_decide(brain, anomalous_features.data(), 10);

    // Get state after anomaly
    brain_state_t anomaly_state = brain_get_internal_state(ctx, STATE_STRATEGY_BALANCED);

    // Compare states
    float similarity = brain_state_similarity(&baseline_state, &anomaly_state);

    printf("[EMERGENT] Self-monitoring detected state change: similarity=%.2f\n", similarity);

    if (decision) {
        printf("  Anomaly confidence: %.2f (low confidence suggests novelty)\n",
               decision->confidence);
        brain_free_decision(decision);
    }

    brain_state_free(&baseline_state);
    brain_state_free(&anomaly_state);
    introspection_context_destroy(ctx);
    brain_destroy(brain);
}

// Test: Adaptive behavior based on introspection
TEST(IntrospectionSalienceIntegration, AdaptiveBehaviorFromIntrospection)
{
    ScopedTimer timer("AdaptiveBehaviorFromIntrospection");

    brain_t brain =
        brain_create("adaptive_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 8, 2);
    ASSERT_NE(brain, nullptr);

    introspection_config_t config = introspection_default_config();
    introspection_context_t ctx = introspection_context_create(brain, &config);
    ASSERT_NE(ctx, nullptr);

    // SCENARIO: Adapt learning rate based on uncertainty

    // Train with varying confidence
    auto confident_features = create_feature_vector(8, 0.8f);
    for (int i = 0; i < 5; i++) {
        brain_learn_example(brain, confident_features.data(), 8, "confident", 0.95f);
    }

    // Get uncertainty estimate
    brain_uncertainty_t uncertainty = brain_get_uncertainty(ctx, confident_features.data(), 8);

    // Adapt: If confident (low uncertainty), can reduce learning
    // If uncertain (high uncertainty), increase learning
    bool should_learn_more = (uncertainty.epistemic > 0.5f);

    printf("[EMERGENT] Adaptive behavior based on introspection\n");
    printf("  Epistemic uncertainty: %.2f\n", uncertainty.epistemic);
    printf("  Aleatoric uncertainty: %.2f\n", uncertainty.aleatoric);
    printf("  Confidence: %.2f\n", uncertainty.confidence);
    printf("  Recommendation: %s\n", should_learn_more ? "Learn more" : "Confident enough");

    brain_uncertainty_free(&uncertainty);
    introspection_context_destroy(ctx);
    brain_destroy(brain);
}

//=============================================================================
// 6. FULL SYSTEM INTEGRATION TESTS
//=============================================================================

// Test: Complete infant learning scenario
TEST(FullSystemIntegration, InfantLearningScenario)
{
    ScopedTimer timer("InfantLearningScenario");

    // Create all subsystems
    brain_t brain =
        brain_create("infant_brain", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 15, 5);
    ASSERT_NE(brain, nullptr);

    curiosity_engine_t curiosity = curiosity_engine_create("infant");
    ASSERT_NE(curiosity, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("infant_knowledge");
    ASSERT_NE(knowledge, nullptr);

    // SCENARIO: Infant learns about objects through curiosity-driven exploration

    // High infant curiosity
    curiosity_set_baseline(curiosity, 0.9f);
    curiosity_set_stage(curiosity, STAGE_INFANT);

    // Encounter new object: "ball"
    knowledge_gap_t gap = curiosity_detect_knowledge_gap(curiosity, "ball");
    EXPECT_GT(gap.gap_size, 0.5f);

    // Generate infant-level questions
    generated_question_t questions[5];
    uint32_t num_q = curiosity_generate_questions(curiosity, &gap, questions, 5);

    // Learn from observation
    auto ball_features = create_feature_vector(15, 0.6f);
    curiosity_learn_observation(curiosity, "Round object that rolls", "playing");

    // Neural encoding
    brain_learn_example(brain, ball_features.data(), 15, "ball", 0.8f);

    // Store in knowledge
    knowledge_learn_from_text(knowledge, "A ball is round and bounces", KNOWLEDGE_DOMAIN_GENERAL);

    // Progress check
    learning_progress_t progress;
    curiosity_get_progress(curiosity, &progress);

    printf("[EMERGENT] Infant learning scenario completed\n");
    printf("  Questions generated: %u\n", num_q);
    printf("  Observations: %lu, Concepts learned: %lu\n", progress.total_experiences,
           progress.concepts_learned);

    knowledge_system_destroy(knowledge);
    curiosity_engine_destroy(curiosity);
    brain_destroy(brain);
}

// Test: Multi-modal sensory integration
TEST(FullSystemIntegration, MultiModalSensoryIntegration)
{
    ScopedTimer timer("MultiModalSensoryIntegration");

    // Create sensory-processing brain
    brain_t visual_brain =
        brain_create("visual", BRAIN_SIZE_SMALL, BRAIN_TASK_PATTERN_MATCHING, 20, 1);
    ASSERT_NE(visual_brain, nullptr);

    brain_t audio_brain =
        brain_create("audio", BRAIN_SIZE_SMALL, BRAIN_TASK_PATTERN_MATCHING, 15, 1);
    ASSERT_NE(audio_brain, nullptr);

    brain_t integration_brain =
        brain_create("multimodal", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 3);
    ASSERT_NE(integration_brain, nullptr);

    // SCENARIO: Integrate visual + audio → unified percept

    // Visual input (seeing a dog)
    auto visual_features = create_feature_vector(20, 0.7f);
    brain_decision_t* visual_decision = brain_decide(visual_brain, visual_features.data(), 20);

    // Audio input (hearing a bark)
    auto audio_features = create_feature_vector(15, 0.6f);
    brain_decision_t* audio_decision = brain_decide(audio_brain, audio_features.data(), 15);

    // Integrate both modalities
    auto integrated_features = create_feature_vector(10, 0.65f);
    brain_learn_example(integration_brain, integrated_features.data(), 10, "dog", 0.95f);

    brain_decision_t* integrated = brain_decide(integration_brain, integrated_features.data(), 10);
    ASSERT_NE(integrated, nullptr);

    printf("[EMERGENT] Multi-modal integration\n");
    printf("  Integrated decision: %s (confidence: %.2f)\n", integrated->label,
           integrated->confidence);

    if (visual_decision)
        brain_free_decision(visual_decision);
    if (audio_decision)
        brain_free_decision(audio_decision);
    brain_free_decision(integrated);

    brain_destroy(integration_brain);
    brain_destroy(audio_brain);
    brain_destroy(visual_brain);
}

// Test: End-to-end autonomous agent behavior
TEST(FullSystemIntegration, AutonomousAgentBehavior)
{
    ScopedTimer timer("AutonomousAgentBehavior");

    // Create complete agent
    brain_t perception =
        brain_create("perception", BRAIN_SIZE_SMALL, BRAIN_TASK_PATTERN_MATCHING, 12, 1);
    ASSERT_NE(perception, nullptr);

    brain_t decision = brain_create("decision", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 4);
    ASSERT_NE(decision, nullptr);

    ethics_config_t ethics_config;
    memset(&ethics_config, 0, sizeof(ethics_config));
    ethics_config.action_feature_size = 10;
    ethics_config.max_agents = 3;
    ethics_config.golden_rule_threshold = 0.0f;

    ethics_engine_t ethics = ethics_engine_create(&ethics_config);
    ASSERT_NE(ethics, nullptr);

    curiosity_engine_t curiosity = curiosity_engine_create("agent");
    ASSERT_NE(curiosity, nullptr);

    // SCENARIO: Agent perceives → decides → ethics checks → acts

    // 1. Perceive environment
    auto percept_features = create_feature_vector(12, 0.55f);
    brain_decision_t* percept = brain_decide(perception, percept_features.data(), 12);

    // 2. Decide on action
    auto decision_features = create_feature_vector(10, 0.6f);
    brain_decision_t* action_decision = brain_decide(decision, decision_features.data(), 10);

    // 3. Ethics check
    action_context_t action;
    memset(&action, 0, sizeof(action));
    action.features = decision_features.data();
    action.num_features = 10;
    action.predicted_harm = 0.1f;

    agent_id_t agents[] = {1};
    action.affected_agents = agents;
    action.num_affected_agents = 1;

    ethics_evaluation_t eval = ethics_engine_evaluate_action(ethics, &action);

    // 4. If allowed, execute (simulated)
    bool executed = eval.allowed;

    // 5. Learn from outcome
    if (executed) {
        curiosity_learn_experience(curiosity, "Successful action execution",
                                   decision_features.data(), 10);
    }

    printf("[EMERGENT] Autonomous agent cycle completed\n");
    printf("  Perception: %s\n", percept ? "successful" : "failed");
    printf("  Decision: %s\n", action_decision ? action_decision->label : "none");
    printf("  Ethics allowed: %d\n", eval.allowed);
    printf("  Executed: %d\n", executed);

    if (percept)
        brain_free_decision(percept);
    if (action_decision)
        brain_free_decision(action_decision);

    curiosity_engine_destroy(curiosity);
    ethics_engine_destroy(ethics);
    brain_destroy(decision);
    brain_destroy(perception);
}

// Test: Real-world task simulation (simplified household robot)
TEST(FullSystemIntegration, HouseholdRobotSimulation)
{
    ScopedTimer timer("HouseholdRobotSimulation");

    // Robot subsystems
    brain_t object_recognition =
        brain_create("vision", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 15, 5);
    ASSERT_NE(object_recognition, nullptr);

    brain_t task_planning =
        brain_create("planning", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 12, 6);
    ASSERT_NE(task_planning, nullptr);

    knowledge_system_t world_model = knowledge_system_create("robot_knowledge");
    ASSERT_NE(world_model, nullptr);

    ethics_config_t safety_config;
    memset(&safety_config, 0, sizeof(safety_config));
    safety_config.action_feature_size = 12;
    safety_config.max_agents = 5;
    safety_config.golden_rule_threshold = 0.0f;

    ethics_engine_t safety = ethics_engine_create(&safety_config);
    ASSERT_NE(safety, nullptr);

    // SCENARIO: "Pick up cup and place on table"

    // 1. Recognize cup
    auto cup_features = create_feature_vector(15, 0.65f);
    brain_learn_example(object_recognition, cup_features.data(), 15, "cup", 0.9f);
    brain_decision_t* recognized = brain_decide(object_recognition, cup_features.data(), 15);

    // 2. Store in world model
    knowledge_learn_from_text(world_model, "Cup is a container for liquids",
                              KNOWLEDGE_DOMAIN_GENERAL);

    // 3. Plan action
    auto plan_features = create_feature_vector(12, 0.5f);
    brain_learn_example(task_planning, plan_features.data(), 12, "grasp_and_move", 0.85f);

    // 4. Safety check
    action_context_t grasp_action;
    memset(&grasp_action, 0, sizeof(grasp_action));
    grasp_action.features = plan_features.data();
    grasp_action.num_features = 12;
    grasp_action.predicted_harm = 0.05f;  // Low harm - careful grasp

    agent_id_t people[] = {1};  // One person nearby
    grasp_action.affected_agents = people;
    grasp_action.num_affected_agents = 1;

    ethics_evaluation_t safety_eval = ethics_engine_evaluate_action(safety, &grasp_action);

    // 5. Execute if safe
    bool task_completed = safety_eval.allowed;

    printf("[EMERGENT] Household robot task simulation\n");
    printf("  Object recognized: %s (conf: %.2f)\n", recognized ? recognized->label : "unknown",
           recognized ? recognized->confidence : 0.0f);
    printf("  Safety check: %s\n", safety_eval.allowed ? "SAFE" : "UNSAFE");
    printf("  Task completed: %s\n", task_completed ? "YES" : "NO");

    if (recognized)
        brain_free_decision(recognized);

    ethics_engine_destroy(safety);
    knowledge_system_destroy(world_model);
    brain_destroy(task_planning);
    brain_destroy(object_recognition);
}

//=============================================================================
// Performance and Resource Tests
//=============================================================================

// Test: Multi-system memory usage
TEST(PerformanceTests, MultiSystemMemoryUsage)
{
    ScopedTimer timer("MultiSystemMemoryUsage");

    brain_t brain = brain_create("memory_test", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 3);
    ASSERT_NE(brain, nullptr);

    knowledge_system_t knowledge = knowledge_system_create("knowledge_test");
    ASSERT_NE(knowledge, nullptr);

    curiosity_engine_t curiosity = curiosity_engine_create("curiosity_test");
    ASSERT_NE(curiosity, nullptr);

    // Get memory usage
    size_t brain_memory = brain_get_memory_usage(brain);

    printf("[PERFORMANCE] Multi-system memory usage\n");
    printf("  Brain: %zu bytes (%.2f MB)\n", brain_memory, brain_memory / (1024.0 * 1024.0));

    // Verify reasonable memory usage
    EXPECT_LT(brain_memory, 100 * 1024 * 1024);  // Less than 100MB for small brain

    curiosity_engine_destroy(curiosity);
    knowledge_system_destroy(knowledge);
    brain_destroy(brain);
}

// Test: Integration throughput
TEST(PerformanceTests, IntegrationThroughput)
{
    ScopedTimer timer("IntegrationThroughput");

    brain_t brain =
        brain_create("throughput_test", BRAIN_SIZE_SMALL, BRAIN_TASK_CLASSIFICATION, 10, 3);
    ASSERT_NE(brain, nullptr);

    salience_config_t sal_config = salience_default_config();
    salience_evaluator_t salience = salience_evaluator_create(brain, &sal_config);
    ASSERT_NE(salience, nullptr);

    // Process many inputs through multiple systems
    const int NUM_INPUTS = 100;
    auto start = std::chrono::high_resolution_clock::now();

    for (int i = 0; i < NUM_INPUTS; i++) {
        auto features = create_feature_vector(10, 0.01f * i);

        // Salience check
        brain_salience_t sal = brain_evaluate_salience(salience, features.data(), 10);

        // Decision (if salient)
        if (sal.salience > 0.5f) {
            brain_decision_t* decision = brain_decide(brain, features.data(), 10);
            if (decision) {
                brain_free_decision(decision);
            }
        }
    }

    auto end = std::chrono::high_resolution_clock::now();
    auto duration = std::chrono::duration_cast<std::chrono::milliseconds>(end - start);

    float throughput = (NUM_INPUTS * 1000.0f) / duration.count();

    printf("[PERFORMANCE] Integration throughput\n");
    printf("  Processed %d inputs in %ldms\n", NUM_INPUTS, duration.count());
    printf("  Throughput: %.2f inputs/second\n", throughput);

    EXPECT_GT(throughput, 10.0f);  // At least 10 inputs per second

    salience_evaluator_destroy(salience);
    brain_destroy(brain);
}

//=============================================================================
// Main Test Runner
//=============================================================================

int main(int argc, char** argv)
{
    printf("=================================================================\n");
    printf("NIMCP 2.5 - MULTI-MODULE COGNITIVE INTEGRATION TESTS\n");
    printf("=================================================================\n\n");

    ::testing::InitGoogleTest(&argc, argv);
    int result = RUN_ALL_TESTS();

    printf("\n=================================================================\n");
    printf("Integration tests completed\n");
    printf("=================================================================\n");

    return result;
}
