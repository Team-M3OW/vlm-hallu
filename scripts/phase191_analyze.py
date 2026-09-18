import json,sys,numpy as np
f=sys.argv[1]; rows=[json.loads(l) for l in open(f)]; n=len(rows); cat=np.array([r["category"] for r in rows]); rng=np.random.default_rng(191)
arms=list(rows[0]["probs"]); A=lambda k: np.array([float(int(np.argmax(r["probs"][k]))==r["label"]) for r in rows]); acc={k:A(k) for k in arms}
tok={k:np.mean([r["realized_tokens"][k] for r in rows]) for k in arms}; txt={k:np.mean([r["text_tokens"][k] for r in rows]) for k in arms}
def ci(d):
    m=len(d); b=np.array([d[rng.integers(0,m,m)].mean() for _ in range(8000)]); return d.mean()*100,np.percentile(b,2.5)*100,np.percentile(b,97.5)*100
print(f"\n{f.split('/')[-1]} n={n}   image tokens (incl. localiser where separate): "+"  ".join(f"{k} {tok[k]:.0f}" for k in arms)+"\n   text tokens: "+"  ".join(f"{k} {txt[k]:.0f}" for k in arms))
print(f"  {'stratum':>11} "+" ".join(f"{k:>11}" for k in arms))
for t,m in [("single",cat=="direct_attributes"),("relational",cat=="relative_position"),("ALL",np.ones(n,bool))]:
    print(f"  {t:>11} "+" ".join(f"{acc[k][m].mean()*100:10.1f}%" for k in arms))
for t,m in [("single",cat=="direct_attributes"),("relational",cat=="relative_position"),("ALL",np.ones(n,bool))]:
    out=[]
    for nm,a,b in [("P1/P2 ctx-bar",acc["ridge_ctx"],acc["uniform@600"]),("GUARD ctx-ridge300",acc["ridge_ctx"],acc["ridge300"]),("oracle_ctx-oracle300",acc["oracle_ctx"],acc["oracle300"])]:
        d,lo,hi=ci((a-b)[m]); out.append(f"{nm} {d:+5.1f}[{lo:+5.1f},{hi:+5.1f}]{'✔' if lo>0 else ('✗' if hi<0 else ' ')}")
    print(f"  {t:>11}  "+"   ".join(out))
