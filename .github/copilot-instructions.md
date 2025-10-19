# Agent Risk - Copilot Instructions

## 🤖 New Agent Onboarding
**Before starting any task**, please:

1. **Read these instructions completely** - This document contains essential project-specific architecture, patterns, and constraints
2. **Explore the current codebase** - Check what modules/files already exist vs. what's described here
3. **Update these instructions** - If you discover new patterns, architectural decisions, or find outdated information during your work, please update this file to help future agents
4. **Follow the separation of concerns** - Ensure your code follows the established architectural patterns and module boundaries described below
5. **Prioritize the formal AI methods** - This is a research project focused on HTN, Behavior Trees, Finite Automata, and Petri nets for agent behaviors (📋 **PLANNED** for future development)

**Key Questions to Ask Yourself:**
- Does my implementation support dynamic board generation with configurable (g, p, s) parameters? ✅ **IMPLEMENTED**
- Am I following the established separation of concerns (state management, rendering, input handling, etc.)? ✅ **CRITICAL**
- Does my code preserve the modular architecture with proper imports and dependencies? ✅ **CRITICAL**
- Do all my functions have proper docstrings following the `:param:` and `:returns:` format? ✅ **MANDATORY**
- For functions >20 lines, have I asked the user about including examples? ✅ **REQUIRED**
- Will my code support replay functionality through serializable events? (📋 **PLANNED** - not yet implemented)
- Does my agent implementation follow one of the formal behavior representation methods? (📋 **PLANNED** - not yet implemented)
- Does my implementation work with the keyboard shortcuts for rapid testing? ✅ **IMPLEMENTED**

## Project Overview
A modular event-driven simulation framework inspired by the board game of Risk 
using pygame. This project implements a configurable Risk-like simulation with 
AI agents using formal behavior representation methods (HTN, Behavior Trees, 
Finite Automata, Petri nets). **The board is dynamically generated based on 
simulation parameters, not a fixed 1:1 recreation of the Risk board game.**

## Running the Simulation
The simulation can be started using the `run_game.py` script with configurable parameters:

```bash
python run_game.py [-g REGIONS] [-p PLAYERS] [-s ARMY_SIZE] [--attack-rate RATE] [--ai-delay DELAY] [--human-player ID]
```

**Command-line Arguments:**
- `-g, --regions`: Number of territories/regions to generate (default: 27)
- `-p, --players`: Number of players in the simulation (default: 3) 
- `-s, --army-size`: Starting army count **per player** (default: 20) - Each player gets exactly this many armies
- `--attack-rate`: AI attack probability 0.0-1.0 (default: 0.85) - How aggressive AI agents are
- `--ai-delay`: Delay between AI actions in seconds (default: 1.0) - Controls AI turn speed for visibility
- `--human-player`: Player ID to be human (0 to players-1), others will be AI (default: all AI)

**Examples:**
```bash
# Run with default parameters (27 regions, 3 players, 20 armies each)
python run_game.py

# Run a larger simulation (30 regions, 4 players, 15 armies per player = 60 total armies)
python run_game.py -g 30 -p 4 -s 15

# Run a smaller test simulation (8 regions, 2 players, 10 armies per player = 20 total armies)
python run_game.py --regions 8 --players 2 --army-size 10

# Run with AI agents (all AI players)
python run_game.py -g 15 -p 4 --attack-rate 0.7 --ai-delay 2.0

# Run with mixed human/AI players (player 0 is human, others are AI)
python run_game.py -p 3 --human-player 0 --attack-rate 0.6

# Run fast AI simulation for testing
python run_game.py -g 10 -p 2 --ai-delay 0.5 --attack-rate 0.9
```

The script includes validation to ensure minimum values (regions ≥ 1, players ≥ 2, army-size ≥ 1).

**Runtime Controls (Keyboard Shortcuts):**
Once the simulation is running, you can use these keyboard shortcuts for real-time testing:

- **Ctrl+R**: Regenerate game state/board with current parameters
- **Ctrl+G**: Increase regions (+1) and regenerate
- **Ctrl+P**: Increase players (+1) and regenerate  
- **Ctrl+S**: Increase starting armies (+1) and regenerate
- **H**: Show help with all available controls
- **I**: Show info for selected territory (click to select)
- **D**: Show debug information
- **Space**: Pause/unpause game simulation
- **ESC**: Quit game

These shortcuts enable rapid iteration and testing of different board configurations without restarting the application.

## Architecture Modules
The project follows a **modular architecture with clear separation of concerns**. Each module has distinct responsibilities and should maintain clean boundaries:

**Current Implementation (✅ IMPLEMENTED):**
- **`risk.game`** - Event loop, pygame rendering, and user input handling
  - `loop.py` - Main game event loop with keyboard shortcuts, parameter management, and pause functionality
  - `renderer.py` - Pygame board rendering and visualization
  - `input.py` - User input handling with Ctrl+ shortcuts, event processing, and pause controls
  - `selection.py` - Territory selection management and selection state handling
  - `ui.py` - Turn-based UI components (buttons, labels, counters, attack popups)
  - `ui_renderer.py` - Pygame rendering for turn UI elements with consistent styling
- **`risk.state`** - Game state data structures, territory management, and board generation
  - `game_state.py` - Core GameState, Player classes, and game phase management
  - `territory.py` - Territory definitions, ownership states, and adjacency management
  - `board_generator.py` - Dynamic board generation using polygon subdivision algorithms
  - `fight.py` - Dice-based combat system with Fight, DiceRoll, and battle resolution
  - `turn_manager.py` - Turn progression, phase management, and player turn coordination
  - `plan.py` - Goal and plan representation for agent behaviors (Plan, Step, Goal classes)
  - `event_stack/` - Event queue management system
    - `stack.py` - Event stack data structures and management
    - `events/` - Event type definitions
      - `turns.py` - Turn-based event definitions
- **`risk.utils`** - Shared utility functions and helper classes
  - `distance.py` - Point geometry, distance calculations, and random walk algorithms
  - `polygon.py` - Polygon operations, area calculations, centroid finding, and bounding box computation
