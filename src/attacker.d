import mdp;
import std.format;
import std.array;
import std.numeric;
import std.typecons;
import std.math;
import std.conv;
import std.exception;
import std.algorithm;


class AttackerState : mdp.State {
	
	private int [] location;
	private int time;
	private int orientation;
	private double totalDetectionProb;
	
	public this ( int [] location = [-1,-1], int orientation = 0, int time = 0, double detectProb = 0) {
		
		setLocation(location);
		setOrientation(orientation);
		setTime(time);
		setDetectionProb(detectProb);
	}
	
	public int[] getLocation() {
		return location;
	}
	
	public void setLocation(int [] l) {
		assert(l.length == 2);
		
		this.location = l;
		
	}
	
	public int getOrientation() {
		return orientation;
	}
	
	public void setOrientation(int o) {
		orientation = o;
	}
		
	public int getTime() {
		return time;
	}
	
	public void setTime(int t) {
		time = t;
	}
		
	public double getDetectionProb() {
		return totalDetectionProb;
	}
	
	public void setDetectionProb(double p) {
		totalDetectionProb = p;
	}
		
	public double distance(AttackerState s) {
		return sqrt(cast(double)((location[0] - s.location[0])*(location[0] - s.location[0]) + (location[1] - s.location[1])*(location[1] - s.location[1]))); 
		
	}
	
	public override string toString() {
		auto writer = appender!string();
		formattedWrite(writer, "AttackerState: [location = %(%s, %) O: %s @ time %s]", this.location, this.orientation, this.time);
		return writer.data; 
	}


	override hash_t toHash() {
		return location[0] + location[1] + orientation + time;
	}	
	
	override bool opEquals(Object o) {
		AttackerState p = cast(AttackerState)o;
		
		return p && p.location[0] == location[0] && p.location[1] == location[1] && p.orientation == orientation && p.time == time;	
	}
	
	override public bool samePlaceAs(State o) {
		AttackerState p = cast(AttackerState)o;
		
		return p && p.location[0] == location[0] && p.location[1] == location[1] && p.time == time;	
	}
	
	override int opCmp(Object o) {
		AttackerState p = cast(AttackerState)o;

		if (!p) 
			return -1;
		
		
		for (int i = 0; i < location.length; i ++) {
			if (p.location[i] < location[i])
				return 1;
			else if (p.location[i] > location[i])
				return -1;
			
		}
		
		if (p.orientation < orientation)
			return 1;
		else if (p.orientation > orientation)
			return -1;
		
		return p.time - time;
		
	}
}

class AttackerExtendedState : mdp.State {

	private int [] location;
	private int time;
	private int orientation;
	private double totalDetectionProb;
	public int current_goal;

	public this ( int [] location = [-1,-1], int orientation = 0, int current_goal = 0, int time = 0, double detectProb = 0) {

		setLocation(location);
		setOrientation(orientation);
        setGoal(current_goal);
		setTime(time);
		setDetectionProb(detectProb);
	}

	public int[] getLocation() {
		return location;
	}

	public void setLocation(int [] l) {
		assert(l.length == 2);

		this.location = l;

	}

	public int getCurrentGoal() {
		return current_goal;
	}

	public void setGoal(int cg) {
		this.current_goal = cg;
	}

	public int getOrientation() {
		return orientation;
	}

	public void setOrientation(int o) {
		orientation = o;
	}

	public int getTime() {
		return time;
	}

	public void setTime(int t) {
		time = t;
	}

	public double getDetectionProb() {
		return totalDetectionProb;
	}

	public void setDetectionProb(double p) {
		totalDetectionProb = p;
	}

	public double distance(AttackerExtendedState s) {
		return sqrt(cast(double)((location[0] - s.location[0])*(location[0] - s.location[0]) + (location[1] - s.location[1])*(location[1] - s.location[1])));

	}

	public override string toString() {
		auto writer = appender!string();
		formattedWrite(writer, "AttackerState: [location = %(%s, %) , %s, O: %s @ time %s]", this.location,
		this.orientation, this.current_goal, this.time);
		return writer.data;
	}


	override hash_t toHash() {
		return 2*(4*(9*location[0] + location[1]) + location[2]) + current_goal; //location[0] + location[1] + orientation + time;
	}

	override bool opEquals(Object o) {
		AttackerExtendedState p = cast(AttackerExtendedState)o;

		return p && p.location[0] == location[0] && p.location[1] == location[1] && p.orientation == orientation
		&& p.current_goal == current_goal && p.time == time;
	}

	override public bool samePlaceAs(State o) {
		AttackerExtendedState p = cast(AttackerExtendedState)o;

		return p && p.location[0] == location[0] && p.location[1] == location[1] && p.time == time;
	}

	override int opCmp(Object o) {
		AttackerExtendedState p = cast(AttackerExtendedState)o;

		if (!p)
			return -1;


		for (int i = 0; i < location.length; i ++) {
			if (p.location[i] < location[i])
				return 1;
			else if (p.location[i] > location[i])
				return -1;

		}

		if (p.orientation < orientation)
			return 1;
		else if (p.orientation > orientation)
			return -1;

		return p.time - time;

	}
}

public class AttackerMoveForward : Action {
	
	AttackerModel model;
	
	public this (AttackerModel m) {
		model = m;
	}
	
	public override State apply(State state) {
		AttackerState p = cast(AttackerState)state;
		
		int orientation = p.getOrientation();
		
		int [] s = p.getLocation().dup;
		if (orientation == 0) 
			s[1] += 1;
		if (orientation == 1) 
			s[0] -= 1;
		if (orientation == 2) 
			s[1] -= 1;
		if (orientation == 3) 
			s[0] += 1;
		
		AttackerState a = new AttackerState(s, orientation, p.getTime() + 1);
		
		if (model.is_legal(a))
			return model.mapping[s[0]][s[1]][orientation][ p.getTime() + 1];
		else
			return a;
	}
	
	public override string toString() {
		return "AttackerMoveForward"; 
	}


	override hash_t toHash() {
		return 0;
	}	
	
	override bool opEquals(Object o) {
		AttackerMoveForward p = cast(AttackerMoveForward)o;
		
		return p && true;
		
	}
	
	override int opCmp(Object o) {
		AttackerMoveForward p = cast(AttackerMoveForward)o;
		
		if (!p) 
			return -1;
			
		return 0;
		
	}
	
}

public class AttackerMoveForward2 : Action {

	AttackerExtendedModel model;

	public this (AttackerExtendedModel m) {
		model = m;
	}

	public override State apply(State state) {
		AttackerExtendedState p = cast(AttackerExtendedState)state;

		int orientation = p.getOrientation();
        int cg = p.getCurrentGoal();
		int [] s = p.getLocation().dup;
		if (orientation == 0)
			s[1] += 1;
		if (orientation == 1)
			s[0] -= 1;
		if (orientation == 2)
			s[1] -= 1;
		if (orientation == 3)
			s[0] += 1;

		AttackerExtendedState a = new AttackerExtendedState(s, orientation, cg, p.getTime() + 1);

		if (model.is_legal(a))
			return model.mapping[s[0]][s[1]][orientation][ p.getTime() + 1];
		else
			return a;
	}

	public override string toString() {
		return "AttackerMoveForward";
	}


	override hash_t toHash() {
		return 0;
	}

	override bool opEquals(Object o) {
		AttackerMoveForward2 p = cast(AttackerMoveForward2)o;

		return p && true;

	}

	override int opCmp(Object o) {
		AttackerMoveForward2 p = cast(AttackerMoveForward2)o;

		if (!p)
			return -1;

		return 0;

	}

}

public class AttackerTurnLeft : Action {

	AttackerModel model;
	
	public this(AttackerModel m) {
		model = m;
	}

	public override State apply(State state) {
		AttackerState p = cast(AttackerState)state;
		
		int orientation = p.getOrientation() + 1;
		if (orientation > 3)
			orientation = 0;
			
		int [] s = p.getLocation().dup;
				
		AttackerState a = new AttackerState(s, orientation, p.getTime() + 1);
				
		if (model.is_legal(a))
			return model.mapping[s[0]][s[1]][orientation][ p.getTime() + 1];
		else
			return a;
	}
	
	public override string toString() {
		return "AttackerTurnLeft"; 
	}


	override hash_t toHash() {
		return 1;
	}	
	
	override bool opEquals(Object o) {
		AttackerTurnLeft p = cast(AttackerTurnLeft)o;
		
		return p && true;
		
	}
	
	override int opCmp(Object o) {
		AttackerTurnLeft p = cast(AttackerTurnLeft)o;
		
		if (!p) 
			return -1;
			
		return 0;
		
	}	
	
}

public class AttackerTurnLeft2 : Action {

	AttackerExtendedModel model;

	public this(AttackerExtendedModel m) {
		model = m;
	}

	public override State apply(State state) {

		AttackerExtendedState p = cast(AttackerExtendedState)state;

		int orientation = p.getOrientation() + 1;
        int cg = p.getCurrentGoal();
		if (orientation > 3)
			orientation = 0;

		int [] s = p.getLocation().dup;

		AttackerExtendedState a = new AttackerExtendedState(s, orientation, cg, p.getTime() + 1);

		if (model.is_legal(a))
			return model.mapping[s[0]][s[1]][orientation][ p.getTime() + 1];
		else
			return a;
	}

	public override string toString() {
		return "AttackerTurnLeft";
	}


	override hash_t toHash() {
		return 1;
	}

	override bool opEquals(Object o) {
		AttackerTurnLeft2 p = cast(AttackerTurnLeft2)o;

		return p && true;

	}

	override int opCmp(Object o) {
		AttackerTurnLeft2 p = cast(AttackerTurnLeft2)o;

		if (!p)
			return -1;

		return 0;

	}

}

public class AttackerTurnRight : Action {
	
	AttackerModel model;
	
	public this(AttackerModel m) {
		model = m;
	}
	
	public override State apply(State state) {
		AttackerState p = cast(AttackerState)state;
		
		int orientation = p.getOrientation() - 1;
		
		if (orientation < 0)
			orientation = 3;
			
		int [] s = p.getLocation().dup;
		
		AttackerState a = new AttackerState(s, orientation, p.getTime() + 1);
						
		if (model.is_legal(a))
			return model.mapping[s[0]][s[1]][orientation][ p.getTime() + 1];
		else
			return a;
	}
	
	public override string toString() {
		return "AttackerTurnRight"; 
	}


	override hash_t toHash() {
		return 2;
	}	
	
	override bool opEquals(Object o) {
		AttackerTurnRight p = cast(AttackerTurnRight)o;
		
		return p && true;
		
	}
	
	override int opCmp(Object o) {
		AttackerTurnRight p = cast(AttackerTurnRight)o;
		
		if (!p) 
			return -1;
			
		return 0;
		
	}
		
}

public class AttackerTurnRight2 : Action {

	AttackerExtendedModel model;

