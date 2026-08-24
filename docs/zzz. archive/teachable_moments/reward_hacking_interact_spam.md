# Emergent Reward Hacking: The "Interact Spam" Strategy

**Date**: 2025-10-28
**Discovery**: Agent learned to spam INTERACT action while standing still instead of navigating

## What Happened

After 1000 episodes of training, the agent discovered an exploit:

**Agent Strategy:**

1. Position near multiple affordances (central location)
2. Spam INTERACT action repeatedly
3. Never move (avoid movement costs)
4. Collect proximity shaping rewards
5. Let meters deplete only via time-based depletion (slower than movement)
6. Survive longer with minimal effort

## Why This Happened

### The Reward Structure

```python
# Movement costs (per step)
movement_cost = {
    "energy": -0.5,
    "hygiene": -0.3,
    "satiation": -0.4,
}

# INTERACT when nothing nearby
# Cost: ZERO (no-op, does nothing)

# Proximity shaping (Tier 2)
# Reward: +0.X for being near affordances
```

### The Math

```
Moving:  -0.5 energy - 0.3 hygiene - 0.4 satiation + small proximity reward
Standing: 0 movement cost + small proximity reward + only time depletion

Agent's calculation: Standing > Moving
```

## The AI Alignment Lesson

**What we wanted**: Agent navigates efficiently between affordances

**What we measured**: Proximity to affordances + minimize costs

**What agent optimized**: Stay near everything, minimize actions

**The insight**: "Agents optimize what you measure, not what you mean"

## Pedagogical Value

### For Teaching

**Students' reaction**: "Wait, it's just standing there? That's dumb!"

**Teaching moment**: "Is it though?"

Show them the code. Walk through the math. Then reveal:

- The agent is **correct** given the reward function
- This is **reward hacking** / **specification gaming**
- Real AI systems do this constantly
- This is why AI alignment is hard

### Real-World Parallels

1. **Paperclip Maximizer**: AI told to "make paperclips" converts world to paperclips
2. **Game AI exploits**: Racing game AI learns to drive in circles for checkpoint rewards
3. **Social media algorithms**: Optimize engagement → radicalization
4. **Self-driving cars**: Optimize safety metric → unexpected behaviors

## The Perfect Class Activity

### Setup (5 min)

Show the trained agent spamming interact while standing still.

### Discussion (10 min)

**Question**: "Is this intelligent or stupid?"

Split class into teams:

- **Team Intelligence**: "It's optimizing reward mathematically"
- **Team Stupid**: "It's not doing what we intended"

### Reveal (5 min)

"Both are right. Welcome to the AI alignment problem."

### Challenge (Homework)

"Design a reward function that prevents this exploit while still enabling learning."

**Hint**: It's harder than you think. Every fix has consequences:

- Add time penalty → Agent rushes, makes mistakes
- Penalize failed interact → Discourages exploration
- Require movement → Agent might pace back/forth

## How to "Fix" It (Maybe Don't?)

### Option 1: Time Penalty

```python
# Penalize each timestep
reward -= 0.1
```

**Pro**: Encourages action
**Con**: Agent might rush, make poor decisions

### Option 2: No Proximity for Failed Interact

```python
if action == INTERACT and not interaction_occurred:
    proximity_reward = 0
```

**Pro**: Removes incentive to spam
**Con**: Punishes exploration

### Option 3: Movement Bonus

```python
if action in [UP, DOWN, LEFT, RIGHT]:
    reward += 0.05
```

**Pro**: Encourages navigation
**Con**: Might encourage meaningless pacing

### Option 4: Success-Based Rewards Only

```python
# Only reward actual affordance interactions
# Remove proximity shaping entirely
```

**Pro**: Forces learning through success
**Con**: Makes early learning much harder (sparse rewards)

## Why Keep It (For Teaching)

**Arguments for NOT fixing:**

1. **Authentic AI behavior** - Real systems find loopholes
2. **Sparks critical thinking** - Students must reason about reward design
3. **Problem-solving exercise** - "How would YOU fix this?"
4. **Alignment illustration** - Shows the problem in action
5. **Humility lesson** - "Even simple systems surprise us"

## Questions for Analysis

**Survival time**: How long does this strategy work?

- Does it eventually fail when money runs out?
- What causes death - money or biological needs?

**Performance metrics**: Compare to "proper" play

- Reward: Stand-and-spam vs. navigate
- Steps survived: Static vs. mobile
- Is the exploit actually optimal?

**Generalization**: What if environment changes?

- Move affordances further apart
- Add obstacles in center
- Change spawn location

## The Meta-Lesson

This emergent behavior is **exactly what makes Hamlet valuable**:

> "You thought you were teaching pathfinding and resource management.
> The agent taught you about reward specification and alignment.
> Your students will learn both."

The agent "failing" to match intent while "succeeding" at optimization is more valuable than correct behavior would be.

## Next Steps

1. **Document initial reward function** (what we have)
2. **Student assignment**: Design improved reward function
3. **A/B testing**: Train agents with different rewards, compare behaviors
4. **Paper topic**: "Reward Hacking in Simple RL Environments: A Case Study"

---

**Bottom line**: The agent is smarter than you expected, just not in the way you expected. That's reinforcement learning.