- **`risk.agents`** - AI agent implementations and controllers ✅ **IMPLEMENTED**
  - `simple/` - Basic AI agent implementations
    - `random_agent.py` - Random decision-making agent with BaseAgent interface
    - `ai_game_loop.py` - Extended game loop with AI agent integration

**Planned Modules (📋 PLANNED - Formal Methods):**
- **`risk.agents.htn`** - Hierarchical Task Network agents
- **`risk.agents.bt`** - Behavior Tree agents  
- **`risk.agents.fa`** - Finite Automata agents
- **`risk.agents.pn`** - Petri Net agents

## Critical Architectural Patterns

### ✅ **SEPARATION OF CONCERNS - STRICTLY ENFORCE**
The codebase follows clear module boundaries that **MUST** be preserved:

**1. Geometric/Mathematical Operations → `risk.utils.distance`**
```python
# ✅ CORRECT: Put point geometry and distance functions here
def euclidean_distance(point1: Point, point2: Point) -> float
def random_walk(start: Point, end: Point, ...) -> List[Point]
def clean_sequence(vertices: List[Point]) -> List[Point]

# ❌ WRONG: Don't put polygon operations here (now in risk.utils.polygon)
```

**1a. Polygon Operations → `risk.utils.polygon`**
```python
# ✅ CORRECT: Put polygon-specific operations here
def compute_area(polygon: List[Point]) -> float
def find_centroid(polygon: List[Point]) -> Point
def compute_bounding_box(polygon: List[Point]) -> Tuple[float, float, float, float]

# ❌ WRONG: Don't put these in board_generator.py or distance.py
```

**2. Game State & Board Logic → `risk.state.*`**
```python
# ✅ CORRECT: Game entities and board generation
class GameState, Player, Territory  # in game_state.py
class PolygonTerritory, BoardGenerator  # in board_generator.py
class Fight, DiceRoll, TurnManager, TurnState  # in fight.py, turn_manager.py

# ❌ WRONG: Don't put pygame rendering code here
# ❌ WRONG: Don't put input handling here
```

**3. Rendering & Visualization → `risk.game.renderer`**
```python
# ✅ CORRECT: Pure rendering - reads state, never modifies it
def draw_board(self) -> None:
def get_territory_at_position(self, pos) -> Optional[Territory]:

# ❌ WRONG: Don't modify game state in renderer
# ❌ WRONG: Don't put game logic here
```

**4. Input & Events → `risk.game.input`**
```python
# ✅ CORRECT: Event processing with callbacks
def handle_event(self, event: pygame.event.Event) -> None:
def register_callback(self, event_type: str, callback: Callable) -> None:

# ❌ WRONG: Don't put rendering code here
# ❌ WRONG: Don't put game logic here
```

**4a. Selection Management → `risk.game.selection`**
```python
# ✅ CORRECT: Territory selection state and logic
class TerritorySelectionHandler:
def handle_territory_selected(self, input_event) -> None:
def select_territory(self, territory_id: int) -> None:

# ❌ WRONG: Don't put rendering logic here
# ❌ WRONG: Don't put game state mutations here
```

**4b. Turn UI Components → `risk.game.ui` + `risk.game.ui_renderer`**
```python
# ✅ CORRECT: UI logic separated from rendering
class TurnUI:  # UI state and interaction logic
class UIRenderer:  # Pygame drawing of UI elements
class AttackPopup:  # Attack dialog management

# ❌ WRONG: Don't put game logic in UI components
# ❌ WRONG: Don't put rendering in ui.py, use ui_renderer.py
```

**5. Coordination & Lifecycle → `risk.game.loop`**
```python
# ✅ CORRECT: Orchestrates all components
def __init__(self, ...): # dependency injection
def run(self) -> None:   # main game loop
def _register_turn_ui_callbacks(self) -> None:  # UI integration
def _handle_resolve_attack(self) -> None:  # turn action handlers

# ❌ WRONG: Don't put specific rendering/input logic here
```

**Critical Import Patterns:**
```python
# ✅ GOOD: utils ← state ← game (dependency flow)
from ..utils.distance import Point, random_walk  # state uses utils
from ..state import GameState, Territory         # game uses state

# ❌ BAD: No circular dependencies
# Don't import game modules in state modules
# Don't import state modules in utils modules
```

## Current Separation of Concerns

### ✅ **State Management** (`risk.state`)
- **Purpose**: Pure data structures and game state logic
- **Responsibilities**: 
  - Game state representation (`GameState`, `Player`, `Territory`)
  - Territory ownership and army management
  - Board generation and territory adjacency calculation
  - Game phase tracking and turn management
- **Dependencies**: Only depends on `risk.utils` for geometric calculations
- **Key Pattern**: Immutable-focused design with clear state transitions

### ✅ **Rendering** (`risk.game.renderer`)
- **Purpose**: Pygame-based visualization of game state
- **Responsibilities**:
  - Drawing territories, armies, and player information
  - Color management and visual styling
  - Territory selection and hit testing
  - UI legends and game information display
- **Dependencies**: Depends on `risk.state` for game data, pygame for graphics
- **Key Pattern**: Renderer operates on read-only game state, no state mutations

### ✅ **Input Handling** (`risk.game.input`)
- **Purpose**: Event processing and user interaction
- **Responsibilities**:
  - Pygame event processing and keyboard shortcuts
  - Mouse click handling and territory selection
  - Command pattern for input events
  - Help and debug information display
- **Dependencies**: pygame for events, minimal coupling to other modules
- **Key Pattern**: Callback-based event system with clean abstractions

### ✅ **Selection Management** (`risk.game.selection`)
- **Purpose**: Territory selection state and logic management
- **Responsibilities**:
  - Managing selected territories and primary selection state
  - Handling territory selection events and multi-select behavior
  - Providing territory selection status and clearing selections
  - Coordinating with input system for selection events
- **Dependencies**: Depends on `risk.state` for territory and game state data
- **Key Pattern**: Stateful selection handler with event-driven updates

