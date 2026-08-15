#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::.................:::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::.............................::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::......................................:::::::::::::::::::::::::::
#  ::::::::::::::::::::::::......................*%:....................::::::::::::::::::::::::
#  ::::::::::::::::::::::.......................+@@@-......................::::::::::::::::::::::
#  ::::::::::::::::::::........................+@@@@@:.......................:::::::::::::::::::
#  ::::::::::::::::::.........................=@@@@@@@:........................:::::::::::::::::
#  ::::::::::::::::..........................:@@@@@@@@@-........................:::::::::::::::
#  :::::::::::::::..........................-@@@@@@@@@@@=.........................:::::::::::::
#  :::::::::::::...........................=@@@@@@@@@@@@@-.........................::::::::::::::
#  ::::::::::::...........................-@@@@@@@@@@@@@@@..........................:::::::::::
#  :::::::::::............................:%@@@@@@@@@@@@@+...........................:::::::::
#  ::::::::::..............................=@@@@@@@@@@@@%:............................:::::::::
#  ::::::::::...............................*@@@@@@@@@@@=..............................::::::::
#  :::::::::................................:@@@@@@@@@@%:...............................::::::
#  ::::::::..................................*@@@@@@@@@-................................::::::::
#  ::::::::..................:@@+:...........:@@@@@@@@@.............:+-..................:::::::
#  :::::::...................*@@@@@@*-:.......%@@@@@@@+........:-*@@@@@..................:::::::
#  :::::::..................:@@@@@@@@@@@%:....*@@@@@@@:....:=%@@@@@@@@@=.................:::::::
#  :::::::..................*@@@@@@@@@@@@#....=@@@@@@@....:*@@@@@@@@@@@#..................::::::
#  :::::::.................:@@@@@@@@@@@@@@-...=@@@@@@@....*@@@@@@@@@@@@@:.................::::::
#  :::::::.................*@@@@@@@@@@@@@@@:..=@@@@@@#...+@@@@@@@@@@@@@@=.................::::::
#  :::::::................:@@@@@@@@@@@@@@@@*..=@@@@@@#..+@@@@@@@@@@@@@@@+.................::::::
#  :::::::................=@@@@@@@@@@@@@@@@@-.#@@@@@@@.-@@@@@@@@@@@@@@@@*................:::::::
#  :::::::...............:#@@@@@@@@@@@@@@@@@*.@@@@@@@@:@@@@@@@@@@@@@@@@@%:...............:::::::
#  ::::::::..............:*@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@%:...............:::::::
#  ::::::::................:*@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@-...............::::::::
#  :::::::::.................:=#@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@%-.................::::::::
#  ::::::::::....................:#@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@=...................::::::::::
#  ::::::::::.......................:*@@@@@@@@@@@@@@@@@@@@@@@@@#-.....................:::::::::
#  :::::::::::.........................:=@@@@@@@@@@@@@@@@@@*:........................:::::::::::
#  ::::::::::::......................:=%@@@@@@@@@@@@@@@@@@@@#:......................::::::::::::
#  :::::::::::::.............+#%@@@@@@@@@@@@@@%-::*-.:%@@@@@@@@%=:.................::::::::::::::
#  :::::::::::::::...........:#@@@@@@@@@@@#--+%@@@@@@@#=:=%@@@@@@@@@@-............::::::::::::::::
#  ::::::::::::::::............-@@@@@@+-=#@@@@@@@@@@@@@@@@#=-=#@@@@*:............::::::::::::::::
#  ::::::::::::::::::...........:==:...-@@@@@@@@@@@@@@@@@@@@:...:=-............:::::::::::::::::
#  :::::::::::::::::::...................@@@@@@@@@@@@@@@@@-..................::::::::::::::::::::
#  ::::::::::::::::::::::................:#@@@@@@@@@@@@@*:.................::::::::::::::::::::::
#  ::::::::::::::::::::::::...............:*@@%+-.:=#@%-................::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::.............:........................:::::::::::::::::::::::::::
#  :::::::::::::::::::::::::::::::...............................:::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::.....................:::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::


"""GOM Prototype: Yang-Mills mass gap as spectral gap.
Constructs a simplified lattice gauge manifold, computes graph Laplacian,
measures the spectral gap (first nonzero eigenvalue = mass gap proxy).
Deploy to EC2."""
import torch, json, math, random, os
import torch.nn.functional as F

DEVICE="cuda"; D=512; N_CONFIGS=2000
OUT="C:/Users/legom/HyperTensor/benchmarks/gom_prototype"
os.makedirs(OUT,exist_ok=True)

print("="*60)
print("  GOM PROTOTYPE: Yang-Mills Mass Gap")
print("  Paper XXV: Spectral gap on Gauge Orbit Manifold")
print("="*60)