	public this(AttackerExtendedModel m) {
		model = m;
	}

	public override State apply(State state) {
		AttackerExtendedState p = cast(AttackerExtendedState)state;

		int orientation = p.getOrientation() - 1;
        int cg = p.getCurrentGoal();
		if (orientation < 0)
			orientation = 3;

		int [] s = p.getLocation().dup;

		AttackerExtendedState a = new AttackerExtendedState(s, orientation, cg, p.getTime() + 1);

		if (model.is_legal(a))
			return model.mapping[s[0]][s[1]][orientation][ p.getTime() + 1];
		else
			return a;
	}

	public override string toString() {
		return "AttackerTurnRight";
	}


	override hash_t toHash() {
		return 2;
	}

	override bool opEquals(Object o) {
		AttackerTurnRight2 p = cast(AttackerTurnRight2)o;

		return p && true;

	}

	override int opCmp(Object o) {
		AttackerTurnRight2 p = cast(AttackerTurnRight2)o;

		if (!p)
			return -1;

		return 0;

	}

}


public class AttackerAction : Action {
	
	private int [] direction;
	
	public this (int [] direction) {
		this.direction = direction;
	}
	
	public override State apply(State state) {
		AttackerState p = cast(AttackerState)state;
		
		int [] newLocation = p.location.dup;
		
		newLocation[] += direction[];
		
		return new AttackerState(newLocation, p.time + 1);
		
	}
	
	public override string toString() {
		auto writer = appender!string();
		formattedWrite(writer, "AttackerAction: %(%s, %) ", this.direction);
		return writer.data;  
	}


	override hash_t toHash() {
		return direction[0] + direction[1];
	}	
	
	override bool opEquals(Object o) {
		AttackerAction a = cast(AttackerAction)o;
		
		if (!a)
			return false;
			
		for (int i = 0; i < direction.length; i ++) {
			if (a.direction[i] != direction[i])
				return false;
		}
		
		return true;
		
	}
	
	override int opCmp(Object o) {
		AttackerAction a = cast(AttackerAction)o;
		
		if (!a) 
			return -1;
		
		if (a.direction[0] < direction[0])
			return 1;
			
		if (a.direction[0] > direction[0])
			return -1;

		
		if (a.direction[1] < direction[1])
			return 1;
			
		if (a.direction[1] > direction[1])
			return -1;
			
		return 0;
		
	}
}

public class AttackerAction2 : Action {

	private int [] direction;

	public this (int [] direction) {
		this.direction = direction;
	}

	public override State apply(State state) {
		AttackerExtendedState p = cast(AttackerExtendedState)state;

		int [] newLocation = p.location.dup;
        int cg = p.getCurrentGoal();
		newLocation[] += direction[];

		return new AttackerExtendedState(newLocation, 0, cg, p.time + 1);

	}

	public override string toString() {
		auto writer = appender!string();
		formattedWrite(writer, "AttackerAction: %(%s, %) ", this.direction);
		return writer.data;
	}


	override hash_t toHash() {
		return direction[0] + direction[1];
	}

	override bool opEquals(Object o) {
		AttackerAction2 a = cast(AttackerAction2)o;

		if (!a)
			return false;

		for (int i = 0; i < direction.length; i ++) {
			if (a.direction[i] != direction[i])
				return false;
		}

		return true;

	}

	override int opCmp(Object o) {
		AttackerAction2 a = cast(AttackerAction2)o;

		if (!a)
			return -1;

		if (a.direction[0] < direction[0])
			return 1;

		if (a.direction[0] > direction[0])
			return -1;


		if (a.direction[1] < direction[1])
			return 1;

		if (a.direction[1] > direction[1])
			return -1;

		return 0;

	}
}

class AttackerModel : Model {
	
	byte [][] map;
	double p_fail;
	Action [] actions;
	State [] states;
	AttackerState [] goals;
	int maxTime;
	AttackerState caught;
	
	AttackerState [][][][] mapping;


	Model [] patrollerModels;
	Agent [] patrollerPolicies;
	State [] patrollerStartingStates;
	int [] patrollerStartingTimes;
	int pastProjectionTime;
	int detectDistance;
	int interactionLength;
	double[Action][] equilibria;
	double [][State][] projection;
	
	char [BoydState][] interactionStates;
	
	public this( double p_fail, byte[][] map, AttackerState [] goals, int maxTime, Model [] patrollerModels, Agent [] patrollerPolicies, State [] patrollerStartingStates, int [] patrollerStartingTimes, int detectDistance, int interactionLength, double[Action][]  equilibria, size_t projectionSamples)
	in {
		enforce (patrollerPolicies.length <= 2, "AttackerRewardPatrollerProjectionBoyd only supports projection of 2 robots at this time");	
	}
	body {
		this.p_fail = p_fail;
		this.goals = goals;
		this.maxTime = maxTime;
		this.map = map;

		this.patrollerModels = patrollerModels;
		this.detectDistance = detectDistance;
		this.maxTime = maxTime;
		this.interactionLength = interactionLength;
		this.equilibria = equilibria;
		
		
		this.actions ~= new AttackerMoveForward(this);
		this.actions ~= new AttackerTurnLeft(this);
		this.actions ~= new AttackerTurnRight(this);
		
				
		if (patrollerPolicies.length > 0) {
		
			createInteractionStates();
			this.patrollerPolicies = patrollerPolicies;
			this.patrollerStartingStates = patrollerStartingStates;
			this.patrollerStartingTimes = patrollerStartingTimes;
			pastProjectionTime = reduce!((a, b) {return a > b ? a : b;})(0, patrollerStartingTimes);

			debug {
				writeln("Start Projections calculation");
			}
			if (projectionSamples > 0) {
				createProjectionUsingSampling(projectionSamples);
			} else {
				createProjection();
			}

		}
		
		debug {
			writeln("Projections calculated");
			
		}
		
		mapping.length = map.length;
		
		for (int i = 0; i < map.length; i ++) {
			
			mapping[i].length = map[i].length;
			for (int j = 0; j < map[i].length; j ++) {
				if (map[i][j] == 1) {
					mapping[i][j].length = 4;
					for (int t = 0; t < maxTime; t ++) {
						for (int o = 0; o < 4; o ++) {
							mapping[i][j][o].length = maxTime;
							
							AttackerState state = new AttackerState([i, j], o, t);
							
							double [] totalDetectionProb;
							totalDetectionProb.length = patrollerPolicies.length;
							totalDetectionProb[] = 0;

							if (projection.length > 0) {
								double[][State] proj = projection[state.getTime() + pastProjectionTime];
								foreach (pat_s, pr_s_array; proj) {
								 	AttackerState pat = convertPatrollerStateToAttacker(pat_s);
									double distance = state.distance(pat);
									double distanceFactor = distance <= detectDistance ? 1.0 : 0.0;
							        if (distanceFactor > 1.0)
							            distanceFactor = 1.0;
							        
							        int directionFactor = 0;    
							        if (getDirectionFactor(pat, state)) 
							        	directionFactor = 1;
							        	
						//    		writeln("Detection: ", distanceFactor, " ", penaltyForDiscovery, " ", directionFactor, " - ", state, " <> ", pat );
						    		foreach (i, pr_s; pr_s_array) {
						    			totalDetectionProb[i] += pr_s * distanceFactor * directionFactor;
						    		}	
						        }
							
							
						        state.setDetectionProb(totalDetectionProb[0] * totalDetectionProb[1] + (1.0 - totalDetectionProb[0]) * totalDetectionProb[1] + totalDetectionProb[0] * (1.0 - totalDetectionProb[1]));
						    }

					        states ~= state;
					        
					        mapping[i][j][o][t] = state;
						}
					}
				}
			}
		}
		
		caught = new AttackerState([0, 0], 0, -1, -1);
		
		states ~= caught;
		  
	}
	
	public override int numTFeatures() {
		return 0;
	}
		
	public override int [] TFeatures(State state, Action action) {
		return null;
	}
	
	public override double[State] T(State state, Action action) {
		double[State] returnval;
		
		Action [] actions = A(state);

        // unfortunately have to assume we're using attackerStates here
        AttackerState aState = cast(AttackerState)state;
        State oldState = new AttackerState(aState.getLocation().dup, aState.getOrientation(), aState.getTime() + 1);
        
        if (! is_legal(oldState)) {
        	oldState = state;
        } else {
        	oldState = mapping[aState.getLocation()[0]][aState.getLocation()[1]][aState.getOrientation()][aState.getTime() + 1];
        }
        		
		double probOfCaught = aState.getDetectionProb();  
		returnval[caught] = probOfCaught;
		
		double totalP = probOfCaught;
		foreach (Action a ; actions) {
			double p = 0;
			if (a == action) {
				p = (1.0 - p_fail);
			} else {
				p = p_fail / (actions.length - 1);
			}
			p *= (1.0 - probOfCaught);
			
			State s_prime = a.apply(state);
			
			if (! is_legal(s_prime) ) {
				returnval[oldState] += p;
			} else {
				returnval[s_prime] += p;
			}
			totalP += p;
		}
		
		returnval[oldState] += 1.0 - totalP;
		
		return returnval;
	}
	
	public override State [] S () {
		return states;
	}
	
	public override Action[] A(State state = null) {
		return actions;
		
	}
	
	public override bool is_terminal(State state) {
		AttackerState p = cast(AttackerState)state;
		
		if (p && p == caught)
			return true;
			
		foreach (t; goals) {
			if ((p.location[0] == t.location[0] && p.location[1] == t.location[1]) || ( p.time == maxTime - 1)) {
				return true;
			}
		}
		return false;
		
	}
	
	public override bool is_legal(State state) {
		AttackerState a = cast(AttackerState)state;
		int [] l = a.location;
		
		return l[0] >= 0 && l[0] < map.length && l[1] >= 0 && l[1] < map[0].length && map[l[0]][l[1]] == 1 && a.time >= 0 && a.time < maxTime && a.totalDetectionProb <= 1; 
	}
	

	public override int [] obsFeatures(State state, Action action, State obState, Action obAction) {
		int [] returnval;
		return returnval;
	}

	public override void setNumObFeatures(int inpNumObFeatures){
		return;
	}

	public override int getNumObFeatures(){
		int returnval;
		return returnval;
	}

	public override void setObsMod(double [StateAction][StateAction] newObsMod) {
		return;
	}

	public override StateAction noiseIntroduction(State s, Action a) {
		StateAction sa = new StateAction(s,a);
		return sa;
	}
		
	public double [][State][] getProjection() {
		return projection;
	}
	
