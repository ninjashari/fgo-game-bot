# Core Logic System Design - Autonomous FGO Bot Architecture

## 🎯 System Overview

The core logic system transforms our FGO Bot from a data management application into a fully autonomous battle automation system. This system leverages **machine learning**, **computer vision**, **decision trees**, and **adaptive algorithms** to create an intelligent bot that learns from its mistakes and continuously improves its performance.

### Key Objectives
- **Autonomous Battle Execution**: Complete automation of FGO battles without user intervention
- **Adaptive Intelligence**: Learning system that improves performance over time
- **Multi-Quest Support**: Handles farming, story quests, events, and challenge content
- **Error Recovery**: Robust error handling and recovery mechanisms
- **Performance Optimization**: Continuous improvement of battle efficiency and resource usage

### Inspiration from Existing Projects
Based on analysis of successful FGO automation projects:
- **[Fate-Grand-Automata (FGA)](https://github.com/Fate-Grand-Automata/FGA)**: Modern Android-native approach using OpenCV, Media Projection, and Accessibility Services
- **[FGO-Lua](https://github.com/29988122/Fate-Grand-Order_Lua)**: Original Lua-based automation using Sikuli for image recognition

## 🏗️ Architecture Design

### Multi-Layer Intelligence Architecture

Our core logic is built on a **4-tier intelligence system**:

#### Tier 1: Perception Layer (Computer Vision & State Detection)
```
┌─────────────────────────────────────────────────────────────┐
│                    PERCEPTION LAYER                         │
├─────────────────────────────────────────────────────────────┤
│ • Screen Analysis Engine    • Battle State Recognition      │
│ • UI Element Detection      • OCR Integration               │
│ • Template Matching         • Animation Detection           │
│ • Color Analysis            • Gesture Recognition           │
└─────────────────────────────────────────────────────────────┘
```

**Components:**
- **Screen Analysis Engine**: Real-time screen capture and image processing
- **Battle State Recognition**: Identifies current battle phase, turn state, enemy positions
- **UI Element Detection**: Recognizes buttons, cards, skills, NP gauges, health bars
- **OCR Integration**: Reads damage numbers, turn counters, buff/debuff text
- **Template Matching**: Fast UI element recognition using pre-trained templates
- **Animation Detection**: Recognizes battle animations and timing

#### Tier 2: Decision Engine (Strategic AI)
```
┌─────────────────────────────────────────────────────────────┐
│                    DECISION ENGINE                          │
├─────────────────────────────────────────────────────────────┤
│ • Battle Strategy Planner   • Team Composition Optimizer   │
│ • Command Card Selector     • Skill Usage Optimizer        │
│ • NP Timing System          • Target Selection AI          │
│ • Resource Manager          • Priority Queue System        │
└─────────────────────────────────────────────────────────────┘
```

**Components:**
- **Battle Strategy Planner**: Analyzes quest requirements and selects optimal approach
- **Team Composition Optimizer**: Dynamically adjusts team based on enemy analysis
- **Command Card Selector**: Uses probability matrices for optimal card chains
- **Skill Usage Optimizer**: Timing-based skill activation with buff stacking logic
- **NP Timing System**: Coordinates Noble Phantasm usage for maximum effectiveness
- **Target Selection AI**: Intelligent enemy targeting based on threat assessment

#### Tier 3: Learning Layer (Adaptive Intelligence)
```
┌─────────────────────────────────────────────────────────────┐
│                    LEARNING LAYER                           │
├─────────────────────────────────────────────────────────────┤
│ • Performance Analytics     • Pattern Recognition          │
│ • Adaptive Algorithms       • Error Recovery System        │
│ • Strategy Evolution        • Behavioral Learning          │
│ • Success Rate Tracking     • Failure Analysis             │
└─────────────────────────────────────────────────────────────┘
```

**Components:**
- **Performance Analytics**: Tracks win rates, turn counts, damage efficiency
- **Pattern Recognition**: Identifies successful strategies and failure points
- **Adaptive Algorithms**: Modifies decision weights based on historical performance
- **Error Recovery System**: Learns from mistakes and develops countermeasures
- **Strategy Evolution**: Continuous improvement of battle strategies
- **Behavioral Learning**: Adapts to different quest types and enemy patterns

#### Tier 4: Execution Layer (Automation Control)
```
┌─────────────────────────────────────────────────────────────┐
│                    EXECUTION LAYER                          │
├─────────────────────────────────────────────────────────────┤
│ • Gesture Controller        • Timing Manager               │
│ • Input Validation          • Error Detection              │
│ • Safety Systems            • Performance Monitor          │
│ • Anti-Detection            • Resource Management          │
└─────────────────────────────────────────────────────────────┘
```

**Components:**
- **Gesture Controller**: Precise touch input simulation with human-like variations
- **Timing Manager**: Handles delays, animations, and response timing
- **Error Detection**: Monitors for unexpected states and recovery scenarios
- **Safety Systems**: Prevents infinite loops and handles edge cases
- **Anti-Detection**: Implements human-like behavior patterns
- **Performance Monitor**: Real-time system performance tracking

## 🧠 Core Components Deep Dive

### 1. Battle Strategy Planner

**Purpose**: Creates comprehensive battle plans based on quest analysis and team capabilities.

**Architecture:**
```kotlin
interface BattleStrategyPlanner {
    suspend fun analyzeBattleConditions(quest: Quest, team: Team): BattleAnalysis
    suspend fun createBattleStrategy(analysis: BattleAnalysis): BattleStrategy
    suspend fun adaptStrategy(currentState: BattleState, strategy: BattleStrategy): BattleStrategy
    suspend fun evaluateStrategyPerformance(result: BattleResult): StrategyEvaluation
}
```

**Key Features:**
- **Quest Analysis Engine**: Analyzes enemy compositions, weaknesses, and special mechanics
- **Strategy Templates**: Pre-built strategies for common scenarios (farming, challenge quests, boss fights)
- **Dynamic Strategy Adaptation**: Modifies strategy mid-battle based on changing conditions
- **Resource Management**: Optimizes AP usage, skill cooldowns, and NP timing
- **Multi-Wave Planning**: Coordinates strategy across multiple battle waves

**Learning Mechanism:**
- Tracks strategy success rates across different quest types
- Identifies which strategies work best against specific enemy compositions
- Adapts strategy selection based on team performance metrics
- Builds knowledge base of effective counter-strategies

### 2. Team Composition Logic

**Purpose**: Intelligently selects and optimizes team compositions for maximum effectiveness.

**Architecture:**
```kotlin
interface TeamCompositionOptimizer {
    suspend fun analyzeQuestRequirements(quest: Quest): QuestRequirements
    suspend fun calculateTeamSynergy(servants: List<Servant>): SynergyScore
    suspend fun optimizeTeamComposition(requirements: QuestRequirements): OptimalTeam
    suspend fun selectSupportServant(team: Team, quest: Quest): SupportSelection
}
```

**Key Features:**
- **Synergy Calculator**: Analyzes servant skill interactions and buff stacking
- **Counter-Pick System**: Selects servants based on enemy class advantages
- **Support Selection AI**: Chooses optimal friend support based on quest requirements
- **Craft Essence Optimizer**: Matches CEs to servant roles and quest objectives
- **Role Assignment**: Assigns specific roles (DPS, Support, Tank) to team members

**Learning Mechanism:**
- Maintains win rate statistics for different team compositions
- Learns which servant combinations work best together
- Adapts team selection based on quest-specific performance data
- Identifies optimal CE pairings for different scenarios

### 3. Command Card Selector

**Purpose**: Makes optimal command card decisions to maximize damage and NP generation.

**Architecture:**
```kotlin
interface CommandCardSelector {
    suspend fun analyzeAvailableCards(cards: List<CommandCard>): CardAnalysis
    suspend fun calculateOptimalChain(analysis: CardAnalysis, objectives: BattleObjectives): CardChain
    suspend fun evaluateChainEffectiveness(chain: CardChain, result: ChainResult): ChainEvaluation
    suspend fun adaptCardStrategy(battleState: BattleState): CardStrategy
}
```

**Key Features:**
- **Card Chain Analyzer**: Calculates optimal card combinations for damage/NP gain
- **Brave Chain Detector**: Prioritizes brave chains when beneficial
- **Critical Hit Optimizer**: Manages critical stars for maximum damage output
- **NP Timing Coordinator**: Builds NP gauge strategically for optimal timing
- **Multi-Target Analysis**: Optimizes card selection for multiple enemies

**Learning Mechanism:**
- Tracks damage output and NP generation efficiency for different card combinations
- Learns enemy behavior patterns to predict optimal timing
- Adapts card selection based on battle phase and remaining enemies
- Builds database of effective card sequences

### 4. Skill Usage Optimizer

**Purpose**: Determines optimal timing and targeting for servant skills.

**Architecture:**
```kotlin
interface SkillUsageOptimizer {
    suspend fun analyzeSkillEffectiveness(skill: Skill, battleState: BattleState): SkillAnalysis
    suspend fun calculateOptimalTiming(skills: List<Skill>, strategy: BattleStrategy): SkillTimingPlan
    suspend fun selectSkillTargets(skill: Skill, availableTargets: List<Target>): TargetSelection
    suspend fun evaluateSkillUsage(usage: SkillUsage, result: SkillResult): SkillEvaluation
}
```

**Key Features:**
- **Buff Stacking Engine**: Maximizes buff effectiveness through proper timing
- **Cooldown Manager**: Tracks skill cooldowns and plans usage accordingly
- **Target Selection AI**: Chooses optimal targets for support skills
- **Emergency Response System**: Uses defensive skills reactively when needed
- **Skill Priority System**: Manages skill usage priority based on battle conditions

**Learning Mechanism:**
- Analyzes skill usage effectiveness in different scenarios
- Learns optimal buff timing for maximum damage windows
- Adapts skill priorities based on battle outcome analysis
- Builds patterns for emergency skill usage

### 5. NP Timing System

**Purpose**: Optimizes Noble Phantasm usage for maximum impact.

**Architecture:**
```kotlin
interface NPTimingSystem {
    suspend fun calculateNPDamage(np: NoblePhantasm, target: Enemy, buffs: List<Buff>): DamageCalculation
    suspend fun planNPSequence(availableNPs: List<NoblePhantasm>, enemies: List<Enemy>): NPSequence
    suspend fun evaluateNPTiming(timing: NPTiming, battleState: BattleState): TimingEvaluation
    suspend fun optimizeNPChains(nps: List<NoblePhantasm>): NPChainOptimization
}
```

**Key Features:**
- **Damage Calculator**: Predicts NP damage against specific enemies
- **Chain Timing Optimizer**: Coordinates multiple NP usage for maximum effect
- **Overkill Prevention**: Avoids wasting NP damage on low-health enemies
- **Wave Clear Optimizer**: Plans NP usage for efficient multi-wave clearing
- **Buff Synchronization**: Coordinates NP timing with buff activation

**Learning Mechanism:**
- Tracks NP effectiveness across different scenarios
- Learns optimal NP timing for various quest types
- Adapts NP usage based on team composition and enemy analysis
- Builds database of effective NP combinations

## 🤖 Autonomous Operation & Learning System

### 1. Reinforcement Learning Framework

**Core Algorithm**: **Q-Learning with Experience Replay**

**Architecture:**
```kotlin
class ReinforcementLearningEngine {
    private val qTable: MutableMap<StateActionPair, Double>
    private val experienceBuffer: CircularBuffer<Experience>
    private val neuralNetwork: TensorFlowLiteModel
    
    suspend fun selectAction(state: BattleState): Action
    suspend fun updateQValues(experience: Experience)
    suspend fun trainModel(batchSize: Int)
    suspend fun evaluatePolicy(testScenarios: List<BattleScenario>): PolicyEvaluation
}
```

**Components:**
- **State Space**: Battle conditions, team status, enemy status, available actions
- **Action Space**: Card selections, skill usage, NP timing, target selection
- **Reward Function**: Based on battle efficiency, turn count, damage dealt, resources used
- **Experience Buffer**: Stores successful and failed decision sequences for learning
- **Neural Network**: Deep Q-Network for complex state-action value approximation

### 2. Adaptive Decision Making

**Dynamic Weight Adjustment:**
```kotlin
class AdaptiveDecisionEngine {
    private val decisionWeights: MutableMap<DecisionType, Double>
    private val performanceTracker: PerformanceTracker
    
    suspend fun adjustWeights(battleResult: BattleResult)
    suspend fun makeDecision(battleState: BattleState, availableActions: List<Action>): Decision
    suspend fun evaluateDecisionQuality(decision: Decision, outcome: Outcome): DecisionEvaluation
}
```

**Features:**
- Each decision component has adjustable weights based on performance
- Successful strategies increase their influence weights
- Failed strategies decrease their weights or trigger alternative approaches
- Continuous learning updates weights in real-time

**Pattern Recognition:**
- Identifies recurring battle patterns and enemy behaviors
- Builds a knowledge base of effective responses to specific situations
- Uses pattern matching to make faster, more accurate decisions
- Implements clustering algorithms to group similar battle scenarios

### 3. Error Recovery & Learning

**Multi-Level Error Detection:**
```kotlin
sealed class AutomationError {
    object VisualAnomaly : AutomationError()
    object PerformanceDegradation : AutomationError()
    object TimeoutScenario : AutomationError()
    object ResourceDepletion : AutomationError()
    data class UnexpectedState(val state: String) : AutomationError()
}

interface ErrorRecoverySystem {
    suspend fun detectError(battleState: BattleState): AutomationError?
    suspend fun recoverFromError(error: AutomationError): RecoveryAction
    suspend fun learnFromError(error: AutomationError, recovery: RecoveryAction, success: Boolean)
}
```

**Error Types:**
- **Visual Anomalies**: Detects unexpected screen states or UI changes
- **Performance Degradation**: Identifies when battle efficiency drops below thresholds
- **Timeout Scenarios**: Handles battles that take longer than expected
- **Resource Depletion**: Manages AP, skill cooldowns, and other limited resources

**Learning from Mistakes:**
- **Failure Analysis**: Analyzes failed battles to identify decision points that led to failure
- **Strategy Adjustment**: Modifies decision weights and strategy selection based on failures
- **Preventive Measures**: Develops safeguards against previously encountered failure modes
- **Recovery Protocols**: Creates specific recovery procedures for common error scenarios

### 4. Performance Optimization

**Continuous Improvement Metrics:**
```kotlin
data class PerformanceMetrics(
    val battleEfficiency: Double,        // Turns per battle, damage per turn
    val winRate: Double,                 // Success rate across quest types
    val timeOptimization: Long,          // Battle completion time
    val resourceEfficiency: Double,      // AP efficiency, item drop rates
    val errorRate: Double,               // Frequency of errors and recoveries
    val learningProgress: Double         // Rate of improvement over time
)
```

**Self-Optimization Algorithms:**
- **Genetic Algorithm Components**: Evolves strategy parameters over time
- **Simulated Annealing**: Fine-tunes decision weights for optimal performance
- **Multi-Armed Bandit**: Balances exploration of new strategies with exploitation of proven ones
- **Bayesian Optimization**: Optimizes hyperparameters for learning algorithms

## 🔧 Technical Implementation Strategy

### 1. Computer Vision Pipeline

**Technologies:**
- **OpenCV**: Core image processing and feature detection
- **TensorFlow Lite**: On-device machine learning for image classification
- **Custom OCR**: Specialized text recognition for FGO UI elements
- **Template Matching**: Fast UI element recognition using pre-trained templates

**Architecture:**
```kotlin
class ComputerVisionPipeline {
    private val openCVProcessor: OpenCVProcessor
    private val tensorFlowModel: TensorFlowLiteModel
    private val ocrEngine: CustomOCREngine
    private val templateMatcher: TemplateMatcher
    
    suspend fun captureScreen(): Bitmap
    suspend fun processImage(image: Bitmap): ImageAnalysis
    suspend fun detectUIElements(analysis: ImageAnalysis): List<UIElement>
    suspend fun recognizeText(regions: List<Region>): List<TextRecognition>
}
```

**Performance Optimizations:**
- **Multi-threaded Processing**: Parallel image analysis for real-time performance
- **Caching System**: Stores recognized UI states to reduce processing overhead
- **Adaptive Quality**: Adjusts image processing quality based on device performance
- **Region of Interest**: Focuses processing on relevant screen areas

### 2. Decision Engine Architecture

**Core Technologies:**
- **Kotlin Coroutines**: Asynchronous decision processing
- **Room Database**: Persistent storage for learning data and battle history
- **StateFlow/Flow**: Reactive state management for real-time decision updates
- **Dependency Injection**: Modular architecture for easy testing and maintenance

**Architecture:**
```kotlin
class DecisionEngineCore {
    private val strategyPlanner: BattleStrategyPlanner
    private val teamOptimizer: TeamCompositionOptimizer
    private val cardSelector: CommandCardSelector
    private val skillOptimizer: SkillUsageOptimizer
    private val npTimingSystem: NPTimingSystem
    
    suspend fun makeDecision(battleState: BattleState): Decision
    suspend fun executeDecision(decision: Decision): ExecutionResult
    suspend fun evaluateOutcome(result: ExecutionResult): Evaluation
}
```

**AI/ML Integration:**
- **TensorFlow Lite**: On-device inference for decision making
- **Custom Neural Networks**: Specialized models for FGO-specific decision scenarios
- **Rule-Based Systems**: Fallback logic for scenarios where ML models are uncertain
- **Ensemble Methods**: Combines multiple models for robust decision making

### 3. Learning Data Management

**Data Collection:**
```kotlin
data class BattleExperience(
    val battleId: String,
    val questType: String,
    val teamComposition: Team,
    val decisions: List<Decision>,
    val outcomes: List<Outcome>,
    val finalResult: BattleResult,
    val performanceMetrics: PerformanceMetrics,
    val timestamp: Long
)
```

**Data Processing:**
- **Feature Engineering**: Extracts meaningful patterns from raw battle data
- **Statistical Analysis**: Identifies significant performance correlations
- **Model Training**: Continuous retraining of decision models based on new data
- **Data Pruning**: Removes outdated or irrelevant learning data

## 🛡️ Safety & Reliability Systems

### 1. Fail-Safe Mechanisms

```kotlin
class SafetySystem {
    private val watchdogTimer: WatchdogTimer
    private val resourceMonitor: ResourceMonitor
    private val userOverride: UserOverrideSystem
    private val emergencyStop: EmergencyStopSystem
    
    suspend fun monitorSystemHealth(): SystemHealth
    suspend fun handleEmergency(emergency: EmergencyType): EmergencyResponse
    suspend fun validateAction(action: Action): ValidationResult
}
```

**Components:**
- **Watchdog Timers**: Prevents infinite loops and stuck states
- **Resource Monitoring**: Tracks device performance and prevents overheating
- **User Override**: Allows manual intervention at any time
- **Emergency Stop**: Immediate halt functionality for unexpected situations

### 2. Anti-Detection Measures

```kotlin
class AntiDetectionSystem {
    private val timingRandomizer: TimingRandomizer
    private val inputVariation: InputVariationSystem
    private val behaviorMimicry: BehaviorMimicrySystem
    private val sessionManager: SessionManager
    
    suspend fun humanizeAction(action: Action): HumanizedAction
    suspend fun calculateDelay(actionType: ActionType): Delay
    suspend fun varyInputPattern(input: Input): VariedInput
}
```

**Features:**
- **Human-like Timing**: Randomized delays that mimic human behavior
- **Input Variation**: Slightly randomized touch positions and gesture patterns
- **Behavioral Patterns**: Mimics human decision-making inconsistencies
- **Session Management**: Implements realistic play session durations and breaks

### 3. Quality Assurance

```kotlin
class QualityAssuranceSystem {
    suspend fun calculateConfidenceScore(decision: Decision): ConfidenceScore
    suspend fun validateDecision(decision: Decision, context: BattleContext): ValidationResult
    suspend fun monitorPerformance(): PerformanceReport
    suspend fun generateQualityReport(): QualityReport
}
```

**Components:**
- **Confidence Scoring**: Each decision includes a confidence level
- **Fallback Strategies**: Alternative approaches when primary strategies fail
- **Validation Systems**: Continuous verification of decision accuracy
- **Performance Monitoring**: Real-time tracking of system health and effectiveness

## 🚀 Implementation Phases

### Phase 3A: Foundation (Week 5)
**Objectives**: Establish core infrastructure and basic automation capabilities

**Deliverables:**
- Basic computer vision pipeline with OpenCV integration
- Core decision engine framework with modular architecture
- Learning data collection system with Room database integration
- Basic battle state detection and UI element recognition
- Accessibility service integration for input simulation

**Key Components:**
- `ComputerVisionEngine.kt` - Screen capture and image processing
- `DecisionEngineCore.kt` - Central decision making system
- `BattleStateDetector.kt` - Battle state recognition
- `LearningDataCollector.kt` - Data collection for ML training
- `AutomationController.kt` - Input simulation and control

### Phase 3B: Intelligence (Week 6)
**Objectives**: Implement intelligent decision making and adaptive learning

**Deliverables:**
- Strategy planning algorithms with quest analysis
- Adaptive decision making system with weight adjustment
- Error recovery mechanisms with learning capabilities
- Machine learning model integration with TensorFlow Lite
- Performance analytics and optimization system

**Key Components:**
- `BattleStrategyPlanner.kt` - Strategic battle planning
- `AdaptiveDecisionEngine.kt` - Learning-based decision making
- `ErrorRecoverySystem.kt` - Error handling and recovery
- `MLModelManager.kt` - Machine learning model management
- `PerformanceAnalyzer.kt` - Performance tracking and optimization

### Phase 3C: Optimization (Week 7)
**Objectives**: Fine-tune performance and prepare for production deployment

**Deliverables:**
- Advanced learning features with reinforcement learning
- Comprehensive testing framework with automated tests
- Performance optimization with multi-threading and caching
- Anti-detection measures with human-like behavior
- Production-ready deployment configuration

**Key Components:**
- `ReinforcementLearningEngine.kt` - Advanced learning algorithms
- `PerformanceOptimizer.kt` - System performance optimization
- `AntiDetectionSystem.kt` - Human behavior mimicry
- `TestingFramework.kt` - Comprehensive testing suite
- `DeploymentManager.kt` - Production deployment management

## 📊 Success Metrics

### Performance Indicators
- **Battle Success Rate**: >95% win rate across different quest types
- **Battle Efficiency**: <50% of average human completion time
- **Learning Speed**: Measurable improvement within 100 battles
- **Error Recovery**: <5% unrecoverable error rate
- **Resource Efficiency**: Optimal AP usage and farming efficiency

### Quality Metrics
- **Decision Accuracy**: >90% optimal decision rate
- **Adaptation Speed**: Strategy improvement within 24 hours
- **System Stability**: <1% crash rate during operation
- **User Satisfaction**: Positive feedback on automation quality
- **Maintenance Requirements**: Minimal manual intervention needed

This architecture creates a truly autonomous system that not only automates FGO battles but continuously improves its performance through machine learning and adaptive algorithms. The bot will become more effective over time, learning from both successes and failures to optimize its decision-making processes. 