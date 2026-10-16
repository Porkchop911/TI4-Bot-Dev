@{
    # Pilot 2, PROJECTION + CRITIC (operator 2026-10-02: start a training pilot). 50 more updates from the
    # first pilot's final checkpoint-4000 on the cached power map (PowerCache: per-system fingerprints,
    # frozen during open actions). Same reward as pilot 1's arm. New seeds 1262702000.

    Bundle   = 'D:\Projects\ti4-engine-rs\out\ppo-armB-waste1-tech01-proj002-critic-pilot-49232-20261002\checkpoints\checkpoint-4000'
    Pool     = 'D:\Projects\ti4-engine-rs\out\pools\full_np8_12_train.json'
    Run      = 'D:\Projects\ti4-engine-rs\out\ppo-armB-waste1-tech01-proj002-critic-pilot2-20261002'
    LibTorch = 'D:\Projects\ti4-engine-rs\out\libtorch-2.9.1-cu128'

    Diplomacy       = $true
    Background      = $true
    Build           = $true
    AllowConcurrent = $false

    Flags = @{
        'stage'            = 2
        'rounds'           = 4
        'temperature'      = 2.5
        'learning-rate'    = '1e-4'
        'movement-entropy' = 0.05
        'entropy-final'    = 0.25
        'updates'          = 50
        'report-every'     = '1:1,25:250,100'
        'seed-base'        = 1262702000
        'seeds-per-update' = 30
        'rotations'        = 1
        'device'           = 'cuda'

        'vp-weight'        = 1
        'waste-penalty'    = 1
        'clearance-weight' = 0.5
        'r1-bonus'         = 3
        'r1-shaping'       = 0.1

        'objective-weight'          = 0
        'secret-weight'             = 0
        'tech-weight'               = 0.1
        'fleet-weight'              = 0
        'projection-weight'         = 0.02
        'fleet-hoard-penalty'       = 0
        'zero-fleet-penalty'        = 0
        'trade-goods-hoard-weight'  = 0
        'strategy-diversity-weight' = 0
        'styx-bonus'                = 0
        'fracture-entry-bonus'      = 0
        'fracture-planet-bonus'     = 0
    }
}