# -- Simulated lattice gauge configurations --
# Represent SU(2) gauge links on a 4^4 lattice (simplified)
# Each config: vector of link variables (group elements -> algebra elements)
# We simulate "cold" (low action, near vacuum) and "hot" (high action, excited)

print("\n[1] Generating lattice gauge configurations...")

def random_su2_element():
    """Random SU(2) element -> Pauli algebra coefficients."""
    # Random point on S^3 (unit quaternion)
    theta=random.uniform(0,2*math.pi)
    phi=random.uniform(0,math.pi)
    # Stereographic-like mapping to algebra coefficients
    r=random.uniform(0,1)
    a0=math.cos(r*math.pi/2)
    a1=math.sin(r*math.pi/2)*math.sin(phi)*math.cos(theta)
    a2=math.sin(r*math.pi/2)*math.sin(phi)*math.sin(theta)
    a3=math.sin(r*math.pi/2)*math.cos(phi)
    return torch.tensor([a0,a1,a2,a3],dtype=torch.float32)

def generate_config(beta):
    """Generate a gauge configuration at coupling beta=4/g^2.
    Low beta = strong coupling = confined, high beta = weak coupling = deconfined.
    beta controls how close links are to identity (coldness)."""
    n_links=64  # simplified 4^4 lattice
    links=[]
    for _ in range(n_links):
        link=random_su2_element()
        # Mix with identity: cold configs have links near (1,0,0,0)
        link[0]=link[0]*0.3+0.7*math.tanh(beta*0.5)  # a0 near 1 for large beta
        link=link/link.norm()  # keep on S^3
        links.append(link)
    return torch.cat(links)  # [n_links*4]

# Generate configs across a range of beta (coupling)
configs=[]; betas=[]
for i in range(N_CONFIGS):
    beta=0.5+3.5*random.random()  # beta in [0.5, 4.0]
    configs.append(generate_config(beta))
    betas.append(beta)

config_vecs=torch.stack(configs)  # [N, 256]
betas=torch.tensor(betas)
print(f"  Generated {N_CONFIGS} configurations, dim={config_vecs.shape[1]}")
print(f"  Beta range: [{betas.min():.1f}, {betas.max():.1f}]")

# -- Embed onto manifold --
print("\n[2] Embedding onto gauge orbit manifold...")

encoder=torch.nn.Sequential(
    torch.nn.Linear(256,512),torch.nn.GELU(),
    torch.nn.Linear(512,D),torch.nn.GELU(),
    torch.nn.Linear(D,D)
).to(DEVICE)

# Train: nearby beta -> nearby embedding (continuity)
opt=torch.optim.AdamW(encoder.parameters(),lr=0.002)
steps=3000

for step in range(steps):
    idx=torch.randint(0,N_CONFIGS,(64,))
    cv=config_vecs[idx].to(DEVICE)
    emb=encoder(cv)
    emb=F.normalize(emb,dim=-1)
    
    # Continuity: points with similar beta should be close
    b=betas[idx].to(DEVICE)
    # Compute pairwise beta distance
    beta_dist=(b.unsqueeze(0)-b.unsqueeze(1)).abs()
    emb_sim=(emb@emb.T)  # cosine similarity
    # Nearby in beta space -> nearby in embedding space
    # Weighted: closer beta = higher target similarity
    target_sim=torch.exp(-beta_dist*2.0)  # decays with beta distance
    continuity_loss=F.mse_loss(emb_sim,target_sim)
    
    # Action proxy: higher beta (colder) configs should have lower "energy"
    # Energy = distance from vacuum embedding
    if step>500:
        vacuum_emb=emb.mean(dim=0,keepdim=True)
        energy=torch.norm(emb-vacuum_emb,dim=-1)
        # Energy should anti-correlate with beta
        beta_norm=(b-b.min())/(b.max()-b.min()+1e-8)
        energy_target=1.0-beta_norm  # high beta -> low energy
        energy_loss=F.mse_loss(energy/energy.max(),energy_target).item()
    else:
        energy_loss=0.0
    
    loss=continuity_loss+0.1*energy_loss
    loss.backward(); opt.step(); opt.zero_grad()
    
    if (step+1)%500==0:
        print(f"  Step {step+1}: loss={loss.item():.4f} cont={continuity_loss.item():.3f} energy={energy_loss:.4f}")

# -- Compute spectral gap --
print("\n[3] Computing spectral gap (mass gap proxy)...")