	private void createInteractionStates()
	in {
		enforce (patrollerModels.length == 2, "createInteractionStates only supports 2 robots at this time");	
	}
	body {
		foreach(BoydState s; cast(BoydState[])(cast(BoydModel)patrollerModels[0]).S()) {
			bool inBoth = false;
			
			foreach(BoydState check; cast(BoydState[])(cast(BoydModel)patrollerModels[0]).S()) {
				if (check == s) {
					inBoth = true;
					break;
				}
			}
			bool add = true;
			foreach (ref iS; interactionStates) {
				if (s in iS) {
					add = false;
					break;
				}
				foreach (otherS; iS.byKey()) {
					if (otherS.samePlaceAs(s)) {
						iS[s] = 'a';
						add = false;
						break;
					}
					
				}
				
			}
			if (add) {
				char [BoydState] temp;
				temp[s] = 'a';
				
				interactionStates ~= temp;
			}
		}			
		
		
	}

	private void createProjectionUsingSampling(size_t samples) {
		
		/*
			create an attackerstate counter for each generated trajectory
			for each timestep create the probability of occupation array for each patroller, this is the projection
		*/
		
		projection.length = maxTime + pastProjectionTime; 
		
		
		foreach (i; 0..samples) {
			
			State [][] traj = createTrajectories();
			
			foreach (p, pat; traj) {

				foreach (timestep, state; pat) {
					if (state is null)
						continue;
					if (! (state in projection[timestep])) {
						projection[timestep][state] = new double [patrollerPolicies.length];
						projection[timestep][state][] = 0;
					}
					projection[timestep][state][p] += (1.0 / samples);
				}
			}
		}
	}

	private State [][] createTrajectories() {
		/*
			1.  Simulate the older of the patrollers until it and the younger are equal in time
			2.  Simulate both patrollers startingTime + maxTime using multi_simulate
		*/
		patrollerModels[0].setReward(new FakeReward());
		patrollerModels[1].setReward(new FakeReward());
		
		int min = int.max;
		foreach (start; patrollerStartingTimes) {
			if (start < min)
				min = start;
		}
		
		int [] sim_times = new int[patrollerStartingTimes.length];
		sim_times[] = patrollerStartingTimes[] - min;
		
		auto max_sim_time = reduce!((a, b) {return a > b ? a : b;})(0, sim_times);
		
		State [] startStates = patrollerStartingStates.dup;
       	
       	State [][] patrollerPositions;
       	patrollerPositions.length = patrollerPolicies.length;
       	foreach (ref p; patrollerPositions) {
       		p.length = max_sim_time;
       	}
		
		foreach (int num, State startState; patrollerStartingStates) {
			double[State] initial;
			foreach (s; patrollerModels[num].S()) 
				initial[s] = 0;
			
			initial[patrollerStartingStates[num]] = 1;
			Distr!State.normalize(initial);
			
			
			
			foreach (size_t timestep, sar s; simulate(patrollerModels[num], patrollerPolicies[num], initial, sim_times[num] + 1)) {
				startStates[num] = s.s;
				if (timestep < sim_times[num])
					patrollerPositions[num][(max_sim_time - sim_times[num]) + timestep] = s.s;
			}
		}

		double[State][] initials = new double[State][startStates.length];
		foreach (int i, State startState; startStates) {
			foreach (s; patrollerModels[i].S()) 
				initials[i][s] = 0;
			
			initials[i][startState] = 1;
			Distr!State.normalize(initials[i]);
		}

       	sar [][] temp = multi_simulate(patrollerModels, patrollerPolicies, initials, min + maxTime, equilibria, interactionLength);


		foreach (int num, sar [] sarArr; temp) {
			
			foreach (int timestep, sar s; sarArr) {
				patrollerPositions[num] ~= s.s;
			}
			
		}
//		writeln(patrollerPositions);

		return patrollerPositions;
	}


	
	private void createProjection() {
	
		
		double [][AugmentedState] prevAS;
		double [][AugmentedState] curAS;
		
		// calculate projection relative times here
		
		int [] projectionStartTimes;

		foreach (start; patrollerStartingTimes) {
			projectionStartTimes ~= pastProjectionTime - start;
		}
		
		int totalProjectionTime = maxTime + pastProjectionTime;
		
		foreach (t; 0..totalProjectionTime) {
			
			double [][][] inflightProbMassMatrix = new double[][][patrollerPolicies.length];
			// initialize matrix to zeros
			
			foreach (ref i; inflightProbMassMatrix) {
				
				// TODO: This is wrong and will break if the two patrollermodels have different maps!
				double [][] j = new double [][patrollerModels[0].S().length];
				foreach (ref k; j) {
					double [] l = new double[patrollerModels[0].S().length];
					l[] = 0;
					
					k ~= l;
				}
				i ~= j;
				
			}
			
			// should we insert the agent's starting state now?
			foreach (i, projStartTime; projectionStartTimes) {
				if (projStartTime == t) {
					AugmentedState toSearch = AugmentedState(cast(BoydState)(patrollerStartingStates[i]), 0);
					
					if ( toSearch !in curAS) {
						double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
						curAS[toSearch] = temp;
						curAS[toSearch][] = 0;
					}
					curAS[toSearch][i] = 1.0;
				}
			}
			
			// go through each prevAS, applying actions to create new AS's that are stored in curAS
			
			foreach (ref as; prevAS.byKey()) {
			
				if (as.interactionStep > 0) {
					AugmentedState newas = AugmentedState(as.s, as.interactionStep - 1);
					
					if (newas.interactionStep == 0) {
						// perform equilibria
					
						foreach(i, ref equil; equilibria) {
							foreach(a, pr_a; equil) {
								foreach(s_prime, pr_s_prime; patrollerModels[i].T(newas.s, a)) {
									AugmentedState tempas = AugmentedState(cast(BoydState)s_prime, 0);
									if (! (tempas in curAS)) {
										double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
										curAS[tempas] = temp;
										curAS[tempas][] = 0;

										curAS[tempas][i] = pr_a * pr_s_prime * prevAS[as][i];
									} else {
										curAS[tempas][i] += pr_a * pr_s_prime * prevAS[as][i];
									}
								}
							}
						}
					} else {
						// just store it in curAS
						
						curAS[newas] = prevAS[as];
					
					}
					
				} else {
					// perform policy actions
					
					// find the interaction state for the current augmented state
					size_t asIs = size_t.max;
					foreach (i, ref iS; patrollerModels[0].S()) {
						if (as.s == iS) {
							asIs = i;
							break;
						}
					}
					
					
					foreach(i, ref patrollerPolicy; patrollerPolicies) {
						foreach(a, pr_a; patrollerPolicy.actions(as.s)) {
							foreach(s_prime, pr_s_prime; patrollerModels[i].T(as.s, a)) {
								AugmentedState tempas = AugmentedState(cast(BoydState)s_prime, 0);
								auto prob = pr_a * pr_s_prime * prevAS[as][i];
								if (! (tempas in curAS)) {
									double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
									curAS[tempas] = temp;
									curAS[tempas][] = 0;
									curAS[tempas][i] = prob;
								} else {
									curAS[tempas][i] += prob;
								}
								
								size_t tempasIs = size_t.max;
								foreach (k, ref iS; patrollerModels[0].S()) {
									if (tempas.s == iS) {
										tempasIs = k;
										break;
									}
								}
								
								inflightProbMassMatrix[i][asIs][tempasIs] += prob;
							}
						}	
					}
				}
			
			}
			
//			writeln(inflightProbMassMatrix);
//			writeln();
			
			// detect interactions from multiple agents being in the same state and split off the joint probability into an 
			// interaction state and add this to curAS
			// TODO: we only support two agents at this point in time, but this could be fixed by considering every combination of agents
			if (interactionLength > 0) {
				foreach (ref iS; interactionStates) {
									
					double [] sum = new double[patrollerPolicies.length];
					sum[] = 0;
					
					foreach (s; iS.byKey()) {
						
						AugmentedState as = AugmentedState(s, 0);
						
						if (as in curAS) {
							sum[] += curAS[as][];
						}	
					}
					
					double [] sum2;
					
					foreach_reverse (p; sum) {
						sum2 ~= p;
					}
					sum = sum2.dup;
					sum[] = 1 - sum[];
					// sum2[x] = chance of interaction for a state
					// sum[x] = chance of no interaction  
	
					foreach (s; iS.byKey()) {
						
						
						auto newas = AugmentedState(s, interactionLength);
						auto as = AugmentedState(s, 0);
	
						if (as !in curAS) {
							continue;
						}
						
						curAS[newas] = curAS[as].dup;
						curAS[newas][] *= sum2[]; 					
						
						curAS[as][] *= sum[];
					}
					
	
				}
				// now catch the probability mass that interacts "in flight", ie two interaction states that exchange probabilities
				
				foreach (agent, ref iss; inflightProbMassMatrix) {
					foreach (ss, ref startState; patrollerModels[0].S()) {
	
						size_t ssIs = size_t.max;
						foreach (i, ref iS; interactionStates) {
							if (cast(BoydState)startState in iS) {
								ssIs = i;
								break;
							}
						}
						foreach (es, ref endState; patrollerModels[0].S()) {
							
							if (iss[ss][es] == 0)
								continue;
								
							size_t esIs = size_t.max;
							foreach (i, ref iS; interactionStates) {
								if (cast(BoydState)endState in iS) {
									esIs = i;
									break;
								}
							}	
							
							if (ssIs != esIs) {
								// we have some (maybe zero) probability mass moving between two interaction states
								// need to multiply the curAS probabity at the end state by the probability of the 
								// other agent moving from esIs to ssIs, and add this to the interaction at endState
								// (subtract from the non interaction prob at endState
								
								
								// calculate the probability mass for the other agent ( sum of all states in es moving to ss)
								
								// multiply the ss -> es prob by this sum to get the prob of inflight interaction
								
								// now multiply 1 - this with the prob at es and add to the interaction at es
								
								
								double sum = 0;
								foreach (esbs; interactionStates[esIs].byKey()) {
									
									size_t esbsid = size_t.max;
									
									foreach (i, ref s; patrollerModels[0].S()) {
										if (s == esbs) {
											esbsid = i;
											break;
										}
										
									} 
									foreach (ssbs; interactionStates[ssIs].byKey()) {
										size_t ssbsid = size_t.max;
										
										foreach (i, ref s; patrollerModels[0].S()) {
											if (s == ssbs) {
												ssbsid = i;
												break;
											}
											
										}
										
										
										sum += inflightProbMassMatrix[1-agent][esbsid][ssbsid];
									}
									
								}
								
								double inflightInteractionProb = sum * iss[ss][es]; 
								
								auto tempas = AugmentedState(cast(BoydState)endState, 0);
								
								curAS[tempas][agent] -= inflightInteractionProb;
								
								tempas = AugmentedState(cast(BoydState)endState, 3);
								
								if (tempas in curAS) {
									curAS[tempas][agent] += inflightInteractionProb;
								} else {
									double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
									curAS[tempas] = temp;
									curAS[tempas][] = 0;
									curAS[tempas][agent] = inflightInteractionProb;
								}
								
								
							}
							
						}
					}
				}

			}
			
			
			
		
			// build the projection array from prevAS
			
			double[][State] dist;


			foreach(s; patrollerModels[0].S()) {
				double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
				dist[s] = temp;
				dist[s][] = 0;
			}

			foreach (ref as; curAS.byKey()) {
				dist[as.s][] += curAS[as][];				
			}

			projection ~= dist;

			prevAS = curAS;
			
			curAS = null;
		
		}
		
		
	}