### ✅ **Game Loop** (`risk.game.loop`)
- **Purpose**: Main coordination and application lifecycle
- **Responsibilities**:
  - Pygame initialization and window management
  - Main event loop and frame rate control
  - Parameter management and board regeneration
  - Coordination between renderer, input handler, and game state
  - Turn management integration and UI callback registration
  - Combat resolution and phase transitions
- **Dependencies**: Orchestrates all other modules
- **Key Pattern**: Central coordinator with dependency injection

### ✅ **Utilities** (`risk.utils`)
- **Purpose**: Shared geometric and mathematical operations
- **Responsibilities**:
  - Point geometry and distance calculations
  - Random walk generation for polygon subdivision
  - Polygon validation and cleanup operations
  - Generic algorithms used across modules
- **Dependencies**: No internal dependencies, only standard library
- **Key Pattern**: Pure functions with clear mathematical abstractions

### ✅ **Fight System** (`risk.state.fight`)
- **Purpose**: Dice-based combat mechanics and battle resolution
- **Responsibilities**:
  - Dice rolling and casualty calculation using Risk rules
  - Round-by-round combat management with Fight class
  - Battle history tracking and result reporting
  - Combat phase management and completion detection
- **Dependencies**: Only standard library for random number generation
- **Key Pattern**: Immutable DiceRoll results with stateful Fight progression

### ✅ **Turn Management** (`risk.state.turn_manager`)
- **Purpose**: Player turn coordination and phase management
- **Responsibilities**:
  - Turn state tracking with TurnState class
  - Phase transitions (placement → attacking → moving)
  - Reinforcement calculation and distribution
  - Attack state management and movement coordination
  - Turn validation and completion detection
- **Dependencies**: Depends on `risk.state` for game state and fight system
- **Key Pattern**: Stateful turn progression with phase-specific validation

### ✅ **Turn UI System** (`risk.game.ui` + `risk.game.ui_renderer`)
- **Purpose**: Interactive turn-based user interface
- **Responsibilities**:
  - Button, label, and counter UI element management
  - Attack popup dialogs with army selection
  - Phase-specific UI layout and state management
  - Keyboard shortcuts and mouse interaction handling
  - UI action callback system for turn operations
- **Dependencies**: Depends on pygame for rendering and `risk.state` for turn state
- **Key Pattern**: Separation between UI logic (`ui.py`) and rendering (`ui_renderer.py`)

## Project Structure
**Current Implementation (✅ IMPLEMENTED):**
```
risk/
├── __init__.py                 # Package version info
├── agents/                     # AI agent implementations and controllers
│   ├── __init__.py            # Module exports (RandomAgent, BaseAgent, etc.)
│   └── simple/                # Basic AI agent implementations
│       ├── __init__.py        # Simple agents module exports
│       ├── random_agent.py    # Random decision-making agent with BaseAgent interface
│       └── ai_game_loop.py    # Extended game loop with AI agent integration
├── game/                       # Pygame event loop and rendering
│   ├── __init__.py            # Module exports (GameLoop, GameRenderer, etc.)
│   ├── loop.py                # Main game event loop with keyboard shortcuts, parameter management, and pause functionality
│   ├── renderer.py            # Pygame board rendering and visualization
│   ├── input.py               # User input handling with Ctrl+ shortcuts, event processing, and pause controls
│   ├── selection.py           # Territory selection management and state handling
│   ├── ui.py                  # Turn-based UI components (buttons, labels, counters, attack popups)
│   └── ui_renderer.py         # Pygame rendering for turn UI elements with consistent styling
├── state/                      # Game state management
│   ├── __init__.py            # Module exports (GameState, Territory, etc.)
│   ├── game_state.py          # GameState, Player classes, and game phases
│   ├── territory.py           # Territory definitions and ownership management
│   ├── board_generator.py     # Dynamic board generation using polygon subdivision
│   ├── fight.py               # Dice-based combat system with Fight, DiceRoll, and battle resolution
│   ├── turn_manager.py        # Turn progression, phase management, and player turn coordination
│   ├── plan.py                # Goal and plan representation for agent behaviors (Plan, Step, Goal classes)
│   └── event_stack/           # Event queue management system
│       ├── __init__.py        # Event stack module exports
│       ├── stack.py           # Event stack data structures and management
│       └── events/            # Event type definitions
│           ├── __init__.py    # Event types module exports
│           └── turns.py       # Turn-based event definitions
├── utils/                      # Shared utility functions
│   ├── distance.py            # Point geometry, distance calculations, random walks
│   └── polygon.py             # Polygon operations, area calculations, centroid finding
└── tests/                      # Unit and integration tests
    ├── __init__.py
    ├── game/                  # Game module tests
    │   ├── __init__.py
    │   ├── test_ai_game_loop_pause.py  # AI game loop pause functionality tests
    │   └── test_game_loop_pause.py     # Game loop pause functionality tests
    └── state/                 # State module tests
        ├── __init__.py
        ├── test_board.py      # Board generation tests
        ├── test_fight.py      # Combat system tests
        ├── test_plans.py      # Plan and goal system tests
        ├── test_turn_manager.py # Turn management tests
        └── events/            # Event system tests
            ├── __init__.py
            ├── test_stacks.py # Event stack tests
            └── test_turns.py  # Turn event tests
```

**Planned Structure for Future Development (📋 PLANNED):**
```
risk/
├── agents/                     # AI agent implementations (partially implemented)
│   ├── htn/                   # Hierarchical Task Network agents
│   │   ├── __init__.py
│   │   └── htn_agent.py       # HTN-based agent implementation
│   ├── bt/                    # Behavior Tree agents
│   │   ├── __init__.py
│   │   └── bt_agent.py        # Behavior Tree agent implementation
│   ├── fa/                    # Finite Automata agents
│   │   ├── __init__.py
│   │   └── fa_agent.py        # Finite Automata agent implementation
│   └── pn/                    # Petri Net agents
│       ├── __init__.py
│       └── pn_agent.py        # Petri Net agent implementation
```

**Entry Point:**
- `run_game.py` - Command-line script with argument parsing for (g, p, s) parameters

## Game Flow Implementation
Follow the specific game phases as defined:

### Phase Structure
- **`init`** - Setup board with parameters (g=regions, p=players, s=army_size)
- **`game`** - Main event loop containing:
  - **`game turn`** - Cycle through active players
  - **`player turn`** - Individual player actions:
    - `get troops` - Game distributes reinforcement troops
    - `place troops` - Agent decides troop placement
    - `move troops` - Agent attacks/moves to adjacent regions
    - `end turn` - Agent signals turn completion
  - **`game turn cleanup`** - Check win conditions
  - **`game end`** - Victory condition met
- **`score`** - Post-simulation agent performance evaluation

## Turn-Based Game Flow Implementation (✅ **IMPLEMENTED**)
The current implementation includes a complete turn-based system with dice-based combat and interactive UI:

### Turn Management Architecture
**TurnManager** coordinates player turns with three distinct phases:

**1. Placement Phase (`TurnPhase.PLACEMENT`)**
- Player receives reinforcements: `max(3, territories_controlled // 3)`
- Must place all reinforcements before advancing to attacking phase
- UI shows reinforcement counter and placement controls
- Supports undo functionality for placement corrections
- Click on owned territory to place 1 reinforcement army

**2. Attacking Phase (`TurnPhase.ATTACKING`)**
- Player can attack adjacent enemy territories
- Uses Risk-standard dice-based combat through `Fight` system
- Attack popup shows army selection and battle controls
- Supports multi-round combat with casualty tracking
- Can cancel attacks or continue until conquest/retreat

**3. Moving Phase (`TurnPhase.MOVING`)**
- Player can move armies between owned adjacent territories
- Movement counter allows selecting number of armies to move
- Must leave at least 1 army in source territory
- Optional phase - can end turn without moving

### Combat System (`risk.state.fight`)
**Dice-Based Combat** following Risk rules:
- Attacker rolls 1-3 dice based on attacking army count
- Defender rolls 1-2 dice based on defending army count
- Higher dice win, ties go to defender
- **`Fight`** class manages multi-round combat progression
- **`DiceRoll`** class tracks individual round results
- Battle history preserved for replay and analysis

### Turn UI System (`risk.game.ui` + `risk.game.ui_renderer`)
**Interactive Turn Interface** with phase-specific controls:

**Placement Phase UI:**
- Reinforcement counter showing armies remaining
- "Undo (U)" button for placement corrections
- "Start Attacking" button (enabled when all reinforcements placed)

**Attacking Phase UI:**
- Attack popup dialog for target selection
- Army count selector (1 to max available)
- "Attack!" button for dice rolling
- "End Attack" button to cancel current attack
- Real-time dice roll display and casualty tracking

**Moving Phase UI:**
- Movement army counter with +/- controls
- "Move Armies" button to execute movement
- Visual feedback for valid movement pairs

**Common UI Elements:**
- Phase indicator showing current turn phase
- "End Turn" button (always available)
- Keyboard shortcuts: U (undo), Enter/Space (advance phase), 1-9 (army selection)
- Mouse hover effects and visual feedback

### UI Integration in Game Loop (`risk.game.loop`)
**Central Coordination** of turn system components:

```python
# Turn system initialization in GameLoop.__init__()
self.turn_manager = TurnManager(self.game_state)
self.renderer = GameRenderer(self.screen, self.game_state)  # Includes turn UI
self.input_handler = GameInputHandler(self.renderer, self.renderer.get_turn_ui())

# Turn UI callback registration
self._register_turn_ui_callbacks()  # Connects UI actions to turn logic

# Turn progression
self.turn_manager.start_player_turn(player_id)  # Starts turn with reinforcements
current_turn = self.turn_manager.get_current_turn()
self.renderer.set_turn_state(current_turn)  # Updates UI display
```

**Turn Action Handlers** in GameLoop:
- `_handle_place_reinforcement()` - Places armies on selected territory
- `_handle_undo_placement()` - Removes last reinforcement placement
- `_handle_resolve_attack()` - Executes dice-based combat rounds
- `_handle_advance_phase()` - Progresses through turn phases
- `_handle_end_turn()` - Completes turn and advances to next player

**Key Integration Patterns:**
- **Callback-based UI**: UI actions trigger game loop handlers
- **State synchronization**: Turn state changes update UI automatically  
- **Separation of concerns**: UI manages display, turn manager handles logic
- **Event-driven updates**: Territory selections and combat results flow through system

### Combat Integration Example
```python
# User clicks "Attack!" in attack popup
def _handle_resolve_attack(self) -> None:
    result = current_turn.resolve_attack()  # Fight system calculates casualties
    attacker_territory.armies -= result['attacker_casualties']
    defender_territory.armies -= result['defender_casualties']
    
    if result.get('territory_conquered'):
        # Handle territory conquest, move surviving armies
        defender_territory.owner = current_turn.player_id
        defender_territory.armies = result['surviving_attackers']
    
    # UI automatically updates to show new army counts and battle results
```

This turn-based system provides a complete foundation for human play and can be easily extended for AI agent integration through the same turn manager interface.

## AI Agent System Implementation (✅ **IMPLEMENTED**)
The current implementation includes a complete AI agent framework with working random agents for testing and simulation:

### AI Agent Architecture
**BaseAgent Interface** defines the contract for all AI agents:

**Core Decision Methods:**
- `decide_placement()` - Choose where to place reinforcement armies during placement phase
- `decide_attack()` - Select attack targets and decide whether to continue attacking
- `decide_movement()` - Choose army movements between owned territories after attacking
- `choose_attack_armies()` - Determine how many armies to use in specific attacks
- `choose_movement_armies()` - Determine how many armies to move between territories

**Agent Lifecycle Integration:**
- Agents integrate seamlessly with existing TurnManager and turn phases
- Each agent controls one player and makes decisions during that player's turn
- Agents receive full GameState context for informed decision-making
- Support for mixed human/AI games through `--human-player` parameter

### Random Agent Implementation (`risk.agents.simple.random_agent`)
**RandomAgent** provides baseline AI behavior for testing and simulation:

**Placement Strategy:**
- Randomly selects owned territories for reinforcement placement
- Distributes armies evenly across controlled territories
- Prioritizes territories with fewer armies for balanced distribution

