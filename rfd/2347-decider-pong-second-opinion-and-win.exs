# Copyright (c) 2026 K. S. Ernest (iFire) Lee
# SPDX-License-Identifier: MIT
use RFD.DSL

rfd 2347, "decider-pong: a second opinion, and a model that wins", :committed do
  feature "a Pong recording whose labels match what the live model does, and a run where it
wins"
  scope "the decider-pong interactor's `recorder_second_opinion.py`, its simulators, evals
and `PEER_REVIEW.md`"

  prose ~S"""
  :: hook
  A live Pong model wins 7-0 and 8-0, and the write-up says who does the predicting.
  :: intrigue
  The shipped video showed "a live decider" playing Pong. The model was right on 34 to 52
  percent of its replies, answered "up" most of the time, and lost 0-25 in 2 minutes.
  :: exit
  Read `PEER_REVIEW.md` in decider-pong, which carries every number.
  :: decision
  The live paddle plays with four parts. Code predicts the y where the
  ball will reach the paddle by running `Pong.step` forward. The model
  answers the sign of the 10-px steps to that point. A held move stops
  at the target. An answer older than 15 frames hands the paddle to the
  teacher. With the classic angle rule on both paddles, the model wins
  7-0 and 8-0 on its own points over two 5-minute runs. The teacher
  controls on the same seeds end 7-6 and 9-8.
  :: related
  - RFD66606-2345, the video format; RFD66606-2346, decider-pong in the
    workspace.
  - `PEER_REVIEW.md` and `evidence/` in decider-pong carry every number.
  """

  details_title "What was wrong, what was tried, and what the win shows"

  prose ~S"""
  :: details The review, in short
  The shipped prompt scored 68 percent offline, with 41 of 60 answers
  "up". A held answer overshot: one "move" carries the paddle 40 px over
  a 4-frame reply, against a 14-px reach. One failed request froze the
  paddle on "stay" for the rest of a run. The drawn paddles were twice
  the size of the colliding ones, and the right one sat 10 px behind its
  hit plane. The overlap test had a wrong y term, the timecode printed
  hundredths, serves were seeded from the clock, and 600 frames sat in
  memory. The README contradicted the files on disk.
  :: details Why the game could not be won
  Under the repo physics no paddle can win: the teacher never misses.
  A hit never changes the ball's vertical speed, which stays under 4.1
  px a frame. A paddle moves 10 px a frame. Teacher against teacher held
  0-0 for 30 simulated minutes on three seeds. The classic angle rule,
  `--english 8`, lets the hit point change the vertical speed by up to 8
  px a frame. It applies to both paddles, and teacher against teacher
  stays even under it.
  :: details What each step fixed
  1. Simulation first. `sim_right_paddle.py` showed that even a paddle
     that is always right loses about 4 points a minute when it holds an
     answer for a 4-frame delay. Aiming at the crossing point and
     stopping there loses almost none, even with 60 percent wrong answers.
  2. Prompt. A two-number prompt at temperature 0 was right 98 percent
     of the time on spread cases, but 81 percent on gaps under 30 px,
     where it answered "stay". The STEPS prompt was right on 80 of 80
     close calls at a median of about 105 ms.
  3. Prediction. A mirror-reflection formula tied 2-2. It was wrong on
     80 of 80 approaches, because the game pins the ball to the wall.
     The rollout matched the real hit-test y on 80 of 80.
  4. Staleness. The first 5-minute rollout run led 4-0, then an endpoint
     stall froze the paddle for about 30 s and it lost 13 points. A 1 s
     request timeout and a 15-frame answer limit fixed it. A planted
     endpoint that never answers gave 600 of 600 teacher frames, with
     the paddle still moving.
  :: details Results that count
  Seed 7, 5 minutes: 0-7, all 7 points the model's, 3232 of 3232 replies
  correct, p50 84 ms. Seed 11, 5 minutes: 2-8. The model's points are
  8-0, and the 2 lost came while the teacher held the paddle during 13
  endpoint failures. Without the angle rule the rollout run holds 0-0,
  the most the physics allows.
  :: details What the win does not show
  The model answers the sign of a small integer. A rule in code would do
  the same. It does not plan, aim or read the game. The next test gives
  the model the game state and scores the target it chooses.
  :: details Files
  Every render is CineForm and FLAC in Matroska on the Desktop, named by
  mode, seed and length, with its decision log. Runs that exposed a bug
  keep a suffix that says so, such as `_stale-reply-bug`. The commits
  that carry this work are on decider-pong `main`.
  :: details The problem
  Code does the predicting in the winning
  runs, and the write-up must say so.
  """
end