with torch.no_grad():
    all_emb=F.normalize(encoder(config_vecs.to(DEVICE)),dim=-1)
    
    # Build graph Laplacian from k-NN
    k_nn=30
    # Compute pairwise distances (subset for efficiency)
    n_subset=min(500,N_CONFIGS)
    emb_sub=all_emb[:n_subset]
    
    # Distance matrix
    sim=emb_sub@emb_sub.T  # cosine sim
    dist=1-sim  # cosine distance in [0,2]
    
    # k-NN adjacency
    adj=torch.zeros(n_subset,n_subset,device=DEVICE)
    for i in range(n_subset):
        _,nn_idx=torch.topk(sim[i],k=k_nn+1)
        adj[i,nn_idx[1:]]=1  # skip self
    
    # Symmetric adjacency
    adj=(adj+adj.T)/2
    adj=torch.clamp(adj,0,1)
    
    # Graph Laplacian: L = D - A
    deg=adj.sum(dim=1)
    L=torch.diag(deg)-adj
    
    # Normalized Laplacian: L_norm = I - D^(-1/2) A D^(-1/2)
    deg_inv_sqrt=torch.diag(1.0/torch.sqrt(deg+1e-8))
    L_norm=torch.eye(n_subset,device=DEVICE)-deg_inv_sqrt@adj@deg_inv_sqrt
    
    # Compute eigenvalues
    eigvals=torch.linalg.eigvalsh(L_norm)
    
    # Spectral gap = first nonzero eigenvalue
    eigvals_sorted=sorted(eigvals.cpu().tolist())
    nonzero_eigs=[e for e in eigvals_sorted if e>1e-6]
    spectral_gap=nonzero_eigs[0] if nonzero_eigs else 0.0
    
    print(f"  Graph Laplacian: {n_subset}x{n_subset}, k-NN={k_nn}")
    print(f"  First 10 eigenvalues: {[round(e,4) for e in eigvals_sorted[:10]]}")
    print(f"  Spectral gap (λ_1): {spectral_gap:.6f}")
    print(f"  λ_max: {eigvals_sorted[-1]:.4f}")
    
    # Spectral gap vs beta (mass gap prediction)
    # Higher spectral gap -> larger mass gap
    mass_gap_proxy=spectral_gap*1000  # scale for readability
    print(f"  Mass gap proxy: {mass_gap_proxy:.2f} (λ_1 × 1000)")
    
    # Check: does gap vary with coupling?
    # High-beta (weak coupling) should have different gap than low-beta
    high_beta_mask=betas[:n_subset]>2.5
    low_beta_mask=betas[:n_subset]<=2.5
    
    if high_beta_mask.sum()>=2 and low_beta_mask.sum()>=2:
        # Sub-Laplacians
        for name,mask in [("low-beta",low_beta_mask),("high-beta",high_beta_mask)]:
            idx_sub=mask.nonzero(as_tuple=True)[0]
            if len(idx_sub)<3: continue
            emb_s=emb_sub[idx_sub]
            sim_s=emb_s@emb_s.T
            adj_s=torch.zeros(len(idx_sub),len(idx_sub),device=DEVICE)
            k_eff=min(k_nn,len(idx_sub)-1)
            for i in range(len(idx_sub)):
                _,nn_idx=torch.topk(sim_s[i],k=k_eff+1)
                adj_s[i,nn_idx[1:]]=1
            adj_s=(adj_s+adj_s.T)/2
            deg_s=adj_s.sum(dim=1)
            L_s=torch.diag(deg_s)-adj_s
            deg_inv_s=torch.diag(1.0/torch.sqrt(deg_s+1e-8))
            Ln_s=torch.eye(len(idx_sub),device=DEVICE)-deg_inv_s@adj_s@deg_inv_s
            ev_s=torch.linalg.eigvalsh(Ln_s)
            ev_list=sorted(ev_s.cpu().tolist())
            gap_s=next((e for e in ev_list if e>1e-6),0)
            print(f"  {name} (n={len(idx_sub)}): λ_1={gap_s:.6f}")

# -- Save --
results={
    "n_configs":N_CONFIGS,"d_embed":D,"n_subset":n_subset,"k_nn":k_nn,
    "spectral_gap":round(spectral_gap,6),
    "mass_gap_proxy":round(mass_gap_proxy,2),
    "first_10_eigs":[round(e,4) for e in eigvals_sorted[:10]],
    "lambda_max":round(eigvals_sorted[-1],4),
    "interpretation":"spectral_gap>0 implies positive mass gap on GOM",
}
with open(f"{OUT}/results.json","w") as f: json.dump(results,f,indent=2)
torch.save({"encoder":encoder.state_dict()},f"{OUT}/model.pt")
print(f"\nSaved to {OUT}/")
print(f"GOM: spectral_gap={spectral_gap:.6f} => mass gap {'EXISTS' if spectral_gap>0 else 'ABSENT'}")