**Attack Strategy:**
- Configurable attack probability (default 85% chance to attack each turn)
- Randomly selects attack targets from adjacent enemy territories
- Uses random army counts within valid constraints (1 to max available)
- Continues attacking until probability threshold or no valid targets remain

**Movement Strategy:**
- Random chance to move armies after attacking phase
- Selects random source and destination territories from owned adjacent pairs
- Moves random number of armies while respecting minimum garrison requirements

### AI Game Loop Extension (`risk.agents.simple.ai_game_loop`)
**AIGameLoop** extends the base GameLoop with automatic AI turn execution:

**AI Turn Management:**
- Automatic execution of AI player turns with configurable timing delays
- Seamless integration with human player turns (mixed human/AI games)
- Respects pause state - AI turns halt when game is paused
- Visual feedback showing AI decision-making process

**Agent Controller Integration:**
- `AgentController` manages multiple AI agents across different players
- Automatic agent assignment during game initialization
- Support for different agent types per player (future extensibility)
- Clean separation between AI logic and game state management

**Configuration Options:**
- `--ai-delay`: Controls speed of AI actions for visualization (default 1.0 seconds)
- `--attack-rate`: Sets AI aggression level (default 0.85 = 85% attack probability)
- `--human-player`: Designates which player is human-controlled

### AI Integration Example
```python
# Create AI-enabled game with mixed players
from risk.agents.simple import create_ai_game

# Game with player 0 as human, others as AI
game = create_ai_game(
    regions=15, 
    players=3, 
    army_size=20,
    human_player_id=0,  # Player 0 is human
    ai_delay=1.5,       # 1.5 second delays between AI actions
    attack_rate=0.7     # 70% chance for AI to attack each turn
)

# All AI players
game = create_ai_game(
    regions=20,
    players=4, 
    army_size=15,
    human_player_id=None,  # All players are AI
    ai_delay=0.5,          # Fast AI for quick simulation
    attack_rate=0.9        # Very aggressive AI
)
```

**Key AI System Features:**
- **Mixed Human/AI Games**: Seamless integration of human and AI players
- **Configurable AI Behavior**: Attack rates, timing delays, and aggression levels
- **Visual AI Feedback**: Watch AI decision-making with timing controls
- **Extensible Architecture**: BaseAgent interface ready for formal method implementations
- **Pause-Aware AI**: AI respects pause state and can be interrupted
- **Turn Manager Integration**: AI agents use same turn system as human players

This AI system provides a complete foundation for testing gameplay mechanics and serves as a baseline for implementing more sophisticated agent behaviors using formal methods (HTN, Behavior Trees, Finite Automata, Petri nets).

## Development Patterns

### Architectural Principles (✅ **CRITICAL PATTERNS**)
The codebase follows these essential architectural patterns:

**Separation of Concerns:**
- **Geometric calculations** (Point class, distance functions, random walks) → `risk.utils.distance`
- **Polygon operations** (area, centroid, bounding box calculations) → `risk.utils.polygon`
- **Game state management** (GameState, Player, Territory classes) → `risk.state`
- **Board generation logic** (polygon subdivision, territory creation) → `risk.state.board_generator`
- **Combat mechanics** (dice rolling, fight resolution, casualty tracking) → `risk.state.fight`
- **Turn coordination** (phase management, reinforcement calculation, turn progression) → `risk.state.turn_manager`
- **Rendering logic** (pygame drawing, colors, visualization) → `risk.game.renderer`
- **Input handling** (events, callbacks, keyboard shortcuts) → `risk.game.input`
- **Selection management** (territory selection state and logic) → `risk.game.selection`
- **UI components** (buttons, labels, popups, phase-specific interfaces) → `risk.game.ui`
- **UI rendering** (pygame drawing of UI elements with consistent styling) → `risk.game.ui_renderer`
- **Application lifecycle** (initialization, main loop, coordination) → `risk.game.loop`

**Dependency Flow:**
```
risk.game.loop (coordinator)
├── risk.game.renderer (depends on state)
├── risk.game.input (minimal dependencies)
├── risk.game.selection (depends on state)
├── risk.game.ui + ui_renderer (depends on pygame + state)
└── risk.state (depends on utils)
    ├── risk.state.turn_manager (depends on fight + game_state)
    ├── risk.state.fight (pure combat logic)
    └── risk.utils (no internal dependencies)
```

**Key Design Patterns:**
- **Event-Driven Architecture**: Input handlers use callbacks for loose coupling
- **Dependency Injection**: GameLoop coordinates components through constructor injection
- **Immutable State Focus**: GameState designed for clear state transitions
- **Factory Methods**: `GameState.create_new_game()` for consistent initialization
- **Pure Functions**: Utility functions in `risk.utils` have no side effects

### Current Board Generation Implementation (✅ **IMPLEMENTED**)
The board generation uses **polygon subdivision** with these key components:

**In `risk.state.board_generator` (State Management):**
- `PolygonTerritory` class: Manages polygon data during subdivision process
- `BoardGenerator` class: Orchestrates board creation and territory assignment
- `create_polygon_to_fill_space()`: Creates initial continent using random walks
- Adjacency calculation: Determines territory borders through shared edges
- Territory distribution: Assigns territories and armies to players
- Continent assignment: Geographic grouping of territories

**In `risk.utils.distance` (Pure Utilities):**
- `Point` dataclass: Represents geometric coordinates
- `random_walk()`: Generates jagged lines for polygon subdivision
- `clean_sequence()`: Removes duplicate/close vertices for polygon cleanup
- Distance functions: Euclidean and Manhattan distance calculations
- Pure mathematical functions with no side effects

**In `risk.utils.polygon` (Polygon Utilities):**
- `compute_area()`: Calculates polygon area using shoelace formula
- `find_centroid()`: Computes geometric center of polygons
- `compute_bounding_box()`: Determines axis-aligned bounding box
- Pure geometric functions for polygon operations

