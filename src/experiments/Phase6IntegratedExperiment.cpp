#include "Phase6IntegratedExperiment.hpp"
#include "../core/Config/Config.hpp"
#include "../core/Logger/Logger.hpp"
#include "../brain/Brain.hpp"
#include "../world/SimpleWorld.hpp"
#include "../agent/AgentBrain.hpp"
#include "../memory/NeuralWorkingMemory.hpp"
#include "../memory/NeuralEpisodicMemory.hpp"
#include <chrono>
#include <cmath>

namespace nlm {

Phase6IntegratedExperiment::Phase6IntegratedExperiment() {}

Phase6IntegratedExperiment::~Phase6IntegratedExperiment() = default;

Phase6IntegrationResult Phase6IntegratedExperiment::run(const Phase6Config& config) {
    Phase6IntegrationResult result;
    result.startTime = time(nullptr);
    
    auto startWall = std::chrono::high_resolution_clock::now();
    
    NLM_LOG_INFO("=== Phase 6 Integration Experiment ===");
    NLM_LOG_INFO("Configuration: " + std::to_string(config.neuronCount) + " neurons, " +
                 std::to_string(config.maxSteps) + " steps");
    
    // Create configuration
    auto cfg = std::make_shared<Config>();
    cfg->set("neuron_count", static_cast<int64_t>(config.neuronCount));
    cfg->set("region_count", static_cast<int64_t>(config.regionCount));
    cfg->set("connection_probability", config.connectionProbability);
    cfg->set("stdp_ltp_weight", 0.01f);
    cfg->set("stdp_ltd_weight", 0.012f);
    cfg->set("synaptogenesis_rate", 0.0001f);
    cfg->set("pruning_rate", 0.00001f);
    
    // Create brain
    auto brain = std::make_shared<Brain>(cfg);
    if (!brain->initialize()) {
        NLM_LOG_ERROR("Failed to initialize brain");
        result.endTime = time(nullptr);
        return result;
    }
    
    // Create simple world
    SimpleWorld world;
    world.configure(16, 16, 16, 16);
    world.reset();
    
    // Create agent
    AgentBrain agent(brain);
    agent.initialize(world);
    agent.enableRewardModulation(true);
    agent.enableStructuralPlasticity(config.enableDevelopment);
    agent.enableDevelopment(config.enableDevelopment);
    agent.enableCuriosity(true);
    
    NLM_LOG_INFO("Brain and agent initialized successfully");
    
    // Run simulation
    float totalReward = 0.0f;
    float totalFiringRate = 0.0f;
    size_t firingCount = 0;
    
    for (uint64_t step = 0; step < config.maxSteps; ++step) {
        // Get observation
        world.update(0.001);
        SensoryPercept percept = world.getSensoryPercept();
        
        // Process sensory input
        agent.processSensoryInput(percept);
        
        // Brain step
        brain->step(step, step * 0.001);
        
        // Get motor command
        MotorCommand cmd = agent.decodeMotorCommand();
        
        // Apply action to world
        ActionResult actionResult = world.applyMotorCommand(cmd, step * 0.001);
        
        // Compute reward
        float reward = actionResult.reward;
        totalReward += reward;
        
        // Apply reward modulation
        agent.applyRewardModulation(reward, 0.0f);
        
        // Update development
        if (config.enableDevelopment) {
            agent.updateDevelopment(0.001);
        }
        
        // Collect metrics
        totalFiringRate += brain->getAverageFiringRate();
        if (brain->getFiringNeuronCount() > 0) firingCount++;
        
        // Periodic status
        if (step % 1000 == 0) {
            NLM_LOG_INFO("Step " + std::to_string(step) + 
                        " | Reward: " + std::to_string(totalReward / (step + 1)) +
                        " | Firing: " + std::to_string(brain->getAverageFiringRate()) +
                        " | WorkingMem: " + std::to_string(brain->getWorkingMemory() ? 
                            brain->getWorkingMemory()->getActiveTraces() : 0));
        }
    }
    
    // Collect final metrics
    result.totalReward = totalReward / config.maxSteps;
    result.avgFiringRate = totalFiringRate / config.maxSteps;
    result.memoryEpisodesStored = brain->getEpisodicMemory() ? 
        static_cast<float>(brain->getEpisodicMemory()->getEpisodeCount()) : 0.0f;
    result.noveltyLevel = agent.getNoveltyLevel();
    result.curiosityLevel = agent.getCuriosityLevel();
    result.dopamineLevel = agent.getNeuromodulationLevel();
    
    // Verify integration
    result.memoryWorkingMemoryIntegrated = (brain->getWorkingMemory() != nullptr);
    result.memoryEpisodicMemoryIntegrated = (brain->getEpisodicMemory() != nullptr);
    result.neuromodulationIntegrated = (brain->getDopamine() != nullptr);
    result.predictionIntegrated = (brain->getPredictionSystem() != nullptr);
    result.developmentIntegrated = (brain->getDevelopmentSystem() != nullptr);
    
    NLM_LOG_INFO("=== Integration Verification ===");
    NLM_LOG_INFO("Working Memory: " + std::string(result.memoryWorkingMemoryIntegrated ? "YES" : "NO"));
    NLM_LOG_INFO("Episodic Memory: " + std::string(result.memoryEpisodicMemoryIntegrated ? "YES" : "NO"));
    NLM_LOG_INFO("Neuromodulation: " + std::string(result.neuromodulationIntegrated ? "YES" : "NO"));
    NLM_LOG_INFO("Prediction: " + std::string(result.predictionIntegrated ? "YES" : "NO"));
    NLM_LOG_INFO("Development: " + std::string(result.developmentIntegrated ? "YES" : "NO"));
    
    // Test checkpointing with proper validation
    if (config.enableCheckpointing) {
        NLM_LOG_INFO("Testing checkpoint save/load with validation...");
        
        // Save the checkpoint
        if (!brain->save(config.checkpointPath)) {
            NLM_LOG_ERROR("Failed to save checkpoint");
            continue; // Skip checkpoint test if save fails
        }
        NLM_LOG_INFO("Checkpoint saved successfully");
        
        // Create new brain and load
        auto brain2 = std::make_shared<Brain>(cfg);
        brain2->initialize();
        
        // Load the checkpoint
        if (!brain2->load(config.checkpointPath)) {
            NLM_LOG_ERROR("Failed to load checkpoint");
            continue; // Skip validation if load fails
        }
        NLM_LOG_INFO("Checkpoint loaded successfully");
        
        // Validate that checkpoint worked properly
        bool checkpointValid = validateCheckpoint(brain, brain2);
        if (checkpointValid) {
            NLM_LOG_INFO("✓ Checkpoint validation PASSED");
            result.checkpointingWorks = true;
        } else {
            NLM_LOG_ERROR("✗ Checkpoint validation FAILED - state not properly restored");
        }
    }
    
    result.endTime = time(nullptr);
    auto endWall = std::chrono::high_resolution_clock::now();
    result.totalWallClockTime = std::chrono::duration<double>(endWall - startWall).count();
    
    NLM_LOG_INFO("=== Experiment Complete ===");
    NLM_LOG_INFO("Total reward: " + std::to_string(result.totalReward));
    NLM_LOG_INFO("Avg firing rate: " + std::to_string(result.avgFiringRate));
    NLM_LOG_INFO("Episodes stored: " + std::to_string(result.memoryEpisodesStored));
    NLM_LOG_INFO("Wall time: " + std::to_string(result.totalWallClockTime) + "s");
    
    return result;
}

bool Phase6IntegratedExperiment::verifyIntegration() {
    NLM_LOG_INFO("=== Phase 6 Integration Verification ===");
    
    // Create minimal brain
    auto cfg = std::make_shared<Config>();
    cfg->set("neuron_count", 100);
    cfg->set("region_count", 1);
    
    auto brain = std::make_shared<Brain>(cfg);
    if (!brain->initialize()) {
        NLM_LOG_ERROR("Brain initialization failed");
        return false;
    }
    
    bool success = true;
    
    // Test 1: Memory systems exist and are connected
    if (brain->getWorkingMemory() != nullptr) {
        NLM_LOG_INFO("[PASS] Working memory is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Working memory is NOT integrated");
        success = false;
    }
    
    if (brain->getEpisodicMemory() != nullptr) {
        NLM_LOG_INFO("[PASS] Episodic memory is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Episodic memory is NOT integrated");
        success = false;
    }
    
    // Test 2: Neuromodulation systems exist
    if (brain->getDopamine() != nullptr) {
        NLM_LOG_INFO("[PASS] Dopamine system is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Dopamine system is NOT integrated");
        success = false;
    }
    
    if (brain->getCuriosity() != nullptr) {
        NLM_LOG_INFO("[PASS] Curiosity system is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Curiosity system is NOT integrated");
        success = false;
    }
    
    // Test 3: Prediction system exists
    if (brain->getPredictionSystem() != nullptr) {
        NLM_LOG_INFO("[PASS] Prediction system is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Prediction system is NOT integrated");
        success = false;
    }
    
    // Test 4: Cognition systems exist
    if (brain->getPlanner() != nullptr) {
        NLM_LOG_INFO("[PASS] Planner is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Planner is NOT integrated");
        success = false;
    }
    
    if (brain->getConceptFormation() != nullptr) {
        NLM_LOG_INFO("[PASS] Concept formation is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Concept formation is NOT integrated");
        success = false;
    }
    
    if (brain->getAttention() != nullptr) {
        NLM_LOG_INFO("[PASS] Attention is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Attention is NOT integrated");
        success = false;
    }
    
    // Test 5: Development system exists
    if (brain->getDevelopmentSystem() != nullptr) {
        NLM_LOG_INFO("[PASS] Development system is integrated");
    } else {
        NLM_LOG_ERROR("[FAIL] Development system is NOT integrated");
        success = false;
    }
    
    return success;
}

bool Phase6IntegratedExperiment::testMemoryIntegration() {
    NLM_LOG_INFO("=== Testing Memory Integration ===");
    
    auto cfg = std::make_shared<Config>();
    cfg->set("neuron_count", 100);
    
    auto brain = std::make_shared<Brain>(cfg);
    brain->initialize();
    
    // Get memory systems
    auto* wm = brain->getWorkingMemory();
    auto* em = brain->getEpisodicMemory();
    
    if (!wm || !em) {
        NLM_LOG_ERROR("Memory systems not available");
        return false;
    }
    
    // Run some steps
    for (int i = 0; i < 100; ++i) {
        brain->step(i, i * 0.001);
    }
    
    // Check if working memory has traces
    if (wm->getActiveTraces() > 0) {
        NLM_LOG_INFO("[PASS] Working memory has active traces: " + std::to_string(wm->getActiveTraces()));
    } else {
        NLM_LOG_INFO("[INFO] Working memory has no active traces (may be normal for simple simulation)");
    }
    
    // Check if episodic memory has episodes
    if (em->getEpisodeCount() > 0) {
        NLM_LOG_INFO("[PASS] Episodic memory has episodes: " + std::to_string(em->getEpisodeCount()));
    } else {
        NLM_LOG_INFO("[INFO] Episodic memory has no episodes (may be normal for simple simulation)");
    }
    
    return true;
}

bool Phase6IntegratedExperiment::testNeuromodulationIntegration() {
    NLM_LOG_INFO("=== Testing Neuromodulation Integration ===");
    
    auto cfg = std::make_shared<Config>();
    cfg->set("neuron_count", 100);
    
    auto brain = std::make_shared<Brain>(cfg);
    brain->initialize();
    
    // Get neuromodulation systems
    auto* dopamine = brain->getDopamine();
    auto* curiosity = brain->getCuriosity();
    auto* novelty = brain->getNovelty();
    
    if (!dopamine || !curiosity || !novelty) {
        NLM_LOG_ERROR("Neuromodulation systems not available");
        return false;
    }
    
    // Run some steps with sensory input
    for (int i = 0; i < 50; ++i) {
        // Inject some sensory activity
        brain->injectCurrentToNeurons(NeuronType::Sensory, 5.0f);
        brain->step(i, i * 0.001);
    }
    
    NLM_LOG_INFO("[PASS] Neuromodulation systems are functional");
    return true;
}

bool Phase6IntegratedExperiment::testCheckpointing() {
    NLM_LOG_INFO("=== Testing Checkpoint Save/Load ===");
    
    auto cfg = std::make_shared<Config>();
    cfg->set("neuron_count", 100);
    
    // Create and initialize brain
    auto brain1 = std::make_shared<Brain>(cfg);
    brain1->initialize();
    
    // Run some steps
    for (int i = 0; i < 100; ++i) {
        brain1->step(i, i * 0.001);
    }
    
    float avgFiring1 = brain1->getAverageFiringRate();
    size_t totalSpikes1 = brain1->getTotalSpikeCount();
    
    NLM_LOG_INFO("Brain1 avg firing: " + std::to_string(avgFiring1));
    NLM_LOG_INFO("Brain1 total spikes: " + std::to_string(totalSpikes1));
    
    // Save checkpoint
    std::string path = "/tmp/nlm_checkpoint_test.bin";
    if (!brain1->save(path)) {
        NLM_LOG_ERROR("Failed to save checkpoint");
        return false;
    }
    
    // Create new brain and load
    auto brain2 = std::make_shared<Brain>(cfg);
    brain2->initialize();
    
    if (!brain2->load(path)) {
        NLM_LOG_ERROR("Failed to load checkpoint");
        return false;
    }
    
    size_t totalSpikes2 = brain2->getTotalSpikeCount();
    NLM_LOG_INFO("Brain2 total spikes after load: " + std::to_string(totalSpikes2));
    
    // Note: Due to the nature of neural simulation, exact state restoration
    // is complex. The load should restore the structure at minimum.
    
    }

// Helper function to get mean weight of a brain
static double getMeanWeight(const std::shared_ptr<Brain>& brain) {
    double sum = 0.0;
    size_t count = 0;
    for (const auto& region : brain->getRegions()) {
        for (const auto& syn : region->getSynapses()) {
            sum += syn->getWeight();
            ++count;
        }
    }
    return count > 0 ? sum / static_cast<double>(count) : 0.0;
}

// Helper function to get first membrane potential
static float getFirstMembranePotential(const std::shared_ptr<Brain>& brain) {
    for (const auto& region : brain->getRegions()) {
        for (const auto* neuron : region->getAllNeurons()) {
            return neuron->getMembranePotential();
        }
    }
    return 0.0f;
}

bool Phase6IntegratedExperiment::validateCheckpoint(std::shared_ptr<Brain> originalBrain, std::shared_ptr<Brain> restoredBrain) {
    NLM_LOG_INFO("=== Validating Checkpoint Restore ===");
    
    // Get original brain statistics
    double originalMeanWeight = getMeanWeight(originalBrain);
    float originalMembrane = getFirstMembranePotential(originalBrain);
    size_t originalPending = originalBrain->getPendingSpikeEventCount();
    
    // Get restored brain statistics
    double restoredMeanWeight = getMeanWeight(restoredBrain);
    float restoredMembrane = getFirstMembranePotential(restoredBrain);
    size_t restoredPending = restoredBrain->getPendingSpikeEventCount();
    
    // Log statistics
    NLM_LOG_INFO("Original brain - Mean weight: " + std::to_string(originalMeanWeight) +
                ", Membrane: " + std::to_string(originalMembrane) +
                ", Pending: " + std::to_string(originalPending));
    NLM_LOG_INFO("Restored brain - Mean weight: " + std::to_string(restoredMeanWeight) +
                ", Membrane: " + std::to_string(restoredMembrane) +
                ", Pending: " + std::to_string(restoredPending));
    
    // Validation criteria
    bool weightRestored = std::abs(originalMeanWeight - restoredMeanWeight) < 1e-6;
    bool membraneRestored = std::abs(originalMembrane - restoredMembrane) < 1e-6;
    bool pendingRestored = originalPending == restoredPending;
    
    NLM_LOG_INFO("Weight restoration: " + std::string(weightRestored ? "✓ PASS" : "✗ FAIL"));
    NLM_LOG_INFO("Membrane restoration: " + std::string(membraneRestored ? "✓ PASS" : "✗ FAIL"));
    NLM_LOG_INFO("Pending spikes restoration: " + std::string(pendingRestored ? "✓ PASS" : "✗ FAIL"));
    
    if (!weightRestored || !membraneRestored || !pendingRestored) {
        NLM_LOG_ERROR("Checkpoint validation FAILED - state not properly restored");
        return false;
    }
    
    // Additional test: run identical steps and check firing rates stay close
    NLM_LOG_INFO("Testing firing rate stability after restore...");
    const size_t testSteps = 10;
    
    float originalRate = originalBrain->getAverageFiringRate();
    float restoredRate = restoredBrain->getAverageFiringRate();
    
    // Run identical steps on both brains
    for (size_t step = 0; step < testSteps; ++step) {
        originalBrain->step(static_cast<SimulationStep>(step), static_cast<Timestamp>(step) * 0.001);
        restoredBrain->step(static_cast<SimulationStep>(step), static_cast<Timestamp>(step) * 0.001);
    }
    
    float finalOriginalRate = originalBrain->getAverageFiringRate();
    float finalRestoredRate = restoredBrain->getAverageFiringRate();
    
    // Check that firing rates stay close
    float denom = std::max(std::abs(finalOriginalRate), 1.0f);
    bool ratesStable = std::abs(finalOriginalRate - finalRestoredRate) / denom < 0.25f;
    
    NLM_LOG_INFO("Original final firing rate: " + std::to_string(finalOriginalRate));
    NLM_LOG_INFO("Restored final firing rate: " + std::to_string(finalRestoredRate));
    NLM_LOG_INFO("Firing rate stability: " + std::string(ratesStable ? "✓ PASS" : "✗ FAIL"));
    
    if (!ratesStable) {
        NLM_LOG_ERROR("Firing rates diverged after restore");
        return false;
    }
    
    NLM_LOG_INFO("✓ Checkpoint validation PASSED");
    return true;
}
    
    // Run some steps
    for (int i = 0; i < 200; ++i) {
        brain->step(i, i * 0.001);
    }
    
    // Check if episodes exist for replay
    size_t episodeCount = em->getEpisodeCount();
    if (episodeCount > 0) {
        NLM_LOG_INFO("[PASS] Episodes available for replay: " + std::to_string(episodeCount));
        
        // Get episodes for replay
        auto episodes = em->getEpisodesForReplay(3);
        if (!episodes.empty()) {
            NLM_LOG_INFO("[PASS] Replay system can retrieve episodes");
            return true;
        }
    }
    
    NLM_LOG_INFO("[INFO] No episodes available for replay (may be normal)");
    return true;
}

} // namespace nlm