	struct AugmentedState {
	
		this(BoydState bs, int i) {
			s = bs;
			interactionStep = i;
		}
		
		BoydState s;
		int interactionStep;
		
		
  		
		bool opEquals(ref const AugmentedState rhs) const{
			writeln("opEquals");
			return s == rhs.s && interactionStep == rhs.interactionStep;
		}
		
		hash_t toHash() const {

			string temp = text(s.toHash(), interactionStep);
			return parse!hash_t(temp);
		}
		
		int opCmp(ref const AugmentedState o) const {
			if (toHash() < o.toHash()) 
				return -1;
			if (toHash() > o.toHash())
				return 1;

			if (s < cast(BoydState)o.s) 
				return -1;
			if (s > cast(BoydState)o.s)
				return 1;
			
			if (interactionStep < o.interactionStep)
				return -1;
			if (interactionStep > o.interactionStep)
				return 1;
								
			return 0;
			
		}
		
	};
	
	
	unittest {
		
		// first with deterministic T
		
		
		byte [][] map  = 		[[1, 1, 1, 1, 1]];
		
		BoydModel [] pmodel;
		pmodel  ~= new BoydModel(null, map, null, 1, &simplefeatures);
		pmodel  ~= new BoydModel(null, map, null, 1, &simplefeatures);
		
		double [] weights = [1];
		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));


		double reward = 0;
		double maxDetectionRisk = 0;

		Action[State] policy;
		foreach (s; pmodel[0].S()) {
			policy[s] = new MoveForwardAction();
		}

	    Agent [] agents;
    	agents ~= new MapAgent(policy);
    	agents ~= new MapAgent(policy);
    	
    	BoydState [] startingStates;
		int [] startingTimes;
		
		startingStates ~= new BoydState([0, 0, 0]);
		startingStates ~= new BoydState([0, 4, 2]);
		
		startingTimes ~= 0;
		startingTimes ~= 0;
		
		int detectDistance = 1;
		int predictTime = 2;
		int interactionLength = 0;
		
	    double[Action][] equilibria = new double[Action][2];
	    equilibria[0][new MoveForwardAction()] = 1.0;
	    equilibria[1][new StopAction()] = 1.0;



		AttackerModel aModel = new AttackerModel(0.95, map, new AttackerState([0, 4],0), predictTime);
	
		AttackerRewardPatrollerProjectionBoyd aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
		
		double [][State][] proj = aReward.getProjection();
		
		//writeln(proj);
		// should've set the initial states correctly 
		
		assert(proj[0][startingStates[0]][0] == 1.0);
		assert(proj[0][startingStates[1]][1] == 1.0);
		
		// should've moved the patrollers forward one step
		
		BoydState testState = new BoydState([0,1,0]);
		assert(proj[1][testState][0] == 1.0);
		testState = new BoydState([0,3,2]);
		assert(proj[1][testState][1] == 1.0);
		
		
		
		// now again with non-deterministic T
		double error = .001;
		
		weights = [0.95];
		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
		
		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
		
		proj = aReward.getProjection();

		//writeln(proj);
		// should've set the initial states correctly 

		assert(proj[0][startingStates[0]][0] == 1.0);
		assert(proj[0][startingStates[1]][1] == 1.0);
		
		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,1,0]);
		assert(abs(proj[1][testState][0] - weights[0]) < error);
		testState = new BoydState([0,3,2]);
		assert(abs(proj[1][testState][1] - weights[0]) < error);

		// make sure the total probability per timestep sums to one

		foreach (i; 0..agents.length) {
			foreach (t; proj) {
				double sum = 0;
				foreach (s; pmodel[0].S()) {
					sum += t[s][i];
				}
				assert (abs(sum - 1.0) < error);
			}
		}
		
		// now test interaction with deterministic T
		
		
		weights = [1];
		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
		interactionLength = 3;
		predictTime = 10;
		
		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
		
		proj = aReward.getProjection();
		
		//writeln(proj);
		// should've set the initial states correctly 
		
		assert(proj[0][startingStates[0]][0] == 1.0);
		assert(proj[0][startingStates[1]][1] == 1.0);
		
		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,1,0]);
		assert(proj[1][testState][0] == 1.0);
		testState = new BoydState([0,3,2]);
		assert(proj[1][testState][1] == 1.0);
		
		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,2,0]);
		assert(proj[2][testState][0] == 1.0);
		testState = new BoydState([0,2,2]);
		assert(proj[2][testState][1] == 1.0);

		// now we're interacting for 3 steps, on the 3rd step perform the interaction action

		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,2,0]);
		assert(proj[3][testState][0] == 1.0);
		assert(proj[4][testState][0] == 1.0);
		testState = new BoydState([0,2,2]);
		assert(proj[3][testState][1] == 1.0);
		assert(proj[4][testState][1] == 1.0);
		
		testState = new BoydState([0,3,0]);
		assert(proj[5][testState][0] == 1.0);
		testState = new BoydState([0,2,2]);
		assert(proj[5][testState][1] == 1.0);

		
		// now test interaction with non-deterministic T
		
		
		weights = [0.95];
		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
		interactionLength = 3;
		predictTime = 10;
		
//		writeln();
//		writeln();
//		writeln();
		
		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
		
		proj = aReward.getProjection();
		
		//writeln(proj);
		// should've set the initial states correctly 
		
		assert(proj[0][startingStates[0]][0] == 1.0);
		assert(proj[0][startingStates[1]][1] == 1.0);
		
		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,1,0]);
		assert(abs(proj[1][testState][0] - weights[0]) < error);
		testState = new BoydState([0,3,2]);
		assert(abs(proj[1][testState][1] - weights[0]) < error);
		
		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,2,0]);
		assert(abs(proj[2][testState][0] - weights[0]*weights[0]) < error);
		testState = new BoydState([0,2,2]);
		assert(abs(proj[2][testState][1] - weights[0]*weights[0]) < error);

		// now we're interacting for 3 steps, on the 3rd step perform the interaction action
		// but only weights[0]^4 has entered the interaction, (weight[0]^2 - weights[0]^4) has moved forward, leaving 1 - T behind 
		double wsq = (weights[0]*weights[0]);
		double wft = wsq * wsq;

		testState = new BoydState([0,2,0]);
//		writeln(proj[3][testState][0], " => ", wft, ", ", (wsq - wft)*(1 - weights[0])/4, ", ", weights[0]*(proj[2][new BoydState([0,1,0])][0])," ",(wft + (wsq - wft)*(1 - weights[0])/4 + weights[0]*(proj[2][new BoydState([0,1,0])][0])));
		assert(abs(proj[3][testState][0] - (wft + (wsq - wft)*(1 - weights[0])/4 + weights[0]*(proj[2][new BoydState([0,1,0])][0]))) < error);
//		writeln(proj[4][testState][0], " => ", wft, ", ", (wsq - wft)*(1 - weights[0])/4*(1 - weights[0])/4, ", ", weights[0]*(proj[3][new BoydState([0,1,0])][0]),", ", (1 - weights[0])*weights[0]*(proj[2][new BoydState([0,1,0])][0])," ", (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,1,0])][0]) + (1 - weights[0])*weights[0]*(proj[2][new BoydState([0,1,0])][0])));
		assert(abs(proj[4][testState][0] - (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,1,0])][0])  + (1 - weights[0])*weights[0]*(proj[2][new BoydState([0,1,0])][0]))) < error);
		testState = new BoydState([0,2,2]);
		assert(abs(proj[3][testState][1] - (wft + (wsq - wft)*(1 - weights[0])/4 + weights[0]*(proj[2][new BoydState([0,3,2])][1]))) < error);
		assert(abs(proj[4][testState][1] - (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,3,2])][1])+ (1 - weights[0])*weights[0]*(proj[2][new BoydState([0,3,2])][1]))) < error);
		
		error = .1; // screw it, too tired to figure this out exactly
		testState = new BoydState([0,3,0]);
//		writeln(proj[5][testState][0], " => ", (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,1,0])][0]))*weights[0] + proj[4][testState][0]*(1-weights[0]) );
		// this is wrong, but close enough for these tests
		assert(abs(proj[5][testState][0] - ((wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,1,0])][0]))*weights[0] + proj[4][testState][0]*(1-weights[0]))) < error);
		testState = new BoydState([0,2,0]);
//		writeln(proj[5][testState][0], " => ", wft*(1-weights[0])/4 + proj[4][new BoydState([0,1,0])][1]*weights[0]);
		// this is wrong, but close enough for these tests
		assert(abs(proj[5][testState][0] - (wft*(1-weights[0])/4 + proj[4][new BoydState([0,1,0])][1]*weights[0])) < error);		
		testState = new BoydState([0,2,2]);
		assert(abs(proj[5][testState][1] - (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,3,2])][1]))*weights[0]) < error);
		
		error = .001;
		
		// make sure the total probability per timestep sums to one

		foreach (i; 0..agents.length) {
			foreach (t; proj) {
				double sum = 0;
				foreach (s; pmodel[0].S()) {
					sum += t[s][i];
				}
				assert (abs(sum - 1.0) < error);
			}
		}		
		
		// now test past prediction times

		weights = [1];
		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
		interactionLength = 1;
		predictTime = 2;

		startingTimes[0] = 4;
		startingTimes[1] = 0;
		
		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
		
		proj = aReward.getProjection();

		// should've set the initial states correctly 
		//writeln(proj);
		assert(proj[0][startingStates[0]][0] == 1.0);
		assert(proj[4][startingStates[1]][1] == 1.0);
		
		// should've moved one patroller forward
		
		testState = new BoydState([0,4,0]);
		assert(proj[4][testState][0] == 1.0);
		testState = new BoydState([0,4,2]);
		assert(proj[4][testState][1] == 1.0);
		
		
		
		// Now need to catch instances of the patrollers not perfectly landing on each other (ie, stop the probability mass
		// from moving if it would pass through another)
		
		
		weights = [1];
		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
		interactionLength = 3;
		predictTime = 10;
		startingTimes[0] = 0;
		startingTimes[1] = 0;
		
		startingStates[1] = new BoydState([0, 3, 2]);
				
//		writeln();
//		writeln();
//		writeln();
		
		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
		
		proj = aReward.getProjection();
		