**Critical Separation Patterns:**
```python
# ✅ GOOD: BoardGenerator uses utilities for geometry
from ..utils.distance import Point, random_walk, clean_sequence
from ..utils.polygon import compute_area, find_centroid

# ✅ GOOD: GameLoop coordinates state generation
from ..state.board_generator import generate_sample_board

# ❌ AVOID: Don't put geometric algorithms in board_generator
# ❌ AVOID: Don't put state management in distance utilities
```

**Key Implementation Details:**
- **Polygon Subdivision**: Recursively divides large continent into territories
- **Random Walk Boundaries**: Creates natural, irregular territory borders
- **Shared Edge Detection**: Ensures territories properly connect via shared boundaries
- **Army Distribution**: Each player gets exactly `s` armies distributed among their territories
- **Validation**: Comprehensive polygon validation with error reporting
- **Modular Geometry**: Clean separation between point operations (distance.py) and polygon operations (polygon.py)

### Event System Design (� **PARTIALLY IMPLEMENTED**)
Event queue foundation has been implemented in `risk.state.event_stack`:

**Current Implementation:**
- **Event Stack System** (`event_stack/stack.py`) - Core event queue management with UUID-based event tracking
- **Event Context** - Immutable context containers for event data
- **Turn Events** (`event_stack/events/turns.py`) - Turn-based event definitions
- **Serializable Design** - Events designed for replay functionality

**Event Stack Features:**
- UUID-based event identification for reliable tracking
- Immutable EventContext for consistent event data
- Namespace-based event organization (event, level, stack namespaces)
- Foundation for complete event-driven simulation

**Planned Extensions (📋 PLANNED):**
- Complete event types for all game actions (place_troop, attack, movement)
- Event replay system for game analysis and debugging
- Integration with agent decision-making system
- Serialization support for game state persistence

Example current event structure:
```python
# Event foundation exists in event_stack/stack.py
class Event:
    def __init__(self, name: str, context: Dict[str, object] = None):
        self.name = name
        self.context = EventContext(context)

class EventContext:
    # Immutable context container with attribute access
    def __init__(self, context: Dict[str, object] = None):
        # Implementation provides immutable event data
```

Planned event types:
```python
@dataclass
class PlaceTroopEvent:
    player_id: int
    territory_id: int
    troop_count: int
    timestamp: float

@dataclass  
class AttackEvent:
    attacker_id: int
    from_territory: int
    to_territory: int
    attacking_armies: int
    dice_results: List[int]
```

### Agent Formal Methods (� **FOUNDATION IMPLEMENTED**)
Plan and goal representation has been implemented in `risk.state.plan`:

**Current Implementation:**
- **Goal Class** - Represents agent objectives with achievement checking
- **Plan Class** - Sequences of steps to achieve goals with step management
- **Step Class** - Individual plan actions with execution framework
- **State Integration** - Plan evaluation against GameState for goal completion

**Plan System Features:**
```python
# Basic plan structure implemented in risk.state.plan
class Goal:
    def achieved(self, state: GameState) -> bool: # Goal completion checking
        
class Plan:
    def add_step(self, step: Step) -> Plan:       # Step management
    def goal_achieved(self, state: GameState) -> bool: # Goal evaluation
    def pop_step(self) -> Union[None, Step]:     # Step execution ordering
    
class Step:
    def execute(self, state: GameState) -> Union[GameState, None, Plan]:
        # Returns: new state, None, or sub-plan for hierarchical planning
```

**Planned Formal Method Extensions (📋 PLANNED):**
Implement agents using academic formalisms from "Action, Planning, and Learning":
- **HTN (Hierarchical Task Networks)** - Decompose high-level strategies into primitive actions using existing Plan/Step framework
- **Behavior Trees** - Reactive decision-making with clear success/failure states  
- **Finite Automata** - State-based decision making for different game phases
- **Petri Nets** - Concurrent action modeling and resource management

Example agent interface:
```python
class BaseAgent(ABC):  # Already implemented in risk.agents.simple.random_agent
    @abstractmethod
    def decide_placement(self, game_state: GameState, turn_state: TurnState) -> Optional[int]:
        pass
    
    @abstractmethod
    def decide_attack(self, game_state: GameState, turn_state: TurnState) -> Optional[Tuple[int, int]]:
        pass
    
    @abstractmethod
    def decide_movement(self, game_state: GameState, turn_state: TurnState) -> Optional[Tuple[int, int, int]]:
        pass
```

### Pygame Integration (✅ **IMPLEMENTED**)
The pygame integration follows a clean separation between rendering and game logic:

**Current Architecture:**
```python
# ✅ GOOD: Clear separation of concerns
class GameRenderer:
    def __init__(self, screen: pygame.Surface, game_state: GameState):
        # Renderer depends on GameState (read-only)
        
    def draw_board(self) -> None:
        # Pure rendering - no state mutations
        self._draw_territories()
        self._draw_continent_labels() 
        self._draw_player_summaries()
        self._draw_legend()
        
    def get_territory_at_position(self, pos: Tuple[int, int]) -> Optional[Territory]:
        # Hit testing for user interaction

class GameInputHandler:
    def __init__(self, renderer: GameRenderer, turn_ui: TurnUI):
        # Input handler coordinates with renderer for hit testing
        
    def handle_event(self, event: pygame.event.Event) -> None:
        # Event processing with callback pattern

class TerritorySelectionHandler:
    def __init__(self, game_state: GameState, turn_manager: TurnManager):
        # Selection handler manages territory selection state
        
    def handle_territory_selected(self, input_event) -> None:
        # Territory selection event processing

class TurnUI:
    def __init__(self, screen_width: int, screen_height: int):
        # Turn UI manages interactive turn-based interface
        
    def handle_click(self, pos: Tuple[int, int]) -> bool:
        # UI element interaction handling
        
class GameLoop:
    def __init__(self, ...):
        # Central coordinator - dependency injection pattern
        self.turn_manager = TurnManager(self.game_state)
        self.renderer = GameRenderer(self.screen, self.game_state)
        self.input_handler = GameInputHandler(self.renderer, self.renderer.get_turn_ui())
        self.selection_handler = TerritorySelectionHandler(self.game_state, self.turn_manager)
        
        # Register turn UI callbacks for turn actions
        self._register_turn_ui_callbacks()
```

