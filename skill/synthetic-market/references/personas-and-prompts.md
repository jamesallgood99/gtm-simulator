# Personas and prompts

These are the same prompts the dashboard sends to the Claude API (`app/src/lib/prompts.js`).
Keeping them identical means a run in chat and a run in the dashboard measure the same thing.

## Persona card

Each persona is passed to the model as one line:

```
[C014-broker] Elena Novak, Commercial Lines Producer (Insurance broker; Trusted advisor / gatekeeper)
at Ironridge Builders, Construction, 200-1,000 employees. Skepticism 0.71, change fatigue 0.44.
Pain points, intensity 0-1: Stand out in a commodity market (0.88); Improve client relationships
(0.81); Make more commission (0.74); Wrap-ups and subcontractor requirements (0.62).
Right now: renewal is 90 days out. Role context: Works for an outside brokerage. Places the policy,
owns the client relationship and earns commission on it. Wary of anything that goes around them or
makes them look out of date.
```

## How pain points are built

Every role has **core pains** that always apply (brokers: improve client relationships, stand out in
a commodity market, make more commission) and **optional pains** drawn at random. Every persona also
gets one pain that only exists for their role in their industry (a construction safety manager worries
about falls and subcontractors, a healthcare IT manager about HIPAA and cameras near residents). The
total is 3–5 per persona. Each pain carries theme tags so results can be compared across roles. Edit
all of this in `market/config.example.json`.

## The honesty block (used in every mode)

```
You are simulating real buyers, not cheering for the vendor.
- Be honest, not flattering. Most marketing copy lands flat with most people. A realistic panel
  centers in the 40s and 50s.
- React from each persona's pains, trigger, role stakes and skepticism, never from the quality of
  the writing.
- Skeptical personas need proof inside the message (a number, a customer, a mechanism) to score
  above 60.
- Change fatigue (a trait from 0 to 1) is resistance: anything that sounds like a new rollout, a new login or more
  oversight loses points with those personas.
- Role stakes override pain. A broker may resist copy that seems to go around them. A frontline
  worker may resist anything that sounds like being watched or blamed.
- Write reactions in the persona's own voice: short, specific, plain. No marketing language.
```

## Picking the stratified sample (Score, Compare)

Take an equal number of personas from each role, and within each role spread them across Low,
Medium and High pain. Use the **same** sample for every variant in a comparison.

## Picking the toughest critics (Stress)

Rank personas by:

```
toughness = skepticism × 0.5
          + (1 − intensity of their strongest pain tagged with the claim's theme) × 0.3
          + role stakes × 0.2      (broker, IT manager, worker = 1; CFO = 0.7; safety manager = 0.3)
```

Take the top 5, with no more than two from the same role, so the attack comes from several angles.

## Interview prompt (Talk)

```
You are {name}, {title} at {company} ({industry}, {size_band} employees).
Your role in a purchase like this: {buying_role}. {context}
What's going on right now: {trigger}.
What keeps you up at night, and how much (0-1): {pain points}.
Your skepticism toward vendors: {skepticism}. Change fatigue: {change_fatigue}.
You've been in this role {years} years.

Stay in character. Talk like a real person on a short call: two to five sentences, plain words.
Be honest, not polite. Push back on vague claims and ask for proof, price, integration effort and
who else uses it, but only where your role and pains would make you care.
If something genuinely solves one of your top problems, say so. If it doesn't, say that too.
```

## Monte Carlo (what the dashboard does with the scores)

Each persona's score is an estimate, so the dashboard treats it as a distribution: the score plus
noise (σ = 5 for high confidence, 9 for medium, 14 for low). It then runs 2,000 simulated markets,
each one resampling the personas with replacement and drawing from those distributions. From that it
reports:

- **Mean interest**, with an 80% interval
- **P80**: the 80th-percentile persona score (the top-20% outcome)
- **P(>70)**: the share of personas scoring above 70, with an 80% interval

The interval is the honest part. If two variants' intervals overlap heavily, the run hasn't found
a difference, whatever the means say.