//		writeln(proj);
		assert(proj[0][startingStates[0]][0] == 1.0);
		assert(proj[0][startingStates[1]][1] == 1.0);
		
		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,1,0]);
		assert(proj[1][testState][0] == 1.0);
		testState = new BoydState([0,2,2]);
		assert(proj[1][testState][1] == 1.0);
		
		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,2,0]);
		assert(proj[2][testState][0] == 1.0);
		testState = new BoydState([0,1,2]);
		assert(proj[2][testState][1] == 1.0);

		// now we're interacting for 3 steps, on the 3rd step perform the interaction action

		// should've moved the patrollers forward one step
		
		testState = new BoydState([0,2,0]);
		assert(proj[3][testState][0] == 1.0);
		assert(proj[4][testState][0] == 1.0);
		testState = new BoydState([0,1,2]);
		assert(proj[3][testState][1] == 1.0);
		assert(proj[4][testState][1] == 1.0);
		
		testState = new BoydState([0,3,0]);
		assert(proj[5][testState][0] == 1.0);
		testState = new BoydState([0,1,2]);
		assert(proj[5][testState][1] == 1.0);

		
		
		writeln("Projection unit tests done");
				
	}
	
}


class AttackerExtendedModel : Model {

	byte [][] map;
	double p_fail;
	Action [] actions;
	State [] states;
	AttackerState [] goals;
	int maxTime;
	AttackerState caught;
	AttackerState [][][][] mapping;

	Model [] patrollerModels;
	Agent [] patrollerPolicies;
	State [] patrollerStartingStates;
	int [] patrollerStartingTimes;
	int pastProjectionTime;
	int detectDistance;
	int interactionLength;
	double[Action][] equilibria;
	double [][State][] projection;

	//char [BoydState][] interactionStates;
	char [BoydExtendedState2][] interactionStates;

	public this( double p_fail, byte[][] map, AttackerState [] goals, int maxTime, Model [] patrollerModels,
	Agent [] patrollerPolicies, State [] patrollerStartingStates, int [] patrollerStartingTimes, int detectDistance,
	int interactionLength, double[Action][]  equilibria, size_t projectionSamples)
	in {
		enforce (patrollerPolicies.length <= 2, "AttackerRewardPatrollerProjectionBoyd only supports projection of 2 robots at this time");
	}
	body {
		/*
		After
		the policies for each patrollers have been learned, L jointly projects forward in time, starting from
		the last position each patroller was observed at, to arrive at a prediction for the future positions
		of each patroller. These positions are noted in L’s MDP and any states which are visible from a
		patroller’s position at a given time step receive a negative reward. The goal state at all time steps
		is given a positive reward and the MDP is solved optimally. L then searches for a positive value
		at any time for its starting position and if found there must be a path to the goal that avoids
		detection starting at that time.
		*/
		this.p_fail = p_fail;
		this.goals = goals;
		this.maxTime = maxTime;
		this.map = map;

		this.patrollerModels = patrollerModels;
		this.detectDistance = detectDistance;
		this.maxTime = maxTime;
		this.interactionLength = interactionLength;
		this.equilibria = equilibria;


		this.actions ~= new AttackerMoveForward2(this);
		this.actions ~= new AttackerTurnLeft2(this);
		this.actions ~= new AttackerTurnRight2(this);


		if (patrollerPolicies.length > 0) {

			createInteractionStates();
			this.patrollerPolicies = patrollerPolicies;
			this.patrollerStartingStates = patrollerStartingStates;
			this.patrollerStartingTimes = patrollerStartingTimes;
			pastProjectionTime = reduce!((a, b) {return a > b ? a : b;})(0, patrollerStartingTimes);

			debug {
				writeln("Start Projections calculation");
			}
			if (projectionSamples > 0) {
				createProjectionUsingSampling(projectionSamples);
			} else {
				createProjection();
			}

		}

		debug {
			writeln("Projections calculated");

		}

		mapping.length = map.length;
        int [] cgoals = [0,1,2,3,4];// after projection, cg is not needed for attack
        int [] l;
        bool nextstatelegal, validgoal, validgoal0, validgoal4, validgoal1, validgoal2, validgoal3;
		for (int i = 0; i < map.length; i ++) {

    		mapping[i].length = map[i].length;
			for (int j = 0; j < map[i].length; j ++) {
				if (map[i][j] == 1) {
                    //foreach (int g; cgoals) {
                    //    l = [i,j];
                    //    validgoal0 = g==0 && l[0]>=6 && l[0 .. 2] != [6,0];
                    //    validgoal4 = g==4 && l[0]>=6 && l[0 .. 2] != [6,0];
                    //    validgoal1 = g==1 && l[0]<=6 && !(l[0] == 3 && l[1] > 4) && l[0 .. 2] != [0,8];
                    //    validgoal2 = g==2 && l[0]<=3 && l[0 .. 2] != [3,8];
                    //    validgoal3 = g==3 && l[0]>=3 && !(l[0] == 6 && l[1] < 4) && l[0 .. 2] != [9,0];
                    //    validgoal = validgoal0 || validgoal4 || validgoal1 || validgoal2 || validgoal3;

                        //if (validgoal) {
                    mapping[i][j].length = 4;
                    for (int t = 0; t < maxTime; t ++) {
                        for (int o = 0; o < 4; o ++) {
                            mapping[i][j][o].length = maxTime;

                            AttackerState state = new AttackerState([i, j], o, t);

                            double [] totalDetectionProb;
                            totalDetectionProb.length = patrollerPolicies.length;
                            totalDetectionProb[] = 0;

                            if (projection.length > 0) {
                                double[][State] proj = projection[state.getTime() + pastProjectionTime];
                                foreach (pat_s, pr_s_array; proj) {
                                    AttackerState pat = convertPatrollerStateToAttacker(pat_s);
                                    double distance = state.distance(pat);
                                    double distanceFactor = distance <= detectDistance ? 1.0 : 0.0;
                                    if (distanceFactor > 1.0)
                                        distanceFactor = 1.0;

                                    int directionFactor = 0;
                                    if (getDirectionFactor(pat, state))
                                        directionFactor = 1;

                        //    		writeln("Detection: ", distanceFactor, " ", penaltyForDiscovery, " ", directionFactor, " - ", state, " <> ", pat );
                                    foreach (i, pr_s; pr_s_array) {
                                        totalDetectionProb[i] += pr_s * distanceFactor * directionFactor;
                                    }
                                }


                                state.setDetectionProb(totalDetectionProb[0] * totalDetectionProb[1] + (1.0 - totalDetectionProb[0]) * totalDetectionProb[1] + totalDetectionProb[0] * (1.0 - totalDetectionProb[1]));
                            }

                            states ~= state;

                            mapping[i][j][o][t] = state;
                        }
                    }
                }
                 //   }
				//}
			}
		}

		caught = new AttackerState([0, 0], 0, -1, -1);

		states ~= caught;

	}

	public override int numTFeatures() {
		return 0;
	}

	public override int [] TFeatures(State state, Action action) {
		return null;
	}

	public override double[State] T(State state, Action action) {
		double[State] returnval;

		Action [] actions = A(state);

        // unfortunately have to assume we're using attackerStates here
        AttackerState aState = cast(AttackerState)state;
        State oldState = new AttackerState(aState.getLocation().dup, aState.getOrientation(), aState.getTime() + 1);

        if (! is_legal(oldState)) {
        	oldState = state;
        } else {
        	oldState = mapping[aState.getLocation()[0]][aState.getLocation()[1]][aState.getOrientation()][aState.getTime() + 1];
        }

		double probOfCaught = aState.getDetectionProb();
		returnval[caught] = probOfCaught;

		double totalP = probOfCaught;
		foreach (Action a ; actions) {
			double p = 0;
			if (a == action) {
				p = (1.0 - p_fail);
			} else {
				p = p_fail / (actions.length - 1);
			}
			p *= (1.0 - probOfCaught);

			State s_prime = a.apply(state);

			if (! is_legal(s_prime) ) {
				returnval[oldState] += p;
			} else {
				returnval[s_prime] += p;
			}
			totalP += p;
		}

		returnval[oldState] += 1.0 - totalP;

		return returnval;
	}

	public override State [] S () {
		return states;
	}

	public override Action[] A(State state = null) {
		return actions;

	}

	public override bool is_terminal(State state) {
		AttackerState p = cast(AttackerState)state;

		if (p && p == caught)
			return true;

		foreach (t; goals) {
			if ((p.location[0] == t.location[0] && p.location[1] == t.location[1]) || ( p.time == maxTime - 1)) {
				return true;
			}
		}
		return false;

	}

	public override bool is_legal(State state) {
		AttackerState a = cast(AttackerState)state;
		int [] l = a.location;

		return l[0] >= 0 && l[0] < map.length && l[1] >= 0 && l[1] < map[0].length &&
		map[l[0]][l[1]] == 1 && a.time >= 0 && a.time < maxTime && a.totalDetectionProb <= 1;
        //int g = a.current_goal;
		//bool legal_l = l[0] >= 0 && l[0] < map.length && l[1] >= 0 && l[1] < map[0].length && map[l[0]][l[1]] == 1;
		//bool legal_cg = g >= 0 && g <= 4;
		//bool validgoal, validgoal0, validgoal4, validgoal1, validgoal2, validgoal3;
        //validgoal0 = g==0 && l[0]>=6 && l[0 .. 2] != [6,0];
        //validgoal4 = g==4 && l[0]>=6 && l[0 .. 2] != [6,0];
        //validgoal1 = g==1 && l[0]<=6 && !(l[0] == 3 && l[1] > 4) && l[0 .. 2] != [0,8];
        //validgoal2 = g==2 && l[0]<=3 && l[0 .. 2] != [3,8];
        //validgoal3 = g==3 && l[0]>=3 && !(l[0] == 6 && l[1] < 4) && l[0 .. 2] != [9,0];
        //validgoal = validgoal0 || validgoal4 || validgoal1 || validgoal2 || validgoal3;
		//return legal_l && legal_cg && validgoal && a.time >= 0 && a.time < maxTime && a.totalDetectionProb <= 1;
	}


	public override int [] obsFeatures(State state, Action action, State obState, Action obAction) {
		int [] returnval;
		return returnval;
	}

	public override void setNumObFeatures(int inpNumObFeatures){
		return;
	}

	public override int getNumObFeatures(){
		int returnval;
		return returnval;
	}

	public override void setObsMod(double [StateAction][StateAction] newObsMod) {
		return;
	}

	public override StateAction noiseIntroduction(State s, Action a) {
		StateAction sa = new StateAction(s,a);
		return sa;
	}


	public double [][State][] getProjection() {
		return projection;
	}

	private void createInteractionStates()
	in {
		enforce (patrollerModels.length == 2, "createInteractionStates only supports 2 robots at this time");
	}
	body {
		foreach(BoydExtendedState2 s; cast(BoydExtendedState2[])(cast(BoydExtendedModel2)patrollerModels[0]).S()) {
			bool inBoth = false;

			foreach(BoydExtendedState2 check; cast(BoydExtendedState2[])(cast(BoydExtendedModel2)patrollerModels[0]).S()) {
				if (check == s) {
					inBoth = true;
					break;
				}
			}
			bool add = true;
			foreach (ref iS; interactionStates) {
				if (s in iS) {
					add = false;
					break;
				}
				foreach (otherS; iS.byKey()) {
					if (otherS.samePlaceAs(s)) {
						iS[s] = 'a';
						add = false;
						break;
					}

				}

			}
			if (add) {
				char [BoydExtendedState2] temp;
				temp[s] = 'a';

				interactionStates ~= temp;
			}
		}


	}

