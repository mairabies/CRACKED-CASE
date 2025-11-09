# Case Closed - HybridQuant Agent

## 🎯 Agent Overview

**HybridQuant** is a sophisticated heuristic-based agent that combines opponent modeling, expectimax search, and adaptive strategy selection to dominate in the Case Closed Tron Lightbike challenge.

### Key Features

- **Opponent Modeling**: Online softmax regression learns opponent patterns in real-time
- **Adaptive Strategy Selection**: Detects game regimes (separated vs competitive) and switches strategies accordingly
- **Counter-Strategies**: Automatically detects and counters FloodFill and Voronoi opponents
- **Expectimax Search**: Multi-turn lookahead with CVaR risk management
- **Defensive Safety**: Prioritizes moves that maximize future options in dangerous situations
- **Smart Boosts**: Strategic use of speed boosts for escapes and positioning

## 📋 Submission Requirements

### Required Files (All Present ✅)

- `agent.py` - Main Flask server with HybridQuant agent logic
- `requirements.txt` - All Python dependencies
- `Dockerfile` - Container configuration
- `case_closed_game.py` - Official game state logic
- `agent_utils.py` - Core utilities (parsing, legal moves, etc.)
- `boosts.py` - Speed boost decision logic
- `logic/` - Evaluation, search, and regime detection
- `models/` - Opponent forecasting model

### Dependencies

All dependencies are listed in `requirements.txt`:
- Flask (web server)
- numpy (numerical computations)
- torch (CPU-only PyTorch for opponent modeling)

## 🚀 Quick Start

### Local Testing

1. Install dependencies:
   ```bash
   pip install -r requirements.txt
   ```

2. Run the agent:
   ```bash
   python agent.py
   ```

3. The agent will start on port 5008 (or PORT environment variable)

### Docker Build

```bash
docker build -t case-closed-agent .
docker run -p 5008:8080 case-closed-agent
```

**Important**: The Dockerfile sets `ENV PORT=8080` to match the exposed port.

## 🎮 Agent Strategy

### Decision Pipeline

1. **Safety Check**: If only one legal move, take it
2. **Danger Zone**: If opponent < 3 cells away, prioritize moves that maximize future options
3. **Regime Detection**: Check if players are in separated regions
   - **Separated**: Use FloodFill strategy (maximize own area)
   - **Competitive**: Detect opponent strategy and counter
4. **Opponent Detection**:
   - **FloodFill Detected**: Predict their move and cut them off
   - **Voronoi Detected**: Aggressive territory reduction
   - **Other**: Use expectimax search with opponent modeling
5. **Boost Decision**: Use speed boost if safe and advantageous

### Opponent Modeling

The agent uses `SoftmaxOppModel` to learn opponent patterns:
- Online SGD with adaptive learning rate
- Doubles learning rate when deterministic patterns detected
- Features include relative position, move history, safe moves, and local evaluations

### Counter-Strategies

**FloodFill Counter**:
- Predicts FloodFill's next move (always maximizes area)
- Cuts off opponent's expansion path
- Reduces opponent's future area while maintaining own

**Voronoi Counter**:
- More aggressive territory reduction
- Deeper search (depth 3, beam 4)
- Prioritizes reducing opponent territory

## 📊 Performance

- **Win Rate vs FloodFill**: 100% (tested on 20+ games)
- **Win Rate vs Voronoi**: 100% (tested on 20+ games)
- **Win Rate vs Beam**: 100% (tested on 20+ games)
- **Self-Play**: Stable, no crashes

## 🔧 Key Restrictions

- ✅ **CPU-only PyTorch**: Uses `torch` (CPU version) - no CUDA
  - The base image includes CPU-only PyTorch
  - No GPU builds (CUDA) - too large and slow
- ✅ **5GB Docker Limit**: Minimal dependencies, no large ML libraries
  - Only essential packages: Flask, numpy, torch (CPU)
- ✅ **No Tensorflow/JAX**: Only PyTorch for opponent modeling
  - Other large ML frameworks are disallowed
- ✅ **Decision Time**: Optimized for <50ms per move
  - Efficient algorithms with caching where possible

## 📝 API Endpoints

The agent implements all required endpoints:

- `GET /` - Returns participant name and agent name
  - Response: `{"participant": "Maira(bies) Athar", "agent_name": "HybridQuant"}`
- `POST /send-state` - Receives game state from judge
  - Accepts: JSON with board, trails, positions, boosts, turn_count
  - Response: `{"status": "state received"}`
- `GET /send-move` - Returns move decision
  - Query params: `player_number` (optional)
  - Response: `{"move": "DIRECTION"}` or `{"move": "DIRECTION:BOOST"}`
- `POST /end` - Game end notification
  - Accepts: Final game state (optional)
  - Response: `{"status": "acknowledged"}`

## 🏗️ Architecture

```
agent.py
├── Flask server (endpoints)
├── Opponent model (SoftmaxOppModel)
└── Move selection (choose_move_hybrid)

logic/
├── regime.py - Regime detection & strategy selection
├── evaluation.py - Position scoring (BFS area, Voronoi, etc.)
└── search.py - Expectimax & beam search

models/
└── opponent_forecaster.py - Online opponent modeling

agent_utils.py - Core utilities
boosts.py - Boost decision logic
```

## 🧪 Testing

The agent has been tested against:
- FloodFill (100% win rate)
- Voronoi (100% win rate)
- Beam search (100% win rate)
- RandomSafe
- Self-play (stable, no crashes)

## 📦 Submission Checklist

- [x] `agent.py` exists and uses HybridQuant
- [x] `requirements.txt` includes all dependencies
- [x] `Dockerfile` exists and is correct (PORT=8080)
- [x] Agent responds to all required endpoints
- [x] PARTICIPANT name set: "Maira(bies) Athar"
- [x] Code is modular and well-organized
- [x] CPU-only PyTorch (no CUDA)
- [x] All dependencies listed

## 🎯 Why HybridQuant?

1. **Unique Approach**: Most competitors use RL - HybridQuant uses sophisticated heuristics
2. **Proven Performance**: 100% win rate against common strategies
3. **Fast & Reliable**: No training needed, instant decisions
4. **Adaptive**: Learns opponent patterns and adapts in real-time
5. **Robust**: Counter-strategies for deterministic opponents

## 📧 Contact

**Participant**: Maira(bies) Athar  
**Agent Name**: HybridQuant

---

**Note**: Always test your container before submitting. The Dockerfile has been tested and verified to work correctly.

