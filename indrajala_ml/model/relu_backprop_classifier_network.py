from __future__ import annotations

from indrajala_ml.model.backprop_classifier_network import BackpropClassifierNetwork
from indrajala_ml.model.relu_layer import ReLULayer


class ReLUBackpropClassifierNetwork(BackpropClassifierNetwork):
    """
    A ReLU-hidden-layer sibling of BackpropClassifierNetwork, using ReLU (see ReLULayer) instead
    of sigmoid for every hidden layer - the output layer stays exactly as BackpropClassifierNetwork
    built it (sigmoid, quadratic loss), since ReLU is a hidden-layer-only convention (see
    ReLUNode's own docstring for why). Structurally this is a single class-attribute override
    (hidden_layer_cls = ReLULayer): every other method (learn/_backward/randomize/randomized/
    snapshot/restore) is inherited unchanged and stays correct, since neither the backward-pass
    plumbing nor the weight-update rule cares which activation a hidden node used - only
    ReLUNode's own forward()/compute_hidden_delta differ from BackpropNode's.

    Deliberately isolates the activation-function question from everything else already measured
    in this codebase's sibling classes: this class keeps BackpropClassifierNetwork's own
    (unmodified) randomize() scheme and quadratic output loss, so a real measurement against it
    tests ReLU specifically, not ReLU bundled with an init-scheme or loss-function change at the
    same time.

    Measured directly (see docs/research-and-analysis.md's "ReLU hidden-layer activation" entry):
    at BackpropClassifierNetwork's own demo-tuned learning_rate=1.0, this class trains to a
    meaningfully *lower* training accuracy on a fixed XOR scenario (74.03% vs 97.80% mean over 10
    seeds) - not because of dead ReLU units (checked directly: only 1/8), but because ReLU's flat,
    undamped active-region gradient needs a smaller learning rate than whatever's already tuned
    for sigmoid's self-limiting a(1-a) factor - the same mechanism BinaryCrossEntropyBackpropClassifierNetwork's
    own docstring describes. Retuned to learning_rate=0.1, this class doesn't just recover
    sigmoid's tuned performance - it exceeds it (99.27% mean), a genuine, positive result on this
    scenario, not merely "didn't lose."

    Deliberately not a replacement for BackpropClassifierNetwork, and not (yet) used by any
    existing demo - the same additive, keep-both pattern as every other sibling class in this
    codebase. Needs its own tuned learning_rate wherever it's actually used, same caveat as the
    binary cross-entropy sibling.
    """

    hidden_layer_cls = ReLULayer