	private void createProjectionUsingSampling(size_t samples) {

		/*
			create an attackerstate counter for each generated trajectory
			for each timestep create the probability of occupation array for each patroller, this is the projection
		*/

		projection.length = maxTime + pastProjectionTime;


		foreach (i; 0..samples) {

			State [][] traj = createTrajectories();

			foreach (p, pat; traj) {

				foreach (timestep, state; pat) {
					if (state is null)
						continue;
					if (! (state in projection[timestep])) {
						projection[timestep][state] = new double [patrollerPolicies.length];
						projection[timestep][state][] = 0;
					}
					projection[timestep][state][p] += (1.0 / samples);
				}
			}
		}
	}

	private State [][] createTrajectories() {
		/*
			1.  Simulate the older of the patrollers until it and the younger are equal in time
			2.  Simulate both patrollers startingTime + maxTime using multi_simulate
		*/
		patrollerModels[0].setReward(new FakeReward());
		patrollerModels[1].setReward(new FakeReward());

		int min = int.max;
		foreach (start; patrollerStartingTimes) {
			if (start < min)
				min = start;
		}

		int [] sim_times = new int[patrollerStartingTimes.length];
		sim_times[] = patrollerStartingTimes[] - min;

		auto max_sim_time = reduce!((a, b) {return a > b ? a : b;})(0, sim_times);

		State [] startStates = patrollerStartingStates.dup;

       	State [][] patrollerPositions;
       	patrollerPositions.length = patrollerPolicies.length;
       	foreach (ref p; patrollerPositions) {
       		p.length = max_sim_time;
       	}

		foreach (int num, State startState; patrollerStartingStates) {
			double[State] initial;
			foreach (s; patrollerModels[num].S())
				initial[s] = 0;

			initial[patrollerStartingStates[num]] = 1;
			Distr!State.normalize(initial);



			foreach (size_t timestep, sar s; simulate(patrollerModels[num], patrollerPolicies[num], initial, sim_times[num] + 1)) {
				startStates[num] = s.s;
				if (timestep < sim_times[num])
					patrollerPositions[num][(max_sim_time - sim_times[num]) + timestep] = s.s;
			}
		}

		double[State][] initials = new double[State][startStates.length];
		foreach (int i, State startState; startStates) {
			foreach (s; patrollerModels[i].S())
				initials[i][s] = 0;

			initials[i][startState] = 1;
			Distr!State.normalize(initials[i]);
		}

       	sar [][] temp = multi_simulate(patrollerModels, patrollerPolicies, initials, min + maxTime, equilibria, interactionLength);


		foreach (int num, sar [] sarArr; temp) {

			foreach (int timestep, sar s; sarArr) {
				patrollerPositions[num] ~= s.s;
			}

		}
		//		writeln(patrollerPositions);

		return patrollerPositions;
	}



	private void createProjection() {


		double [][AugmentedState2] prevAS;
		double [][AugmentedState2] curAS;

		// calculate projection relative times here

		int [] projectionStartTimes;

		foreach (start; patrollerStartingTimes) {
			projectionStartTimes ~= pastProjectionTime - start;
		}

		int totalProjectionTime = maxTime + pastProjectionTime;

		foreach (t; 0..totalProjectionTime) {

			double [][][] inflightProbMassMatrix = new double[][][patrollerPolicies.length];
			// initialize matrix to zeros

			foreach (ref i; inflightProbMassMatrix) {

				// TODO: This is wrong and will break if the two patrollermodels have different maps!
				double [][] j = new double [][patrollerModels[0].S().length];
				foreach (ref k; j) {
					double [] l = new double[patrollerModels[0].S().length];
					l[] = 0;

					k ~= l;
				}
				i ~= j;

			}

			// should we insert the agent's starting state now?
			foreach (i, projStartTime; projectionStartTimes) {
				if (projStartTime == t) {
					AugmentedState2 toSearch = AugmentedState2(cast(BoydExtendedState2)(patrollerStartingStates[i]), 0);

					if ( toSearch !in curAS) {
						double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
						curAS[toSearch] = temp;
						curAS[toSearch][] = 0;
					}
					curAS[toSearch][i] = 1.0;
				}
			}

			// go through each prevAS, applying actions to create new AS's that are stored in curAS

			foreach (ref as; prevAS.byKey()) {

				if (as.interactionStep > 0) {
					AugmentedState2 newas = AugmentedState2(as.s, as.interactionStep - 1);

					if (newas.interactionStep == 0) {
						// perform equilibria

						foreach(i, ref equil; equilibria) {
							foreach(a, pr_a; equil) {
								foreach(s_prime, pr_s_prime; patrollerModels[i].T(newas.s, a)) {
									AugmentedState2 tempas = AugmentedState2(cast(BoydExtendedState2)s_prime, 0);
									if (! (tempas in curAS)) {
										double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
										curAS[tempas] = temp;
										curAS[tempas][] = 0;

										curAS[tempas][i] = pr_a * pr_s_prime * prevAS[as][i];
									} else {
										curAS[tempas][i] += pr_a * pr_s_prime * prevAS[as][i];
									}
								}
							}
						}
					} else {
						// just store it in curAS

						curAS[newas] = prevAS[as];

					}

				} else {
					// perform policy actions

					// find the interaction state for the current augmented state
					size_t asIs = size_t.max;
					foreach (i, ref iS; patrollerModels[0].S()) {
						if (as.s == iS) {
							asIs = i;
							break;
						}
					}


					foreach(i, ref patrollerPolicy; patrollerPolicies) {
						foreach(a, pr_a; patrollerPolicy.actions(as.s)) {
							foreach(s_prime, pr_s_prime; patrollerModels[i].T(as.s, a)) {
								AugmentedState2 tempas = AugmentedState2(cast(BoydExtendedState2)s_prime, 0);
								auto prob = pr_a * pr_s_prime * prevAS[as][i];
								if (! (tempas in curAS)) {
									double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
									curAS[tempas] = temp;
									curAS[tempas][] = 0;
									curAS[tempas][i] = prob;
								} else {
									curAS[tempas][i] += prob;
								}

								size_t tempasIs = size_t.max;
								foreach (k, ref iS; patrollerModels[0].S()) {
									if (tempas.s == iS) {
										tempasIs = k;
										break;
									}
								}

								inflightProbMassMatrix[i][asIs][tempasIs] += prob;
							}
						}
					}
				}

			}

			//			writeln(inflightProbMassMatrix);
			//			writeln();

			// detect interactions from multiple agents being in the same state and split off the joint probability into an
			// interaction state and add this to curAS
			// TODO: we only support two agents at this point in time, but this could be fixed by considering every combination of agents
			if (interactionLength > 0) {
				foreach (ref iS; interactionStates) {

					double [] sum = new double[patrollerPolicies.length];
					sum[] = 0;

					foreach (s; iS.byKey()) {

						AugmentedState2 as = AugmentedState2(s, 0);

						if (as in curAS) {
							sum[] += curAS[as][];
						}
					}

					double [] sum2;

					foreach_reverse (p; sum) {
						sum2 ~= p;
					}
					sum = sum2.dup;
					sum[] = 1 - sum[];
					// sum2[x] = chance of interaction for a state
					// sum[x] = chance of no interaction

					foreach (s; iS.byKey()) {


						auto newas = AugmentedState2(s, interactionLength);
						auto as = AugmentedState2(s, 0);

						if (as !in curAS) {
							continue;
						}

						curAS[newas] = curAS[as].dup;
						curAS[newas][] *= sum2[];

						curAS[as][] *= sum[];
					}


				}
				// now catch the probability mass that interacts "in flight", ie two interaction states that exchange probabilities

				foreach (agent, ref iss; inflightProbMassMatrix) {
					foreach (ss, ref startState; patrollerModels[0].S()) {

						size_t ssIs = size_t.max;
						foreach (i, ref iS; interactionStates) {
							if (cast(BoydExtendedState2)startState in iS) {
								ssIs = i;
								break;
							}
						}
						foreach (es, ref endState; patrollerModels[0].S()) {

							if (iss[ss][es] == 0)
								continue;

							size_t esIs = size_t.max;
							foreach (i, ref iS; interactionStates) {
								if (cast(BoydExtendedState2)endState in iS) {
									esIs = i;
									break;
								}
							}

							if (ssIs != esIs) {
								// we have some (maybe zero) probability mass moving between two interaction states
								// need to multiply the curAS probabity at the end state by the probability of the
								// other agent moving from esIs to ssIs, and add this to the interaction at endState
								// (subtract from the non interaction prob at endState


								// calculate the probability mass for the other agent ( sum of all states in es moving to ss)

								// multiply the ss -> es prob by this sum to get the prob of inflight interaction

								// now multiply 1 - this with the prob at es and add to the interaction at es


								double sum = 0;
								foreach (esbs; interactionStates[esIs].byKey()) {

									size_t esbsid = size_t.max;

									foreach (i, ref s; patrollerModels[0].S()) {
										if (s == esbs) {
											esbsid = i;
											break;
										}

									}
									foreach (ssbs; interactionStates[ssIs].byKey()) {
										size_t ssbsid = size_t.max;

										foreach (i, ref s; patrollerModels[0].S()) {
											if (s == ssbs) {
												ssbsid = i;
												break;
											}

										}


										sum += inflightProbMassMatrix[1-agent][esbsid][ssbsid];
									}

								}

								double inflightInteractionProb = sum * iss[ss][es];

								auto tempas = AugmentedState2(cast(BoydExtendedState2)endState, 0);

								curAS[tempas][agent] -= inflightInteractionProb;

								tempas = AugmentedState2(cast(BoydExtendedState2)endState, 3);

								if (tempas in curAS) {
									curAS[tempas][agent] += inflightInteractionProb;
								} else {
									double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
									curAS[tempas] = temp;
									curAS[tempas][] = 0;
									curAS[tempas][agent] = inflightInteractionProb;
								}


							}

						}
					}
				}

			}




			// build the projection array from prevAS

			double[][State] dist;


			foreach(s; patrollerModels[0].S()) {
				double [] temp = new double[patrollerPolicies.length];  // this is to get around a compiler bug in gdc4.6
				dist[s] = temp;
				dist[s][] = 0;
			}

			foreach (ref as; curAS.byKey()) {
				dist[as.s][] += curAS[as][];
			}

			projection ~= dist;

			prevAS = curAS;

			curAS = null;

		}


	}



	struct AugmentedState2 {

		this(BoydExtendedState2 bs, int i) {
			s = bs;
			interactionStep = i;
		}

		BoydExtendedState2 s;
		int interactionStep;