**Key Patterns:**
- **Read-Only Rendering**: Renderer never modifies game state
- **Callback Architecture**: Input handler uses callbacks for loose coupling
- **Dependency Injection**: GameLoop provides dependencies to components
- **Hit Testing**: Clean separation between coordinate math and game logic
- **UI Integration**: Turn UI seamlessly integrates with input handling and state management
- **Phase-based UI**: UI elements adapt to current turn phase (placement, attacking, moving)

### World State Management (✅ **IMPLEMENTED**)
The current implementation features robust state management with clear patterns:

**Game State Architecture:**
```python
# ✅ GOOD: Immutable-focused design
@dataclass
class GameState:
    # Configuration (immutable after creation)
    regions: int
    num_players: int  
    starting_armies: int
    
    # Mutable game state
    phase: GamePhase = GamePhase.INIT
    current_turn: int = 0
    current_player_id: Optional[int] = None
    
    # Entity collections
    territories: Dict[int, Territory] = field(default_factory=dict)
    players: Dict[int, Player] = field(default_factory=dict)
    
    @classmethod
    def create_new_game(cls, regions: int, num_players: int, starting_armies: int) -> 'GameState':
        # Factory method for consistent initialization
```

**Key Features:**
- **Dynamic Board Generation**: Based on (g, p, s) simulation parameters  
- **Adjacency Management**: Automatically calculated during board generation
- **Army Tracking**: Precise distribution ensuring each player gets exactly `s` armies
- **State Validation**: Comprehensive checks for polygon validity and game consistency
- **Phase Management**: Clear game phases from INIT through SCORE
- **Player Statistics**: Real-time updates of territory counts and army totals

**Army Distribution Rule:**
Each player receives exactly `starting_armies` (s parameter) distributed across their territories. The system validates this constraint and reports any discrepancies during initialization.

## Board Generation and Game Rules Implementation
Key mechanics for the configurable simulation:

### Dynamic Board Setup
- Generate `g` territories based on simulation parameters
- Create adjacency graph for territory connections
- Distribute `p` players across the generated board
- Assign starting army size `s` **per player** (each player gets exactly `s` armies)
- Optional: Generate continent groupings for bonus calculations

**Current Board Generation Implementation:**
The current system uses **polygon subdivision** for dynamic board generation:
1. **Initial Continent**: Creates a large jagged polygon covering ~75% of the screen
2. **Recursive Subdivision**: Uses random walk division lines to split polygons
3. **Shared Boundaries**: Ensures territories share exact boundary segments for proper adjacency
4. **Area Preservation**: Tracks and minimizes area loss during subdivision process
5. **Adjacency Calculation**: Automatically determines which territories border each other
6. **Territory Assignment**: Randomly distributes territories among players with initial armies

**⚠️ Important Army Distribution Rule:**
The `s` parameter represents armies **per player**, not total armies to share. Each player receives exactly `s` armies distributed across their territories. For example, with parameters `(g=10, p=3, s=15)`, each of the 3 players gets exactly 15 armies, for a total of 45 armies on the board.

The board generator is robust and handles edge cases like very small polygons without crashing.

### Core Game Mechanics
- **Reinforcements**: Configurable reinforcement rules based on territories 
controlled
- **Attacking**: Dice-based combat between adjacent territories
- **Movement**: Movement between connected owned territories
- **Victory**: Game ends when one player controls all territories on the 
generated board

**Combat System Implementation:**
The current system implements classic Risk dice-based combat rules:
- Attacker rolls 1-3 dice based on available attacking armies
- Defender rolls 1-2 dice based on defending armies
- Dice are compared in descending order (highest vs highest)
- Attacker wins when dice is higher, defender wins ties
- Combat continues until attacker withdraws or territory is conquered
- Round-by-round progression with casualty tracking and battle history

## Key Dependencies to Consider
- `pygame` for graphics and user interface (required)
- `dataclasses` for event/state definitions
- `enum` for game constants (territories, continents, phases)
- `typing` for comprehensive type hints
- `unittest` for testing framework

## Testing Strategy
- Unit tests for game rules and mechanics
- Integration tests for full game simulations
- Property-based testing for game invariants
- Agent vs agent testing for strategy validation

## Documentation Standards

### **Function Docstring Requirements (✅ MANDATORY)**
All functions must follow this exact docstring format to ensure consistency and clarity:

**Standard Format:**
```python
def function_name(param1: Type1, param2: Type2) -> ReturnType:
    """
    Brief one-sentence description. Extended description if needed.
    
    :param param1: Description of parameter purpose and constraints
    :param param2: Description of parameter purpose and constraints
    :returns: Description of return value and its structure
    :raises ExceptionType: When this exception is raised (if applicable)
    """
```

**Key Requirements:**
- **80-character line limit**: All code and docstring lines must not exceed 80 characters
- **Docstring formatting**: Docstrings must start on a new line after the opening triple quotes
- **Two-sentence summary**: First sentence is brief function purpose, second provides context or constraints
- **Parameter documentation**: Use `:param <fieldname>:` format for every parameter
- **Return documentation**: Use `:returns:` to describe return value structure and meaning
- **Exception documentation**: Use `:raises:` for any exceptions that may be raised
- **Type hints**: Always include comprehensive type hints in function signature

**Large Function Rule (>20 lines):**
For functions longer than 20 lines, agents must:
1. **Ask the user**: "This function is >20 lines. Should I include usage examples in the docstring?"
2. **If yes**: Add `:examples:` section with realistic usage scenarios
3. **If no**: Proceed with standard docstring format

