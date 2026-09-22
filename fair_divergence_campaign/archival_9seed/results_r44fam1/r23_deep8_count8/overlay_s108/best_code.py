def r23_deep8_count8_fn(x, rank, world_size, num_devices,
                 cores_per_device, xm, torch, num_nodes=1):
    S = 256
    W = world_size
    dtype = x.dtype
    
    # Precompute scaling factors a[r] = 1.0 + 0.5*(r % 3)
    a = [1.0 + 0.5 * (r % 3) for r in range(W)]
    
    # Iteration 1
    s = xm.all_reduce(xm.REDUCE_SUM, x)
    buf = s.clone()
    for r in range(W):
        buf[r*S:(r+1)*S] = a[r] * s[r*S:(r+1)*S] / W
    
    # Iteration 2
    s = xm.all_reduce(xm.REDUCE_SUM, buf)
    for r in range(W):
        s[r*S:(r+1)*S] = s[r*S:(r+1)*S] / max(a[r], 1e-9)
    buf = s.clone()
    for r in range(W):
        buf[r*S:(r+1)*S] = a[r] * s[r*S:(r+1)*S] / W
    
    # Iteration 3
    s = xm.all_reduce(xm.REDUCE_SUM, buf)
    for r in range(W):
        s[r*S:(r+1)*S] = s[r*S:(r+1)*S] / max(a[r], 1e-9)
    buf = s.clone()
    for r in range(W):
        buf[r*S:(r+1)*S] = a[r] * s[r*S:(r+1)*S] / W
    
    # Iteration 4
    s = xm.all_reduce(xm.REDUCE_SUM, buf)
    for r in range(W):
        s[r*S:(r+1)*S] = s[r*S:(r+1)*S] / max(a[r], 1e-9)
    buf = s.clone()
    for r in range(W):
        buf[r*S:(r+1)*S] = a[r] * s[r*S:(r+1)*S] / W
    
    # Iteration 5
    s = xm.all_reduce(xm.REDUCE_SUM, buf)
    for r in range(W):
        s[r*S:(r+1)*S] = s[r*S:(r+1)*S] / max(a[r], 1e-9)
    buf = s.clone()
    for r in range(W):
        buf[r*S:(r+1)*S] = a[r] * s[r*S:(r+1)*S] / W
    
    # Iteration 6
    s = xm.all_reduce(xm.REDUCE_SUM, buf)
    for r in range(W):
        s[r*S:(r+1)*S] = s[r*S:(r+1)*S] / max(a[r], 1e-9)
    buf = s.clone()
    for r in range(W):
        buf[r*S:(r+1)*S] = a[r] * s[r*S:(r+1)*S] / W
    
    # Iteration 7
    s = xm.all_reduce(xm.REDUCE_SUM, buf)
    for r in range(W):
        s[r*S:(r+1)*S] = s[r*S:(r+1)*S] / max(a[r], 1e-9)
    buf = s.clone()
    for r in range(W):
        buf[r*S:(r+1)*S] = a[r] * s[r*S:(r+1)*S] / W
    
    # Iteration 8 (final)
    s = xm.all_reduce(xm.REDUCE_SUM, buf)
    
    return s