"""Mixture of recursive pragmatic and egocentric listeners.

Listeners in reference games differ in communicative perspective-taking:
the population comprises a mixture of recursive depth-2 pragmatic listeners,
who mentally simulate the speaker's informative choices relative to alternative
objects in the context, and egocentric listeners, who assume the speaker
describes referents without considering competing distractors and evaluate
candidates by the speaker's object-internal feature distribution. On uninformative
trials without a descriptive word, both listener types guess uniformly among
the objects. Observed population choices reflect this latent mixture, with
the pragmatic proportion parameterizing the balance between recursive
perspective-taking and egocentric reference resolution.
"""

import jax.numpy as jnp
import numpyro.distributions as dist
from memo import memo

from src.rsa.memo_kit import EPS, at, with_lapse

PARAMS = {
    "alpha": dist.LogNormal(0.4, 0.25),
    "p_pragmatic": dist.Beta(2.0, 6.0),
    "lapse": dist.Beta(1.0, 9.0),
}


@memo
def L0[u: UTT, r: OBJ](lex: ...):
    listener: knows(u)
    listener: chooses(r in OBJ, wpp=at(lex, u, r))
    return Pr[listener.r == r]


@memo
def L1[u: UTT, r: OBJ](alpha, lex: ...):
    listener: thinks[
        speaker: given(r in OBJ, wpp=1),
        speaker: chooses(
            u in UTT,
            wpp=at(lex, u, r) * exp(alpha * log(L0[u, r](lex) + {EPS})),
        ),
    ]
    listener: observes [speaker.u] is u
    listener: chooses(r in OBJ, wpp=Pr[speaker.r == r])
    return Pr[listener.r == r]


@memo
def L2[u: UTT, r: OBJ](alpha, lex: ...):
    listener: thinks[
        speaker: given(r in OBJ, wpp=1),
        speaker: chooses(
            u in UTT,
            wpp=at(lex, u, r) * exp(alpha * log(L1[u, r](alpha, lex) + {EPS})),
        ),
    ]
    listener: observes [speaker.u] is u
    listener: chooses(r in OBJ, wpp=Pr[speaker.r == r])
    return Pr[listener.r == r]


@memo
def L_ego[u: UTT, r: OBJ](alpha, lex: ...):
    listener: thinks[
        speaker: given(r in OBJ, wpp=1),
        speaker: chooses(u in UTT, wpp=at(lex, u, r)),
    ]
    listener: observes [speaker.u] is u
    listener: chooses(r in OBJ, wpp=exp(alpha * log(Pr[speaker.r == r] + {EPS})))
    return Pr[listener.r == r]


def choice_probs(params, ctx):
    l2_heard = L2(params["alpha"], ctx.lex)[ctx.utterance]
    ego_heard = L_ego(params["alpha"], ctx.lex)[ctx.utterance]
    p_prag = params["p_pragmatic"]
    heard = p_prag * l2_heard + (1.0 - p_prag) * ego_heard
    uniform = jnp.full_like(heard, 1.0 / heard.shape[0])
    return with_lapse(jnp.where(ctx.is_prior > 0, uniform, heard), params["lapse"])