**Examples Section Format:**
```python
def complex_function(data: List[Point], config: Dict[str, Any]) -> ProcessedResult:
    """
    Process complex polygon data with configuration options. Handles 
    validation, transformation, and optimization.
    
    :param data: List of Point objects representing polygon vertices, must 
                have at least 3 points
    :param config: Configuration dictionary with keys 'algorithm', 
                  'tolerance', and 'optimize'
    :returns: ProcessedResult containing transformed data, metadata, and 
             performance metrics
    :raises ValueError: When data has fewer than 3 points or config is 
                       missing required keys
    :examples:
        >>> points = [Point(0, 0), Point(10, 0), Point(5, 10)]
        >>> config = {'algorithm': 'fast', 'tolerance': 0.1, 'optimize': True}
        >>> result = complex_function(points, config)
        >>> print(f"Processed {len(result.vertices)} vertices in {result.time_ms}ms")
        
        # For large datasets with custom optimization
        >>> large_points = generate_random_polygon(1000)  
        >>> config = {'algorithm': 'precise', 'tolerance': 0.01, 'optimize': False}
        >>> result = complex_function(large_points, config)
    """
```

**Class Docstring Requirements:**
```python
class ClassName:
    """
    Brief description of class purpose. Explanation of key responsibilities.
    
    :param init_param: Description of constructor parameter
    :raises InitException: When initialization fails due to invalid 
                          parameters
    :examples:
        >>> handler = ClassName(game_state)
        >>> handler.process_selection(territory_id=5)
    """
```

**Documentation Quality Checklist:**
- [ ] Function purpose is clear from first sentence
- [ ] All parameters are documented with constraints/expectations
- [ ] Return value structure is explained
- [ ] Type hints match parameter documentation
- [ ] Examples show realistic usage patterns (for >20 line functions)
- [ ] Examples include variable names that match function context
- [ ] No line exceeds 80 characters in docstrings or code
- [ ] Docstrings start on new line after opening triple quotes

## Common Patterns
- Use type hints extensively for all interfaces and function signatures
- Implement `__repr__` methods for debugging all data classes
- Use dataclasses with clear field types and default factories
- Create factory methods for complex object initialization
- Follow consistent import patterns and module boundaries
- **Follow documentation standards religiously** - well-documented code is maintainable code

Current import patterns:
```python
# Within risk.state modules
from .territory import Territory, TerritoryState
from .game_state import GameState, Player, GamePhase

# Cross-module dependencies (state → utils)
from ..utils.distance import Point, random_walk, clean_sequence

# Game modules depending on state
from ..state import GameState, Territory
from ..state.board_generator import generate_sample_board

# Entry point imports
from risk.game import main
```

Example patterns currently used:
```python
# Factory method for game setup (✅ IMPLEMENTED)
@classmethod
def create_new_game(cls, regions: int, players: int, army_size: int) -> GameState:
    return GameState(regions=regions, num_players=players, starting_armies=army_size)

# Dataclass with proper defaults (✅ IMPLEMENTED)
@dataclass
class Player:
    id: int
    name: str
    color: Tuple[int, int, int]
    territories_controlled: Set[int] = field(default_factory=set)
    
# Callback registration for loose coupling (✅ IMPLEMENTED)
def register_callback(self, event_type: str, callback: Callable) -> None:
    self.callbacks[event_type] = callback

# Agent interface pattern (✅ IMPLEMENTED)
class BaseAgent(ABC):
    @abstractmethod
    def decide_placement(self, game_state: GameState, turn_state: TurnState) -> Optional[int]:
        pass

# Plan/Goal/Step pattern for agent behaviors (✅ IMPLEMENTED)
class Goal:
    def achieved(self, state: GameState) -> bool:
        return False

class Plan:
    def add_step(self, step: Step) -> Plan:
        self.steps.append(step)
        return self

class Step:
    def execute(self, state: GameState) -> Union[GameState, None, Plan]:
        return None
```

## Testing and Development
When testing new features:
- Use `python run_game.py -g 5 -p 2 -s 5` for quick testing with minimal setup (2 players, 5 armies each = 10 total)
- Use `python run_game.py -g 20 -p 4 -s 30` for comprehensive behavior testing (4 players, 30 armies each = 120 total)
- Default parameters (`python run_game.py`) provide balanced simulation for development (3 players, 20 armies each = 60 total, 27 regions)

**Runtime Testing with Keyboard Shortcuts:**
For rapid iteration and testing of different board configurations:
- Use `python run_game.py -g 3 -p 2 -s 3` for minimal startup time
- Use **Ctrl+G** repeatedly to test different region counts incrementally
- Use **Ctrl+P** to add more players and see how territory distribution changes
- Use **Ctrl+S** to increase armies and see how initial placement affects gameplay
- Use **Ctrl+R** to regenerate the same configuration with different random layouts
- Use **Space** to pause/unpause AI simulation for observation
- All changes trigger immediate board regeneration for visual feedback

**AI Testing Patterns:**
For testing AI agent behavior and integration:
- Use `python run_game.py --ai-delay 0.1 --attack-rate 0.9` for fast AI simulation testing
- Use `python run_game.py --human-player 0 --ai-delay 2.0` to play against AI with visible decision timing
- Use `python run_game.py -g 8 -p 2 --ai-delay 0.5` for quick AI vs AI testing
- Pause functionality (`Space`) allows inspection of AI state mid-turn
- Visual feedback shows AI decisions in real-time with configurable delays

**Testing Separation of Concerns:**
When adding new functionality, verify the architectural boundaries:
```python
# ✅ Test that utilities work independently
from risk.utils.distance import Point, random_walk
points = random_walk(Point(0, 0), Point(100, 100))

# ✅ Test that state management is pure
from risk.state import GameState
game = GameState.create_new_game(5, 2, 10)

# ✅ Test that rendering doesn't modify state
from risk.game import GameRenderer
renderer = GameRenderer(screen, game_state)
original_state = copy.deepcopy(game_state)
renderer.draw_board()
assert game_state == original_state  # State unchanged
```

## Performance Considerations
- Cache territory adjacency calculations
- Use efficient data structures for large-scale tournaments
- Consider async patterns for parallel agent decision-making
- Profile bottlenecks in simulation loops

**Current Implementation Notes:**
- Board generation is optimized for reasonable region counts (up to ~50 territories)
- Polygon subdivision algorithm has O(n²) adjacency calculation complexity
- Pygame rendering at 60 FPS works well for typical board sizes
- Memory usage scales linearly with number of territories and game history
- AI agent decision-making adds minimal overhead due to efficient BaseAgent interface
- Pause functionality allows detailed inspection of AI behavior without performance impact