		bool opEquals(ref const AugmentedState2 rhs) const{
			writeln("opEquals");
			return s == rhs.s && interactionStep == rhs.interactionStep;
		}

		hash_t toHash() const {

			string temp = text(s.toHash(), interactionStep);
			return parse!hash_t(temp);
		}

		int opCmp(ref const AugmentedState2 o) const {
			if (toHash() < o.toHash())
				return -1;
			if (toHash() > o.toHash())
				return 1;

			if (s < cast(BoydExtendedState2)o.s)
				return -1;
			if (s > cast(BoydExtendedState2)o.s)
				return 1;

			if (interactionStep < o.interactionStep)
				return -1;
			if (interactionStep > o.interactionStep)
				return 1;

			return 0;

		}

	};


	//	unittest {
	//
	//		// first with deterministic T
	//
	//
	//		byte [][] map  = 		[[1, 1, 1, 1, 1]];
	//
	//		BoydExtendedModel2 [] pmodel;
	//		pmodel  ~= new BoydExtendedModel2(null, map, null, 1, &simplefeatures);
	//		pmodel  ~= new BoydExtendedModel2(null, map, null, 1, &simplefeatures);
	//
	//		double [] weights = [1];
	//		pmodel[0].setT(pmodel[0].createTransitionFunctionSimple2(0.01));
	//		pmodel[1].setT(pmodel[1].createTransitionFunctionSimple2(0.01));
	//
	//
	//		double reward = 0;
	//		double maxDetectionRisk = 0;
	//
	//		Action[State] policy;
	//		foreach (s; pmodel[0].S()) {
	//			policy[s] = new MoveForwardAction();
	//		}
	//
	//	    Agent [] agents;
	//    	agents ~= new MapAgent(policy);
	//    	agents ~= new MapAgent(policy);
	//
	//    	BoydExtendedState2 [] startingStates;
	//		int [] startingTimes;
	//
	//		startingStates ~= new BoydExtendedState2([9, 1, 0],0);
	//		startingStates ~= new BoydExtendedState2([9, 1, 1],0);
	//
	//		startingTimes ~= 0;
	//		startingTimes ~= 0;
	//
	//		int detectDistance = 1;
	//		int predictTime = 2;
	//		int interactionLength = 0;
	//
	//	    double[Action][] equilibria = new double[Action][2];
	//	    equilibria[0][new MoveForwardAction()] = 1.0;
	//	    equilibria[1][new StopAction()] = 1.0;
	//
	//
	//
	//		AttackerExtendedModel aModel = new AttackerExtendedModel(0.95, map, new AttackerState([0, 4],0), predictTime);
	//
	//		AttackerRewardPatrollerProjectionBoyd2 aReward = new AttackerRewardPatrollerProjectionBoyd2(new AttackerExtendedState([10, 4],1, 0),
	//		aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime,
	//		interactionLength, equilibria);
	//
	//		double [][State][] proj = aReward.getProjection();
	//
	//		//writeln(proj);
	//		// should've set the initial states correctly
	//
	//		assert(proj[0][startingStates[0]][0] == 1.0);
	//		assert(proj[0][startingStates[1]][1] == 1.0);
	//
	//		// should've moved the patrollers forward one step
	//
	//		BoydExtendedState2 testState = new BoydExtendedState2([0,1,0],0);
	//		assert(proj[1][testState][0] == 1.0);
	//		testState = new BoydState([0,3,2]);
	//		assert(proj[1][testState][1] == 1.0);
	//
	//		// now again with non-deterministic T
	//		double error = .001;
	//
	//		weights = [0.95];
	//		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
	//		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
	//
	//		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
	//
	//		proj = aReward.getProjection();
	//
	//		//writeln(proj);
	//		// should've set the initial states correctly
	//
	//		assert(proj[0][startingStates[0]][0] == 1.0);
	//		assert(proj[0][startingStates[1]][1] == 1.0);
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,1,0]);
	//		assert(abs(proj[1][testState][0] - weights[0]) < error);
	//		testState = new BoydState([0,3,2]);
	//		assert(abs(proj[1][testState][1] - weights[0]) < error);
	//
	//		// make sure the total probability per timestep sums to one
	//
	//		foreach (i; 0..agents.length) {
	//			foreach (t; proj) {
	//				double sum = 0;
	//				foreach (s; pmodel[0].S()) {
	//					sum += t[s][i];
	//				}
	//				assert (abs(sum - 1.0) < error);
	//			}
	//		}
	//
	//		// now test interaction with deterministic T
	//
	//
	//		weights = [1];
	//		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
	//		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
	//		interactionLength = 3;
	//		predictTime = 10;
	//
	//		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
	//
	//		proj = aReward.getProjection();
	//
	//		//writeln(proj);
	//		// should've set the initial states correctly
	//
	//		assert(proj[0][startingStates[0]][0] == 1.0);
	//		assert(proj[0][startingStates[1]][1] == 1.0);
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,1,0]);
	//		assert(proj[1][testState][0] == 1.0);
	//		testState = new BoydState([0,3,2]);
	//		assert(proj[1][testState][1] == 1.0);
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,2,0]);
	//		assert(proj[2][testState][0] == 1.0);
	//		testState = new BoydState([0,2,2]);
	//		assert(proj[2][testState][1] == 1.0);
	//
	//		// now we're interacting for 3 steps, on the 3rd step perform the interaction action
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,2,0]);
	//		assert(proj[3][testState][0] == 1.0);
	//		assert(proj[4][testState][0] == 1.0);
	//		testState = new BoydState([0,2,2]);
	//		assert(proj[3][testState][1] == 1.0);
	//		assert(proj[4][testState][1] == 1.0);
	//
	//		testState = new BoydState([0,3,0]);
	//		assert(proj[5][testState][0] == 1.0);
	//		testState = new BoydState([0,2,2]);
	//		assert(proj[5][testState][1] == 1.0);
	//
	//
	//		// now test interaction with non-deterministic T
	//
	//
	//		weights = [0.95];
	//		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
	//		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
	//		interactionLength = 3;
	//		predictTime = 10;
	//
	////		writeln();
	////		writeln();
	////		writeln();
	//
	//		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
	//
	//		proj = aReward.getProjection();
	//
	//		//writeln(proj);
	//		// should've set the initial states correctly
	//
	//		assert(proj[0][startingStates[0]][0] == 1.0);
	//		assert(proj[0][startingStates[1]][1] == 1.0);
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,1,0]);
	//		assert(abs(proj[1][testState][0] - weights[0]) < error);
	//		testState = new BoydState([0,3,2]);
	//		assert(abs(proj[1][testState][1] - weights[0]) < error);
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,2,0]);
	//		assert(abs(proj[2][testState][0] - weights[0]*weights[0]) < error);
	//		testState = new BoydState([0,2,2]);
	//		assert(abs(proj[2][testState][1] - weights[0]*weights[0]) < error);
	//
	//		// now we're interacting for 3 steps, on the 3rd step perform the interaction action
	//		// but only weights[0]^4 has entered the interaction, (weight[0]^2 - weights[0]^4) has moved forward, leaving 1 - T behind
	//		double wsq = (weights[0]*weights[0]);
	//		double wft = wsq * wsq;
	//
	//		testState = new BoydState([0,2,0]);
	////		writeln(proj[3][testState][0], " => ", wft, ", ", (wsq - wft)*(1 - weights[0])/4, ", ", weights[0]*(proj[2][new BoydState([0,1,0])][0])," ",(wft + (wsq - wft)*(1 - weights[0])/4 + weights[0]*(proj[2][new BoydState([0,1,0])][0])));
	//		assert(abs(proj[3][testState][0] - (wft + (wsq - wft)*(1 - weights[0])/4 + weights[0]*(proj[2][new BoydState([0,1,0])][0]))) < error);
	////		writeln(proj[4][testState][0], " => ", wft, ", ", (wsq - wft)*(1 - weights[0])/4*(1 - weights[0])/4, ", ", weights[0]*(proj[3][new BoydState([0,1,0])][0]),", ", (1 - weights[0])*weights[0]*(proj[2][new BoydState([0,1,0])][0])," ", (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,1,0])][0]) + (1 - weights[0])*weights[0]*(proj[2][new BoydState([0,1,0])][0])));
	//		assert(abs(proj[4][testState][0] - (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,1,0])][0])  + (1 - weights[0])*weights[0]*(proj[2][new BoydState([0,1,0])][0]))) < error);
	//		testState = new BoydState([0,2,2]);
	//		assert(abs(proj[3][testState][1] - (wft + (wsq - wft)*(1 - weights[0])/4 + weights[0]*(proj[2][new BoydState([0,3,2])][1]))) < error);
	//		assert(abs(proj[4][testState][1] - (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,3,2])][1])+ (1 - weights[0])*weights[0]*(proj[2][new BoydState([0,3,2])][1]))) < error);
	//
	//		error = .1; // screw it, too tired to figure this out exactly
	//		testState = new BoydState([0,3,0]);
	////		writeln(proj[5][testState][0], " => ", (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,1,0])][0]))*weights[0] + proj[4][testState][0]*(1-weights[0]) );
	//		// this is wrong, but close enough for these tests
	//		assert(abs(proj[5][testState][0] - ((wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,1,0])][0]))*weights[0] + proj[4][testState][0]*(1-weights[0]))) < error);
	//		testState = new BoydState([0,2,0]);
	////		writeln(proj[5][testState][0], " => ", wft*(1-weights[0])/4 + proj[4][new BoydState([0,1,0])][1]*weights[0]);
	//		// this is wrong, but close enough for these tests
	//		assert(abs(proj[5][testState][0] - (wft*(1-weights[0])/4 + proj[4][new BoydState([0,1,0])][1]*weights[0])) < error);
	//		testState = new BoydState([0,2,2]);
	//		assert(abs(proj[5][testState][1] - (wft + (wsq - wft)*(1 - weights[0])/4+ weights[0]*(proj[3][new BoydState([0,3,2])][1]))*weights[0]) < error);
	//
	//		error = .001;
	//
	//		// make sure the total probability per timestep sums to one
	//
	//		foreach (i; 0..agents.length) {
	//			foreach (t; proj) {
	//				double sum = 0;
	//				foreach (s; pmodel[0].S()) {
	//					sum += t[s][i];
	//				}
	//				assert (abs(sum - 1.0) < error);
	//			}
	//		}
	//
	//		// now test past prediction times
	//
	//		weights = [1];
	//		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
	//		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
	//		interactionLength = 1;
	//		predictTime = 2;
	//
	//		startingTimes[0] = 4;
	//		startingTimes[1] = 0;
	//
	//		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
	//
	//		proj = aReward.getProjection();
	//
	//		// should've set the initial states correctly
	//		//writeln(proj);
	//		assert(proj[0][startingStates[0]][0] == 1.0);
	//		assert(proj[4][startingStates[1]][1] == 1.0);
	//
	//		// should've moved one patroller forward
	//
	//		testState = new BoydState([0,4,0]);
	//		assert(proj[4][testState][0] == 1.0);
	//		testState = new BoydState([0,4,2]);
	//		assert(proj[4][testState][1] == 1.0);
	//
	//
	//
	//		// Now need to catch instances of the patrollers not perfectly landing on each other (ie, stop the probability mass
	//		// from moving if it would pass through another)
	//
	//
	//		weights = [1];
	//		pmodel[0].setT(pmodel[0].createTransitionFunction(weights));
	//		pmodel[1].setT(pmodel[1].createTransitionFunction(weights));
	//		interactionLength = 3;
	//		predictTime = 10;
	//		startingTimes[0] = 0;
	//		startingTimes[1] = 0;
	//
	//		startingStates[1] = new BoydState([0, 3, 2]);
	//
	////		writeln();
	////		writeln();
	////		writeln();
	//
	//		aReward = new AttackerRewardPatrollerProjectionBoyd(new AttackerState([0, 4],0), aModel, reward, maxDetectionRisk, pmodel, agents, startingStates, startingTimes, detectDistance, predictTime, interactionLength, equilibria);
	//
	//		proj = aReward.getProjection();
	//
	////		writeln(proj);
	//		assert(proj[0][startingStates[0]][0] == 1.0);
	//		assert(proj[0][startingStates[1]][1] == 1.0);
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,1,0]);
	//		assert(proj[1][testState][0] == 1.0);
	//		testState = new BoydState([0,2,2]);
	//		assert(proj[1][testState][1] == 1.0);
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,2,0]);
	//		assert(proj[2][testState][0] == 1.0);
	//		testState = new BoydState([0,1,2]);
	//		assert(proj[2][testState][1] == 1.0);
	//
	//		// now we're interacting for 3 steps, on the 3rd step perform the interaction action
	//
	//		// should've moved the patrollers forward one step
	//
	//		testState = new BoydState([0,2,0]);
	//		assert(proj[3][testState][0] == 1.0);
	//		assert(proj[4][testState][0] == 1.0);
	//		testState = new BoydState([0,1,2]);
	//		assert(proj[3][testState][1] == 1.0);
	//		assert(proj[4][testState][1] == 1.0);
	//
	//		testState = new BoydState([0,3,0]);
	//		assert(proj[5][testState][0] == 1.0);
	//		testState = new BoydState([0,1,2]);
	//		assert(proj[5][testState][1] == 1.0);
	//
	//
	//
	//		writeln("Projection unit tests done");
	//
	//	}

}




class FakeReward : Reward {
	
	public override double reward(State state, Action action) {
		return 1;
	}
}

import boydmdp;

bool getDirectionFactor(AttackerState patrollerState, AttackerState attackerState) {

	if (patrollerState.getOrientation() == 0) {
		// facing right, col must be greater than and row must be same
		return patrollerState.getLocation()[0] == attackerState.getLocation()[0] && patrollerState.getLocation()[1] <= attackerState.getLocation()[1];
	
	} else if (patrollerState.getOrientation() == 1) {
		// facing up, col must be same than and row must less than
		return patrollerState.getLocation()[0] >= attackerState.getLocation()[0] && patrollerState.getLocation()[1] == attackerState.getLocation()[1];
	} else if (patrollerState.getOrientation() == 2) {
		// facing left, col must be less than and row must be same
		return patrollerState.getLocation()[0] == attackerState.getLocation()[0] && patrollerState.getLocation()[1] >= attackerState.getLocation()[1];
	} else if (patrollerState.getOrientation() == 3) {
		// facing down, col must be same and row must greater than
		return patrollerState.getLocation()[0] <= attackerState.getLocation()[0] && patrollerState.getLocation()[1] == attackerState.getLocation()[1];
    }
	
	return false;
}


AttackerState convertPatrollerStateToAttacker(State s) {
	BoydState state = cast(BoydState)s;
	
	return new AttackerState([state.getLocation()[0], state.getLocation()[1]], state.getLocation()[2], 0);
}

AttackerState convertPatrollerStateToAttacker2(State s) {
	BoydExtendedState2 state = cast(BoydExtendedState2)s;

	return new AttackerState([state.getLocation()[0], state.getLocation()[1]], state.getLocation()[2], 0);
}



import std.stdio;
class AttackerRewardPatrollerPolicyBoyd : LinearReward {
	
	AttackerState destinationState;
	double rewardAtDestination;
	double penaltyForDiscovery;
	Model patrollerModel;
	Model attackerModel;
	Agent [] patrollerPolicies;
	State [] patrollerStartingStates;
	int [] patrollerStartingTimes;
	int safeDistance;
	int maxTime;
	bool addDelay;
	AttackerState [][] patrollerPositions;
	double[Action][] equilibria;
	int interactionLength;
	
	public this (AttackerState destinationState, Model attackerModel, double rewardAtDestination, double penaltyForDiscovery, Model patrollerModel, Agent [] patrollerPolicies, State [] patrollerStartingStates, int [] patrollerStartingTimes, int safeDistance, int maxTime, bool addDelay, double[Action][]  equilibria, int interactionLength) {
		this.destinationState = destinationState;
		this.rewardAtDestination = rewardAtDestination;
		this.penaltyForDiscovery = penaltyForDiscovery;
		this.patrollerModel = patrollerModel;
		this.attackerModel = attackerModel;
		this.patrollerPolicies = patrollerPolicies;
		this.patrollerStartingStates = patrollerStartingStates;
		this.patrollerStartingTimes = patrollerStartingTimes;
		this.safeDistance = safeDistance;
		this.maxTime = maxTime;
		this.addDelay = addDelay;
		this.equilibria = equilibria;
		this.interactionLength = interactionLength;

		if (patrollerPolicies.length > 0)
			createTrajectories();
	}
	
	public override int dim() {
		return 1;
	}
			
	public override double [] features(State s, Action action) {

		
		AttackerState state = cast(AttackerState)s;

		double [] result;
		result.length = dim();
		result[0] = 0;

        if (attackerModel.is_terminal(state)) {
        	result[0] = rewardAtDestination;
        }
        		
		foreach (AttackerState [] patroller; patrollerPositions) {
			if (patroller.length > state.getTime()) {
				AttackerState pat = patroller[state.getTime()];
				double distance = state.distance(pat);
				double distanceFactor = distance <= safeDistance ? 1.0 : 0.0;
		        if (distanceFactor > 1.0)
		            distanceFactor = 1.0;
		        
		        int directionFactor = 0;    
		        if (getDirectionFactor(pat, state)) 
		        	directionFactor = 1;
		        	
		        result[0] += distanceFactor * penaltyForDiscovery * directionFactor;
//    		        writeln("Detection: ", distanceFactor, " ", penaltyForDiscovery, " ", directionFactor, " - ", state, " <> ", pat );    		            
			}
		}
			
		return result;
	}


	void createTrajectories() {
		/*
			1.  Simulate the older of the patrollers until it and the younger are equal in time
			2.  Simulate both patrollers startingTime + maxTime using multi_simulate
		*/
		patrollerModel.setReward(new FakeReward());
		
		int min = int.max;
		foreach (start; patrollerStartingTimes) {
			if (start < min)
				min = start;
		}
		
		int [] sim_times = new int[patrollerStartingTimes.length];
		sim_times[] = patrollerStartingTimes[] - min;
		
		State [] startStates = patrollerStartingStates.dup;
		
		foreach (int num, State startState; patrollerStartingStates) {
			double[State] initial;
			foreach (s; patrollerModel.S()) 
				initial[s] = 0;
			
			initial[patrollerStartingStates[num]] = 1;
			Distr!State.normalize(initial);
			
			foreach (sar s; simulate(patrollerModel, patrollerPolicies[num], initial, sim_times[num])) {
				startStates[num] = s.s;
			}
		}

		double[State][] initials = new double[State][startStates.length];
		foreach (int i, State startState; startStates) {
			foreach (s; patrollerModel.S()) 
				initials[i][s] = 0;
			
			initials[i][startState] = 1;
			Distr!State.normalize(initials[i]);
		}
				
		
		Model [] models = new Model[patrollerStartingTimes.length];
		for (int i = 0; i < models.length; i ++) {
			models[i] = patrollerModel;
		}


       	sar [][] temp = multi_simulate(models, patrollerPolicies, initials, min + maxTime, equilibria, interactionLength);


		foreach (int num, sar [] sarArr; temp) {
			AttackerState [] traj;
			
			foreach (int timestep, sar s; sarArr) {
				if (timestep >= min) {
					traj ~= convertPatrollerStateToAttacker(s.s);
			
				}
			}

			patrollerPositions ~= traj;
			
		}

	}
	
}



class AttackerRewardPatrollerProjectionBoyd : LinearReward {
	
	double rewardAtDestination;
	double penaltyForDetection;
	Model attackerModel;

	
	public this (Model attackerModel, double rewardAtDestination, double penaltyForDetection) { 
		this.rewardAtDestination = rewardAtDestination;
		this.penaltyForDetection = penaltyForDetection;
		this.attackerModel = attackerModel;
		

	}
	
	public override int dim() {
		return 1;
	}
			
	public override double [] features(State s, Action action) {
		AttackerState state = cast(AttackerState)s;

		double [] result;
		result.length = dim();
		result[0] = 0;

        if (attackerModel.is_terminal(state)) {
        	foreach (terminal; (cast(AttackerModel)attackerModel).goals) {
	        	if (state.location[0] == terminal.location[0] && state.location[1] == terminal.location[1]) {
	        		result[0] += rewardAtDestination;
	        		break;
	        	}
        	}
        	if (state.getDetectionProb() < 0) {
        		result[0] -= penaltyForDetection;
        	}
        } 
        					
		return result;
	}
	

}

//class AttackerRewardPatrollerProjectionBoyd2 : LinearReward {
//
//	double rewardAtDestination;
//	double penaltyForDetection;
//	Model attackerModel;
//
//
//	public this (Model attackerModel, double rewardAtDestination, double penaltyForDetection) {
//		this.rewardAtDestination = rewardAtDestination;
//		this.penaltyForDetection = penaltyForDetection;
//		this.attackerModel = attackerModel;
//
//
//	}
//
//	public override int dim() {
//		return 1;
//	}
//
//	public override double [] features(State s, Action action) {
//		AttackerExtendedState state = cast(AttackerExtendedState)s;
//
//		double [] result;
//		result.length = dim();
//		result[0] = 0;
//
//        if (attackerModel.is_terminal(state)) {
//        	foreach (terminal; (cast(AttackerExtendedModel)attackerModel).goals) {
//	        	if (state.location[0] == terminal.location[0] && state.location[1] == terminal.location[1]) {
//	        		result[0] += rewardAtDestination;
//	        		break;
//	        	}
//        	}
//        	if (state.getDetectionProb() < 0) {
//        		result[0] -= penaltyForDetection;
//        	}
//        }
//
//		return result;
//	}
//
//
//}
